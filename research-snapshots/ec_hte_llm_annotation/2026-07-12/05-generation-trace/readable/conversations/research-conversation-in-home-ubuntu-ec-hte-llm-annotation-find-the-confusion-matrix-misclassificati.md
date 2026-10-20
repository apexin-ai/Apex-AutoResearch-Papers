# Research conversation: In /home/ubuntu/ec_hte_llm_annotation, find the confusion matrix / misclassification rate parameters used in exp-001, ex

**When Debiasing Hurts: An Exact Bias Identity for LLM-Annotated Treatment Effects (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 24
- **Recorded user turns:** 1
- **Tool calls:** 9
- **Original source:** `logs/chats/exported-trajectories/account-2/agent-a572c367cd941b852.jsonl`
- **Structured JSON:** [`d26b10be1ed6e22331cd.json`](../../sessions/d2/d26b10be1ed6e22331cd.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Round 1

24 recorded events

### User

_source line 1 · 2026-05-21T14:37:48.284Z_

In /home/ubuntu/ec_hte_llm_annotation, find the confusion matrix / misclassification rate parameters used in exp-001, exp-003, and exp-013. These are simulation experiments, so I need to know:

1. exp-001: What misclass rates were used? Symmetric or asymmetric? Per-subgroup or global? What was P(Z=1)? What K values?
2. exp-003: What misclass rates (0.05-0.25 mentioned)? How mapped to FPR/FNR? P(Z=1)?
3. exp-013: What CM parameters? P(Z=1)?

Search in .py files, config files, and markdown specs (e.g., exp003_dgp_spec.md). Report all numerical parameters verbatim.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": true,
  "promptId": "aeecb45f-e190-4fc9-9bb8-99f0f97968bf",
  "agentId": "a572c367cd941b852",
  "type": "user",
  "uuid": "a67763e4-ac48-4f97-9e23-d9b3f968227e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/ec_hte_llm_annotation",
  "sessionId": "59df5acf-1bd1-4ab3-a49d-fb4a8872a123",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 2 · 2026-05-21T14:37:49.615Z_

I'll search for the confusion matrix and misclassification parameters for experiments 001, 003, and 013. Let me start by exploring the directory structure and then search for relevant files.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a67763e4-ac48-4f97-9e23-d9b3f968227e",
  "isSidechain": true,
  "agentId": "a572c367cd941b852",
  "requestId": "req_011CbFtEkie6gzC8BgzArWWi",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "13242d03-aa4e-4e21-934d-1b0eadcb4e66",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/ec_hte_llm_annotation",
  "sessionId": "59df5acf-1bd1-4ab3-a49d-fb4a8872a123",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01A3Y7itTPzgCNvDVvX77hK8",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 608,
      "cache_read_input_tokens": 17916,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 608,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-21T14:37:49.851Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01M9o4TwcRe2XVi3bsQKADj1`</summary>

```json
{
  "command": "find /home/ubuntu/ec_hte_llm_annotation -type f -name \"*exp*\" | head -20"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "13242d03-aa4e-4e21-934d-1b0eadcb4e66",
  "isSidechain": true,
  "agentId": "a572c367cd941b852",
  "requestId": "req_011CbFtEkie6gzC8BgzArWWi",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "9ca8a942-8f6e-4ba7-b007-09e87d7c6d12",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/ec_hte_llm_annotation",
  "sessionId": "59df5acf-1bd1-4ab3-a49d-fb4a8872a123",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01A3Y7itTPzgCNvDVvX77hK8",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 608,
      "cache_read_input_tokens": 17916,
      "output_tokens": 120,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 608
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 120,
          "cache_read_input_tokens": 17916,
          "cache_creation_input_tokens": 608,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 608,
            "ephemeral_1h_input_tokens": 0
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

_source line 4 · 2026-05-21T14:37:49.948Z_

<details><summary>↩ Tool result · `toolu_01M9o4TwcRe2XVi3bsQKADj1`</summary>

```text
/home/ubuntu/ec_hte_llm_annotation/exp001_regularize.py
/home/ubuntu/ec_hte_llm_annotation/scripts/explore_tweeteval.py
/home/ubuntu/ec_hte_llm_annotation/exp015_semi_real_cm.py
/home/ubuntu/ec_hte_llm_annotation/exp004_hate_speech.py
/home/ubuntu/ec_hte_llm_annotation/exp017_rlearner.py
/home/ubuntu/ec_hte_llm_annotation/.venv/lib/python3.14/site-packages/shap/__pycache__/_explanation.cpython-314.pyc
/home/ubuntu/ec_hte_llm_annotation/.venv/lib/python3.14/site-packages/shap/_explanation.py
/home/ubuntu/ec_hte_llm_annotation/.venv/lib/python3.14/site-packages/shap/explainers/__pycache__/_explainer.cpython-314.pyc
/home/ubuntu/ec_hte_llm_annotation/.venv/lib/python3.14/site-packages/shap/explainers/_explainer.py
/home/ubuntu/ec_hte_llm_annotation/.venv/lib/python3.14/site-packages/shap/benchmark/__pycache__/experiments.cpython-314.pyc
/home/ubuntu/ec_hte_llm_annotation/.venv/lib/python3.14/site-packages/shap/benchmark/__pycache__/_explanation_error.cpython-314.pyc
/home/ubuntu/ec_hte_llm_annotation/.venv/lib/python3.14/site-packages/shap/benchmark/_explanation_error.py
/home/ubuntu/ec_hte_llm_annotation/.venv/lib/python3.14/site-packages/shap/benchmark/experiments.py
/home/ubuntu/ec_hte_llm_annotation/.venv/lib/python3.14/site-packages/statsmodels/othermod/tests/results/foodexpenditure.csv
/home/ubuntu/ec_hte_llm_annotation/.venv/lib/python3.14/site-packages/statsmodels/tsa/holtwinters/_exponential_smoothers.cpython-314-x86_64-linux-gnu.so
/home/ubuntu/ec_hte_llm_annotation/.venv/lib/python3.14/site-packages/statsmodels/tsa/statespace/__pycache__/exponential_smoothing.cpython-314.pyc
/home/ubuntu/ec_hte_llm_annotation/.venv/lib/python3.14/site-packages/statsmodels/tsa/statespace/tests/test_exponential_smoothing.py
/home/ubuntu/ec_hte_llm_annotation/.venv/lib/python3.14/site-packages/statsmodels/tsa/statespace/tests/__pycache__/test_exponential_smoothing.cpython-314.pyc
/home/ubuntu/ec_hte_llm_annotation/.venv/lib/python3.14/site-packages/statsmodels/tsa/statespace/tests/results/exponential_smoothing_params.csv
/home/ubuntu/ec_hte_llm_annotation/.venv/lib/python3.14/site-packages/statsmodels/tsa/statespace/tests/results/exponential_smoothing_states.csv
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "9ca8a942-8f6e-4ba7-b007-09e87d7c6d12",
  "isSidechain": true,
  "promptId": "aeecb45f-e190-4fc9-9bb8-99f0f97968bf",
  "agentId": "a572c367cd941b852",
  "type": "user",
  "uuid": "b53f61f1-e147-4587-b706-06b2cf395ee0",
  "sourceToolAssistantUUID": "9ca8a942-8f6e-4ba7-b007-09e87d7c6d12",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/ec_hte_llm_annotation",
  "sessionId": "59df5acf-1bd1-4ab3-a49d-fb4a8872a123",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 5 · 2026-05-21T14:37:52.302Z_

Now let me search specifically for exp001, exp003, and exp013 files:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b53f61f1-e147-4587-b706-06b2cf395ee0",
  "isSidechain": true,
  "agentId": "a572c367cd941b852",
  "requestId": "req_011CbFtEsqm5T4sU2gCcqads",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "fe4b6450-76f0-419b-931d-1005c1317121",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/ec_hte_llm_annotation",
  "sessionId": "59df5acf-1bd1-4ab3-a49d-fb4a8872a123",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_016k53RS2Mw5PLxDPZQTaXnp",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 5,
      "cache_creation_input_tokens": 1828,
      "cache_read_input_tokens": 18524,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1828,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool call

_source line 6 · 2026-05-21T14:37:52.504Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01NcX8RN4uLA6SjNSfVoZYgA`</summary>

```json
{
  "pattern": "**/exp001*",
  "path": "/home/ubuntu/ec_hte_llm_annotation"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "fe4b6450-76f0-419b-931d-1005c1317121",
  "isSidechain": true,
  "agentId": "a572c367cd941b852",
  "requestId": "req_011CbFtEsqm5T4sU2gCcqads",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "48df1096-9351-4f19-b7ee-dbec0c041af3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/ec_hte_llm_annotation",
  "sessionId": "59df5acf-1bd1-4ab3-a49d-fb4a8872a123",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_016k53RS2Mw5PLxDPZQTaXnp",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 5,
      "cache_creation_input_tokens": 1828,
      "cache_read_input_tokens": 18524,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1828,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 7 · 2026-05-21T14:37:52.559Z_

<details><summary>↩ Tool result · `toolu_01NcX8RN4uLA6SjNSfVoZYgA`</summary>

```text
results/exp001_full_run.log
results/exp001_hb_diagnostics.csv
results/exp001_hb_results.csv
results/exp001_reg_run.log
exp001_regularize.py
exp001_hyperprior_sensitivity.py
results/exp001_hb_results_v2.csv
results/exp001_reg_v2_run.log
exp001_hb_synthetic.py
__pycache__/exp001_hb_synthetic.cpython-314.pyc
results/exp001_hyperprior_sensitivity.csv
results/exp001_hyperprior_run.log
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "48df1096-9351-4f19-b7ee-dbec0c041af3",
  "isSidechain": true,
  "promptId": "aeecb45f-e190-4fc9-9bb8-99f0f97968bf",
  "agentId": "a572c367cd941b852",
  "type": "user",
  "uuid": "cf4ace8f-ba4b-4f4d-accd-1e94da0be659",
  "sourceToolAssistantUUID": "48df1096-9351-4f19-b7ee-dbec0c041af3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/ec_hte_llm_annotation",
  "sessionId": "59df5acf-1bd1-4ab3-a49d-fb4a8872a123",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 8 · 2026-05-21T14:37:52.720Z_

<details open><summary>🔧 Tool call — Glob · `toolu_011QinKPTnidhmrkJjcUPDtJ`</summary>

```json
{
  "pattern": "**/exp003*",
  "path": "/home/ubuntu/ec_hte_llm_annotation"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "cf4ace8f-ba4b-4f4d-accd-1e94da0be659",
  "isSidechain": true,
  "agentId": "a572c367cd941b852",
  "requestId": "req_011CbFtEsqm5T4sU2gCcqads",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "d6960dbd-1cfb-4a2f-bd44-6396acc296c0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/ec_hte_llm_annotation",
  "sessionId": "59df5acf-1bd1-4ab3-a49d-fb4a8872a123",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_016k53RS2Mw5PLxDPZQTaXnp",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 5,
      "cache_creation_input_tokens": 1828,
      "cache_read_input_tokens": 18524,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1828,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 9 · 2026-05-21T14:37:52.774Z_

<details><summary>↩ Tool result · `toolu_011QinKPTnidhmrkJjcUPDtJ`</summary>

```text
results/exp003_phase_a_raw.csv
results/exp003_phase_a.csv
results/exp003_run.log
results/exp003_phase_a_v2_raw.csv
results/exp003_phase_a_v2.csv
results/exp003_v2_run.log
exp003_tweeteval.py
results/exp003_dgp_spec.md
results/exp003_phase_a_v3_raw.csv
results/exp003_phase_a_v3.csv
results/exp003_hb_rerun.log
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d6960dbd-1cfb-4a2f-bd44-6396acc296c0",
  "isSidechain": true,
  "promptId": "aeecb45f-e190-4fc9-9bb8-99f0f97968bf",
  "agentId": "a572c367cd941b852",
  "type": "user",
  "uuid": "6985ea7d-ff1d-44d8-bcdc-c239f879f308",
  "sourceToolAssistantUUID": "d6960dbd-1cfb-4a2f-bd44-6396acc296c0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/ec_hte_llm_annotation",
  "sessionId": "59df5acf-1bd1-4ab3-a49d-fb4a8872a123",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 10 · 2026-05-21T14:37:52.922Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01RZc3XwieHafPe5jXm7a2Z3`</summary>

```json
{
  "pattern": "**/exp013*",
  "path": "/home/ubuntu/ec_hte_llm_annotation"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6985ea7d-ff1d-44d8-bcdc-c239f879f308",
  "isSidechain": true,
  "agentId": "a572c367cd941b852",
  "requestId": "req_011CbFtEsqm5T4sU2gCcqads",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "049a3708-388e-4e15-b815-4592a419c6b0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/ec_hte_llm_annotation",
  "sessionId": "59df5acf-1bd1-4ab3-a49d-fb4a8872a123",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_016k53RS2Mw5PLxDPZQTaXnp",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 5,
      "cache_creation_input_tokens": 1828,
      "cache_read_input_tokens": 18524,
      "output_tokens": 243,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 1828
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 5,
          "output_tokens": 243,
          "cache_read_input_tokens": 18524,
          "cache_creation_input_tokens": 1828,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 1828,
            "ephemeral_1h_input_tokens": 0
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

_source line 11 · 2026-05-21T14:37:52.980Z_

<details><summary>↩ Tool result · `toolu_01RZc3XwieHafPe5jXm7a2Z3`</summary>

```text
exp013_boundary_condition.py
results/exp013_boundary_condition.csv
results/exp013_boundary_summary.csv
results/exp013_boundary_analysis.md
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "049a3708-388e-4e15-b815-4592a419c6b0",
  "isSidechain": true,
  "promptId": "aeecb45f-e190-4fc9-9bb8-99f0f97968bf",
  "agentId": "a572c367cd941b852",
  "type": "user",
  "uuid": "2ec5302f-4772-4687-b501-1edfb43e9898",
  "sourceToolAssistantUUID": "049a3708-388e-4e15-b815-4592a419c6b0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/ec_hte_llm_annotation",
  "sessionId": "59df5acf-1bd1-4ab3-a49d-fb4a8872a123",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 12 · 2026-05-21T14:37:54.746Z_

Great! Now let me search for misclassification, confusion matrix, and related parameters in these Python files:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2ec5302f-4772-4687-b501-1edfb43e9898",
  "isSidechain": true,
  "agentId": "a572c367cd941b852",
  "requestId": "req_011CbFtF6rquent8oVDtWMDY",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "538e7fa0-a679-4de3-a384-133bb456cd2e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/ec_hte_llm_annotation",
  "sessionId": "59df5acf-1bd1-4ab3-a49d-fb4a8872a123",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01HMQR2w6jat1sNtWUt7nYrR",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 658,
      "cache_read_input_tokens": 20352,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 658,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-21T14:37:54.987Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Fbobjw3XNJ7rNo2LuFBHvT`</summary>

```json
{
  "file_path": "/home/ubuntu/ec_hte_llm_annotation/exp001_regularize.py"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "538e7fa0-a679-4de3-a384-133bb456cd2e",
  "isSidechain": true,
  "agentId": "a572c367cd941b852",
  "requestId": "req_011CbFtF6rquent8oVDtWMDY",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "958bfcbc-0feb-4a51-b1a6-7945d543785e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/ec_hte_llm_annotation",
  "sessionId": "59df5acf-1bd1-4ab3-a49d-fb4a8872a123",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01HMQR2w6jat1sNtWUt7nYrR",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 658,
      "cache_read_input_tokens": 20352,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 658,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-21T14:37:54.993Z_

<details><summary>↩ Tool result · `toolu_01Fbobjw3XNJ7rNo2LuFBHvT`</summary>

```text
1	#!/usr/bin/env python3
2	"""exp001_regularize.py - Rerun affected cells with condition-number-guarded inversion."""
3	
4	import argparse
5	import time
6	import numpy as np
7	import pandas as pd
8	
9	from exp001_hb_synthetic import (
10	    REGIMES, SUBGROUP_LABELS,
11	    generate_data, get_counts, build_mixing_matrix, diff_in_means,
12	    estimate_cm_mle, estimate_cm_hb_eb, estimate_cm_hb_gibbs,
13	    invert_mixing_safe, aggregate_results,
14	)
15	
16	AFFECTED_CELLS = [
17	    (4, 'extreme', 50),
18	    (4, 'extreme', 100),
19	    (4, 'moderate', 50),
20	    (4, 'moderate', 100),
21	    (4, 'homogeneous', 50),
22	    (4, 'homogeneous', 100),
23	]
24	
25	
26	def run_one_mc_reg(regime_name, regime_params, n_expert, k, seed,
27	                   cond_threshold=100, n_chains=4, n_iter=4000, n_warmup=2000):
28	    data = generate_data(regime_params, n_expert, k, seed)
29	    Y, T, Z, Z_hat, S = data['Y'], data['T'], data['Z'], data['Z_hat'], data['S']
30	    em = data['expert_mask']
31	    labels = SUBGROUP_LABELS[k]
32	    tau_z0, tau_z1 = regime_params['tau_z0'], regime_params['tau_z1']
33	
34	    counts = get_counts(Z[em], Z_hat[em], S[em], labels)
35	    C_mle = estimate_cm_mle(counts, labels)
36	    C_hb, hb_diag = estimate_cm_hb_gibbs(counts, labels, seed=seed,
37	                                          n_chains=n_chains, n_iter=n_iter,
38	                                          n_warmup=n_warmup)
39	
40	    M_mle = {s: build_mixing_matrix(C_mle[s]) for s in labels}
41	    M_hb = {s: build_mixing_matrix(C_hb[s]) for s in labels}
42	
43	    base = {'regime': regime_name, 'n_expert': n_expert,
44	            'k_subgroups': k, 'mc_run': seed}
45	    rows = []
46	    guard_hb = 0
47	    guard_mle = 0
48	
49	    for s in labels:
50	        sm = S == s
51	        th0_n, se0_n = diff_in_means(Y, T, sm & (Z_hat == 0))
52	        th1_n, se1_n = diff_in_means(Y, T, sm & (Z_hat == 1))
53	
54	        tau_obs = np.array([th0_n, th1_n])
55	        se_obs = np.array([se0_n, se1_n])
56	        if np.any(np.isnan(tau_obs)):
57	            continue
58	
59	        cond_mle = np.linalg.cond(M_mle[s])
60	        cond_hb = np.linalg.cond(M_hb[s])
61	        if cond_mle > cond_threshold:
62	            guard_mle += 1
63	        if cond_hb > cond_threshold:
64	            guard_hb += 1
65	
66	        tml_r, sml_r = invert_mixing_safe(M_mle[s], tau_obs, se_obs, cond_threshold)
67	        thb_r, shb_r = invert_mixing_safe(M_hb[s], tau_obs, se_obs, cond_threshold)
68	
69	        def mr(method, th0, th1, se0, se1):
70	            return {**base, 'subgroup': s, 'method': method,
71	                    'tau_hat_z0': th0, 'tau_hat_z1': th1,
72	                    'se_z0': se0, 'se_z1': se1,
73	                    'tau_true_z0': tau_z0, 'tau_true_z1': tau_z1}
74	
75	        rows.append(mr('mle_laplace_reg', tml_r[0], tml_r[1], sml_r[0], sml_r[1]))
76	        rows.append(mr('hb_dirichlet_reg', thb_r[0], thb_r[1], shb_r[0], shb_r[1]))
77	
78	    return rows, hb_diag, guard_hb, guard_mle
79	
80	
81	if __name__ == '__main__':
82	    parser = argparse.ArgumentParser()
83	    parser.add_argument('--n-mc', type=int, default=100)
84	    parser.add_argument('--cond-threshold', type=float, default=100)
85	    args = parser.parse_args()
86	
87	    print(f"exp-001 Regularization fix v2 | cond_threshold={args.cond_threshold}")
88	    print(f"Affected cells: {AFFECTED_CELLS}")
89	    print(f"n_mc={args.n_mc}")
90	    print(f"MCMC config: n_chains=4, n_iter=4000, n_warmup=2000\n")
91	
92	    # ── MCMC diagnostic comparison (before/after) ────────────────────────────
93	    print("Running MCMC diagnostic comparison (seed=0, per config)...")
94	    diag_rows = []
95	    for k, regime, n_expert in AFFECTED_CELLS:
96	        rp = REGIMES[k][regime]
97	        d = generate_data(rp, n_expert, k, seed=0)
98	        em = d['expert_mask']
99	        labels = SUBGROUP_LABELS[k]
100	        counts = get_counts(d['Z'][em], d['Z_hat'][em], d['S'][em], labels)
101	
102	        _, diag_before = estimate_cm_hb_gibbs(counts, labels, seed=0,
103	                                               n_chains=2, n_iter=2000, n_warmup=1000)
104	        _, diag_after = estimate_cm_hb_gibbs(counts, labels, seed=0,
105	                                              n_chains=4, n_iter=4000, n_warmup=2000)
106	        diag_rows.append({
107	            'config': f"K={k}/{regime}/n={n_expert}",
108	            'rhat_before': diag_before['rhat_max'],
109	            'rhat_after': diag_after['rhat_max'],
110	            'ess_before': diag_before['ess_min'],
111	            'ess_after': diag_after['ess_min'],
112	        })
113	
114	    print("\n" + "=" * 100)
115	    print("MCMC Diagnostic Comparison (seed=0)")
116	    print(f"{'Config':>30s} | {'Rhat_max (2ch)':>14s} | {'Rhat_max (4ch)':>14s} | "
117	          f"{'ESS_min (2ch)':>14s} | {'ESS_min (4ch)':>14s}")
118	    print("-" * 100)
119	    for r in diag_rows:
120	        print(f"{r['config']:>30s} | {r['rhat_before']:14.4f} | {r['rhat_after']:14.4f} | "
121	              f"{r['ess_before']:14.1f} | {r['ess_after']:14.1f}")
122	    print("=" * 100 + "\n")
123	
124	    # ── Main MC loop ─────────────────────────────────────────────────────────
125	    all_rows = []
126	    guard_stats = {}
127	    diag_agg = {}
128	    total = len(AFFECTED_CELLS) * args.n_mc
129	    count = 0
130	    t0 = time.time()
131	
132	    for k, regime, n_expert in AFFECTED_CELLS:
133	        key = (k, regime, n_expert)
134	        guard_stats[key] = {'total': 0, 'guard_hb': 0, 'guard_mle': 0}
135	        diag_agg[key] = {'rhat_max': [], 'ess_min': []}
136	        rp = REGIMES[k][regime]
137	        for mc in range(args.n_mc):
138	            rows, hb_diag, g_hb, g_mle = run_one_mc_reg(
139	                regime, rp, n_expert, k, seed=mc,
140	                cond_threshold=args.cond_threshold,
141	                n_chains=4, n_iter=4000, n_warmup=2000)
142	            all_rows.extend(rows)
143	            guard_stats[key]['total'] += 1
144	            guard_stats[key]['guard_hb'] += g_hb
145	            guard_stats[key]['guard_mle'] += g_mle
146	            diag_agg[key]['rhat_max'].append(hb_diag['rhat_max'])
147	            diag_agg[key]['ess_min'].append(hb_diag['ess_min'])
148	            count += 1
149	            if count % 50 == 0:
150	                el = time.time() - t0
151	                print(f"  [{count}/{total}] {el:.0f}s elapsed")
152	
153	    print(f"  Done: {time.time() - t0:.1f}s ({count} runs)\n")
154	
155	    # ── Singularity guard trigger stats ──────────────────────────────────────
156	    print("=" * 90)
157	    print("Singularity Guard Trigger Statistics")
158	    print(f"{'Config':>30s} | {'Total MC':>8s} | {'Guard HB':>10s} | {'Guard MLE':>10s}")
159	    print("-" * 90)
160	    for key in guard_stats:
161	        k, regime, n_expert = key
162	        gs = guard_stats[key]
163	        config = f"K={k}/{regime}/n={n_expert}"
164	        print(f"{config:>30s} | {gs['total']:8d} | {gs['guard_hb']:10d} | {gs['guard_mle']:10d}")
165	    print("=" * 90 + "\n")
166	
167	    # ── Aggregated MCMC diagnostics across MC runs ───────────────────────────
168	    print("=" * 100)
169	    print("Aggregated MCMC Diagnostics (4 chains, 4000 iter)")
170	    print(f"{'Config':>30s} | {'Rhat_max mean':>14s} | {'Rhat_max max':>14s} | "
171	          f"{'ESS_min mean':>14s} | {'ESS_min min':>14s}")
172	    print("-" * 100)
173	    for key in diag_agg:
174	        k, regime, n_expert = key
175	        config = f"K={k}/{regime}/n={n_expert}"
176	        rhats = diag_agg[key]['rhat_max']
177	        esss = diag_agg[key]['ess_min']
178	        print(f"{config:>30s} | {np.mean(rhats):14.4f} | {np.max(rhats):14.4f} | "
179	              f"{np.mean(esss):14.1f} | {np.min(esss):14.1f}")
180	    print("=" * 100 + "\n")
181	
182	    # ── Aggregate and write results ──────────────────────────────────────────
183	    df_raw = pd.DataFrame(all_rows)
184	    df_agg = aggregate_results(df_raw)
185	
186	    csv_orig = 'results/exp001_hb_results.csv'
187	    csv_v2 = 'results/exp001_hb_results_v2.csv'
188	    df_existing = pd.read_csv(csv_orig)
189	
190	    # Remove previously appended reg rows (keep original 540)
191	    reg_methods = ['hb_dirichlet_reg', 'mle_laplace_reg']
192	    df_base = df_existing[~df_existing['method'].isin(reg_methods)].copy()
193	
194	    agg_cols = list(df_base.columns)
195	    df_combined = pd.concat([df_base, df_agg[agg_cols]], ignore_index=True)
196	    df_combined.to_csv(csv_v2, index=False)
197	
198	    # ── RMSE comparison table ────────────────────────────────────────────────
199	    print("=" * 120)
200	    print("RMSE Comparison (original vs regularized)")
201	    print(f"{'Config':>40s} | {'Method':>15s} | {'RMSE_z0 (orig)':>15s} | "
202	          f"{'RMSE_z0 (reg)':>14s} | {'RMSE_z1 (orig)':>15s} | {'RMSE_z1 (reg)':>14s}")
203	    print("-" * 120)
204	
205	    for k, regime, n_expert in AFFECTED_CELLS:
206	        for subgroup in SUBGROUP_LABELS[k]:
207	            mask_base = ((df_base['k_subgroups'] == k) &
208	                         (df_base['regime'] == regime) &
209	                         (df_base['n_expert'] == n_expert) &
210	                         (df_base['subgroup'] == subgroup))
211	
212	            for orig, reg in [('hb_dirichlet', 'hb_dirichlet_reg'),
213	                              ('mle_laplace', 'mle_laplace_reg')]:
214	                before = df_base[mask_base & (df_base['method'] == orig)]
215	                after = df_agg[(df_agg['k_subgroups'] == k) &
216	                               (df_agg['regime'] == regime) &
217	                               (df_agg['n_expert'] == n_expert) &
218	                               (df_agg['subgroup'] == subgroup) &
219	                               (df_agg['method'] == reg)]
220	
221	                if before.empty or after.empty:
222	                    continue
223	
224	                b_z0 = before['rmse_z0'].values[0]
225	                a_z0 = after['rmse_z0'].values[0]
226	                b_z1 = before['rmse_z1'].values[0]
227	                a_z1 = after['rmse_z1'].values[0]
228	
229	                config = f"K={k}/{regime}/n={n_expert}/{subgroup}"
230	                print(f"{config:>40s} | {orig:>15s} | {b_z0:15.4f} | "
231	                      f"{a_z0:14.4f} | {b_z1:15.4f} | {a_z1:14.4f}")
232	
233	    # Global method comparison
234	    print("-" * 120)
235	    for method in ['diff_in_means', 'mle_laplace', 'hb_dirichlet']:
236	        mask = df_base['method'] == method
237	        if mask.any():
238	            r0 = df_base.loc[mask, 'rmse_z0'].mean()
239	            r1 = df_base.loc[mask, 'rmse_z1'].mean()
240	            print(f"{'Global avg':>40s} | {method:>15s} | {r0:15.4f} | {'---':>14s} | {r1:15.4f} | {'---':>14s}")
241	    for method in ['mle_laplace_reg', 'hb_dirichlet_reg']:
242	        mask = df_agg['method'] == method
243	        if mask.any():
244	            r0 = df_agg.loc[mask, 'rmse_z0'].mean()
245	            r1 = df_agg.loc[mask, 'rmse_z1'].mean()
246	            print(f"{'Global avg (reg cells)':>40s} | {method:>15s} | {'---':>15s} | {r0:14.4f} | {'---':>15s} | {r1:14.4f}")
247	
248	    print("=" * 120)
249	    print(f"\nWrote {csv_v2}: {len(df_base)} original + {len(df_agg)} new = {len(df_combined)} rows")
250	    print(f"Original file {csv_orig} unchanged.")
251	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "958bfcbc-0feb-4a51-b1a6-7945d543785e",
  "isSidechain": true,
  "promptId": "aeecb45f-e190-4fc9-9bb8-99f0f97968bf",
  "agentId": "a572c367cd941b852",
  "type": "user",
  "uuid": "77b75964-a90e-4907-bf9f-821f76fd1b50",
  "sourceToolAssistantUUID": "958bfcbc-0feb-4a51-b1a6-7945d543785e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/ec_hte_llm_annotation",
  "sessionId": "59df5acf-1bd1-4ab3-a49d-fb4a8872a123",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-21T14:37:55.181Z_

<details open><summary>🔧 Tool call — Read · `toolu_01CuBxTxUEWeVsGZqMEc6Xb8`</summary>

```json
{
  "file_path": "/home/ubuntu/ec_hte_llm_annotation/exp001_hb_synthetic.py"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "77b75964-a90e-4907-bf9f-821f76fd1b50",
  "isSidechain": true,
  "agentId": "a572c367cd941b852",
  "requestId": "req_011CbFtF6rquent8oVDtWMDY",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "2e52baba-897f-4905-a223-3500cfe857aa",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/ec_hte_llm_annotation",
  "sessionId": "59df5acf-1bd1-4ab3-a49d-fb4a8872a123",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01HMQR2w6jat1sNtWUt7nYrR",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 658,
      "cache_read_input_tokens": 20352,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 658,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool call

_source line 16 · 2026-05-21T14:37:55.388Z_

<details open><summary>🔧 Tool call — Read · `toolu_01EqZuVgtqU6i8RTKi89R2m8`</summary>

```json
{
  "file_path": "/home/ubuntu/ec_hte_llm_annotation/exp003_tweeteval.py"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2e52baba-897f-4905-a223-3500cfe857aa",
  "isSidechain": true,
  "agentId": "a572c367cd941b852",
  "requestId": "req_011CbFtF6rquent8oVDtWMDY",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "12d5f48d-d74e-4452-86eb-b50cab73adf7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/ec_hte_llm_annotation",
  "sessionId": "59df5acf-1bd1-4ab3-a49d-fb4a8872a123",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01HMQR2w6jat1sNtWUt7nYrR",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 658,
      "cache_read_input_tokens": 20352,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 658,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-21T14:37:55.550Z_

<details open><summary>🔧 Tool call — Read · `toolu_01TgZ1FSPxFNB377WLrbsvSp`</summary>

```json
{
  "file_path": "/home/ubuntu/ec_hte_llm_annotation/exp013_boundary_condition.py"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "12d5f48d-d74e-4452-86eb-b50cab73adf7",
  "isSidechain": true,
  "agentId": "a572c367cd941b852",
  "requestId": "req_011CbFtF6rquent8oVDtWMDY",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "c918c81b-aa9d-4ef6-a379-15fa8860f758",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/ec_hte_llm_annotation",
  "sessionId": "59df5acf-1bd1-4ab3-a49d-fb4a8872a123",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01HMQR2w6jat1sNtWUt7nYrR",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 658,
      "cache_read_input_tokens": 20352,
      "output_tokens": 273,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 658
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 6,
          "output_tokens": 273,
          "cache_read_input_tokens": 20352,
          "cache_creation_input_tokens": 658,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 658,
            "ephemeral_1h_input_tokens": 0
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

_source line 18 · 2026-05-21T14:37:55.555Z_

<details><summary>↩ Tool result · `toolu_01TgZ1FSPxFNB377WLrbsvSp`</summary>

```text
1	#!/usr/bin/env python3
2	"""
3	exp013_boundary_condition.py - Boundary condition test: n_expert=50, K=4, extreme regime.
4	
5	With only ~12.5 expert labels per subgroup, per-subgroup CM estimation is extremely noisy.
6	Tests whether stratified methods degrade vs global correction under these conditions.
7	"""
8	
9	import argparse
10	import os
11	import time
12	import numpy as np
13	import pandas as pd
14	
15	from exp001_hb_synthetic import (
16	    generate_data, get_counts, estimate_cm_mle, estimate_cm_hb_eb,
17	    estimate_cm_hb_gibbs, build_mixing_matrix, invert_mixing_safe,
18	    diff_in_means, REGIMES, SUBGROUP_LABELS, N,
19	)
20	
21	K = 4
22	REGIME_NAME = 'extreme'
23	REGIME_PARAMS = REGIMES[K][REGIME_NAME]
24	N_EXPERT = 50
25	LABELS = SUBGROUP_LABELS[K]
26	
27	
28	def run_one(seed, hb_method='eb'):
29	    data = generate_data(REGIME_PARAMS, N_EXPERT, K, seed)
30	    Y, T, Z, Z_hat, S = data['Y'], data['T'], data['Z'], data['Z_hat'], data['S']
31	    em = data['expert_mask']
32	    tau_z0, tau_z1 = REGIME_PARAMS['tau_z0'], REGIME_PARAMS['tau_z1']
33	
34	    counts = get_counts(Z[em], Z_hat[em], S[em], LABELS)
35	
36	    C_mle = estimate_cm_mle(counts, LABELS)
37	    if hb_method == 'gibbs':
38	        C_hb, _ = estimate_cm_hb_gibbs(counts, LABELS, seed=seed)
39	    else:
40	        C_hb, _ = estimate_cm_hb_eb(counts, LABELS)
41	
42	    cg = counts.sum(axis=0)
43	    C_gl = np.zeros((2, 2))
44	    for z in [0, 1]:
45	        n = cg[z, :].sum()
46	        for zh in [0, 1]:
47	            C_gl[z, zh] = (cg[z, zh] + 1) / (n + 2) if n > 0 else 0.5
48	
49	    M_gl = build_mixing_matrix(C_gl)
50	    M_mle = {s: build_mixing_matrix(C_mle[s]) for s in LABELS}
51	    M_hb = {s: build_mixing_matrix(C_hb[s]) for s in LABELS}
52	
53	    rows = []
54	    for s in LABELS:
55	        sm = S == s
56	        th0_n, se0_n = diff_in_means(Y, T, sm & (Z_hat == 0))
57	        th1_n, se1_n = diff_in_means(Y, T, sm & (Z_hat == 1))
58	        tau_obs = np.array([th0_n, th1_n])
59	        se_obs = np.array([se0_n, se1_n])
60	        if np.any(np.isnan(tau_obs)):
61	            continue
62	
63	        tgc, sgc = invert_mixing_safe(M_gl, tau_obs, se_obs)
64	        tml, sml = invert_mixing_safe(M_mle[s], tau_obs, se_obs)
65	        thb, shb = invert_mixing_safe(M_hb[s], tau_obs, se_obs)
66	
67	        for method, t0, t1, s0, s1 in [
68	            ('naive',            th0_n, th1_n, se0_n, se1_n),
69	            ('global_corrected', tgc[0], tgc[1], sgc[0], sgc[1]),
70	            ('mle_laplace',      tml[0], tml[1], sml[0], sml[1]),
71	            ('hb_eb',            thb[0], thb[1], shb[0], shb[1]),
72	        ]:
73	            for z_label, tau_c, se_c, tau_true in [
74	                ('z0', t0, s0, tau_z0), ('z1', t1, s1, tau_z1)
75	            ]:
76	                lo = tau_c - 1.96 * se_c
77	                hi = tau_c + 1.96 * se_c
78	                rows.append({
79	                    'mc_run': seed, 'subgroup': s, 'method': method,
80	                    'z_level': z_label,
81	                    'tau_corrected': tau_c, 'tau_true': tau_true,
82	                    'se_corrected': se_c,
83	                    'coverage': int(lo <= tau_true <= hi),
84	                })
85	    return rows
86	
87	
88	def summarize(df):
89	    rows = []
90	    for (sg, method, z), grp in df.groupby(['subgroup', 'method', 'z_level']):
91	        err = grp['tau_corrected'].values - grp['tau_true'].values
92	        n_mc = len(grp)
93	        bias = err.mean()
94	        rmse = np.sqrt((err ** 2).mean())
95	        cov = grp['coverage'].mean()
96	        rows.append({
97	            'subgroup': sg, 'method': method, 'z_level': z,
98	            'bias': bias, 'abs_bias': abs(bias), 'rmse': rmse, 'coverage': cov,
99	            'bias_se': err.std() / np.sqrt(n_mc),
100	            'rmse_se': (err ** 2).std() / np.sqrt(n_mc) / (2 * rmse) if rmse > 1e-10 else np.nan,
101	            'coverage_se': np.sqrt(cov * (1 - cov) / n_mc),
102	            'n_mc': n_mc,
103	        })
104	    return pd.DataFrame(rows)
105	
106	
107	def write_analysis(df_summary):
108	    methods = ['naive', 'global_corrected', 'mle_laplace', 'hb_eb']
109	    subgroups = list(LABELS)
110	    misclass = dict(zip(LABELS, REGIME_PARAMS['misclass']))
111	
112	    lines = [
113	        '# exp-013: Boundary Condition Analysis',
114	        f'',
115	        f'**Config**: K={K}, regime={REGIME_NAME}, n_expert={N_EXPERT}, '
116	        f'N={N}, misclass={REGIME_PARAMS["misclass"]}',
117	        f'',
118	        f'Each subgroup gets ~{N_EXPERT / K:.0f} expert labels.',
119	        '',
120	        '## Per-subgroup Results',
121	        '',
122	    ]
123	
124	    header = '| Subgroup (pi) | Method | |Bias|_z0 | RMSE_z0 | Cov_z0 | |Bias|_z1 | RMSE_z1 | Cov_z1 |'
125	    sep =    '|---|---|---|---|---|---|---|---|'
126	    lines += [header, sep]
127	
128	    for s in subgroups:
129	        for m in methods:
130	            r0 = df_summary[(df_summary['subgroup'] == s) & (df_summary['method'] == m) & (df_summary['z_level'] == 'z0')]
131	            r1 = df_summary[(df_summary['subgroup'] == s) & (df_summary['method'] == m) & (df_summary['z_level'] == 'z1')]
132	            if r0.empty or r1.empty:
133	                continue
134	            r0, r1 = r0.iloc[0], r1.iloc[0]
135	            lines.append(
136	                f'| {s} ({misclass[s]:.2f}) | {m} | '
137	                f'{r0["abs_bias"]:.4f} | {r0["rmse"]:.4f} | {r0["coverage"]:.2f} | '
138	                f'{r1["abs_bias"]:.4f} | {r1["rmse"]:.4f} | {r1["coverage"]:.2f} |'
139	            )
140	
141	    lines += ['', '## Average Across Subgroups', '']
142	    lines += [
143	        '| Method | |Bias|_z0 | RMSE_z0 | Cov_z0 | |Bias|_z1 | RMSE_z1 | Cov_z1 |',
144	        '|---|---|---|---|---|---|---|',
145	    ]
146	    for m in methods:
147	        msub = df_summary[df_summary['method'] == m]
148	        r0 = msub[msub['z_level'] == 'z0']
149	        r1 = msub[msub['z_level'] == 'z1']
150	        if r0.empty or r1.empty:
151	            continue
152	        lines.append(
153	            f'| {m} | '
154	            f'{r0["abs_bias"].mean():.4f} | {r0["rmse"].mean():.4f} | {r0["coverage"].mean():.2f} | '
155	            f'{r1["abs_bias"].mean():.4f} | {r1["rmse"].mean():.4f} | {r1["coverage"].mean():.2f} |'
156	        )
157	
158	    lines += ['', '## RMSE Amplification (stratified vs global)', '']
159	    gl_rmse = {}
160	    for z in ['z0', 'z1']:
161	        r = df_summary[(df_summary['method'] == 'global_corrected') & (df_summary['z_level'] == z)]
162	        gl_rmse[z] = r['rmse'].mean() if not r.empty else np.nan
163	
164	    lines += ['| Subgroup | Method | RMSE_z0 / Global | RMSE_z1 / Global |', '|---|---|---|---|']
165	    for s in subgroups:
166	        for m in ['mle_laplace', 'hb_eb']:
167	            r0 = df_summary[(df_summary['subgroup'] == s) & (df_summary['method'] == m) & (df_summary['z_level'] == 'z0')]
168	            r1 = df_summary[(df_summary['subgroup'] == s) & (df_summary['method'] == m) & (df_summary['z_level'] == 'z1')]
169	            if r0.empty or r1.empty:
170	                continue
171	            amp0 = r0.iloc[0]['rmse'] / gl_rmse['z0'] if gl_rmse['z0'] > 1e-10 else np.nan
172	            amp1 = r1.iloc[0]['rmse'] / gl_rmse['z1'] if gl_rmse['z1'] > 1e-10 else np.nan
173	            lines.append(f'| {s} ({misclass[s]:.2f}) | {m} | {amp0:.2f}x | {amp1:.2f}x |')
174	
175	    # Analysis
176	    worst_sg = None
177	    worst_rmse = 0
178	    for s in subgroups:
179	        for m in ['mle_laplace', 'hb_eb']:
180	            for z in ['z0', 'z1']:
181	                r = df_summary[(df_summary['subgroup'] == s) & (df_summary['method'] == m) & (df_summary['z_level'] == z)]
182	                if not r.empty and r.iloc[0]['rmse'] > worst_rmse:
183	                    worst_rmse = r.iloc[0]['rmse']
184	                    worst_sg = (s, m, z)
185	
186	    lines += ['', '## Key Findings', '']
187	    if worst_sg:
188	        lines.append(f'1. **Worst degradation**: subgroup {worst_sg[0]} ({worst_sg[1]}, {worst_sg[2]}) '
189	                      f'with RMSE={worst_rmse:.4f}')
190	
191	    avg_strat_rmse_z0 = df_summary[(df_summary['method'].isin(['mle_laplace', 'hb_eb'])) & (df_summary['z_level'] == 'z0')]['rmse'].mean()
192	    avg_strat_rmse_z1 = df_summary[(df_summary['method'].isin(['mle_laplace', 'hb_eb'])) & (df_summary['z_level'] == 'z1')]['rmse'].mean()
193	    lines.append(f'2. **Average stratified RMSE**: z0={avg_strat_rmse_z0:.4f}, z1={avg_strat_rmse_z1:.4f} '
194	                 f'vs global z0={gl_rmse["z0"]:.4f}, z1={gl_rmse["z1"]:.4f}')
195	    amp_z0 = avg_strat_rmse_z0 / gl_rmse['z0'] if gl_rmse['z0'] > 1e-10 else np.nan
196	    amp_z1 = avg_strat_rmse_z1 / gl_rmse['z1'] if gl_rmse['z1'] > 1e-10 else np.nan
197	    lines.append(f'3. **Amplification factor**: {amp_z0:.2f}x (z0), {amp_z1:.2f}x (z1)')
198	
199	    threshold_met = N_EXPERT / K >= 25
200	    lines.append(f'4. **n_expert/K = {N_EXPERT / K:.1f}** {">=25 threshold met" if threshold_met else "< 25 threshold NOT met"}. '
201	                 f'{"Stratified methods should be usable." if threshold_met else "Below recommended minimum — expect high variance in per-subgroup estimates."}')
202	
203	    # EB vs MLE comparison
204	    eb_rmse = df_summary[df_summary['method'] == 'hb_eb']['rmse'].mean()
205	    mle_rmse = df_summary[df_summary['method'] == 'mle_laplace']['rmse'].mean()
206	    if mle_rmse > 1e-10:
207	        pct = (mle_rmse - eb_rmse) / mle_rmse * 100
208	        lines.append(f'5. **EB vs MLE**: EB RMSE {pct:+.1f}% relative to MLE '
209	                     f'({"EB helps with shrinkage" if pct > 0 else "MLE competitive"})')
210	
211	    lines.append('')
212	    return '\n'.join(lines)
213	
214	
215	def main():
216	    parser = argparse.ArgumentParser()
217	    parser.add_argument('--n-mc', type=int, default=100)
218	    parser.add_argument('--dry-run', action='store_true')
219	    parser.add_argument('--hb-method', choices=['eb', 'gibbs'], default='eb')
220	    args = parser.parse_args()
221	
222	    n_mc = 5 if args.dry_run else args.n_mc
223	    tag = ' (DRY RUN)' if args.dry_run else ''
224	    print(f'exp-013 Boundary Condition{tag} | K={K} {REGIME_NAME} n_expert={N_EXPERT} n_mc={n_mc} hb={args.hb_method}')
225	
226	    all_rows = []
227	    t0 = time.time()
228	    for mc in range(n_mc):
229	        rows = run_one(mc, hb_method=args.hb_method)
230	        all_rows.extend(rows)
231	        if (mc + 1) % max(1, n_mc // 10) == 0:
232	            el = time.time() - t0
233	            print(f'  [{mc + 1}/{n_mc}] {el:.1f}s elapsed')
234	
235	    print(f'  Done: {time.time() - t0:.1f}s ({len(all_rows)} rows)')
236	
237	    df = pd.DataFrame(all_rows)
238	    df_summary = summarize(df)
239	
240	    os.makedirs('results', exist_ok=True)
241	    df.to_csv('results/exp013_boundary_condition.csv', index=False)
242	    df_summary.to_csv('results/exp013_boundary_summary.csv', index=False)
243	    print(f'Saved: results/exp013_boundary_condition.csv ({len(df)} rows)')
244	    print(f'Saved: results/exp013_boundary_summary.csv ({len(df_summary)} rows)')
245	
246	    analysis = write_analysis(df_summary)
247	    with open('results/exp013_boundary_analysis.md', 'w') as f:
248	        f.write(analysis)
249	    print(f'Saved: results/exp013_boundary_analysis.md')
250	
251	    print('\n' + analysis)
252	
253	
254	if __name__ == '__main__':
255	    main()
256	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "c918c81b-aa9d-4ef6-a379-15fa8860f758",
  "isSidechain": true,
  "promptId": "aeecb45f-e190-4fc9-9bb8-99f0f97968bf",
  "agentId": "a572c367cd941b852",
  "type": "user",
  "uuid": "e783f84d-9ce2-476a-9288-2e17705c7509",
  "sourceToolAssistantUUID": "c918c81b-aa9d-4ef6-a379-15fa8860f758",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/ec_hte_llm_annotation",
  "sessionId": "59df5acf-1bd1-4ab3-a49d-fb4a8872a123",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 19 · 2026-05-21T14:37:55.726Z_

<details><summary>↩ Tool result · `toolu_01CuBxTxUEWeVsGZqMEc6Xb8`</summary>

```text
1	#!/usr/bin/env python3
2	"""
3	exp001_hb_synthetic.py - Hierarchical Bayesian EC-HTE Synthetic Validation (exp-001)
4	
5	Compares confusion matrix estimators for CATE correction under heterogeneous
6	misclassification across subgroups:
7	  Oracle, Naive, Global-corrected, MLE (Laplace), HB Dirichlet (partial pooling)
8	
9	Input: Synthetic DGP parameters (regimes, expert budgets, subgroup counts)
10	Output: results/exp001_hb_results.csv, results/exp001_hb_diagnostics.csv
11	"""
12	
13	import argparse
14	import os
15	import sys
16	import time
17	import warnings
18	import numpy as np
19	import pandas as pd
20	from scipy.special import gammaln
21	from scipy.optimize import minimize_scalar
22	
23	warnings.filterwarnings('ignore')
24	
25	try:
26	    import pymc as pm
27	    import pytensor.tensor as pt
28	    import arviz as az
29	    HAS_PYMC = True
30	except ImportError:
31	    HAS_PYMC = False
32	
33	N = 5000
34	SUBGROUP_LABELS = {2: ['A', 'B'], 4: ['A', 'B', 'C', 'D']}
35	
36	REGIMES = {
37	    2: {
38	        'extreme':     {'misclass': [0.25, 0.05], 'tau_z1': 0.5, 'tau_z0': 0.1},
39	        'moderate':    {'misclass': [0.15, 0.10], 'tau_z1': 0.3, 'tau_z0': 0.15},
40	        'homogeneous': {'misclass': [0.12, 0.12], 'tau_z1': 0.25, 'tau_z0': 0.20},
41	    },
42	    4: {
43	        'extreme':     {'misclass': [0.30, 0.20, 0.10, 0.03], 'tau_z1': 0.5, 'tau_z0': 0.1},
44	        'moderate':    {'misclass': [0.20, 0.15, 0.10, 0.05], 'tau_z1': 0.3, 'tau_z0': 0.15},
45	        'homogeneous': {'misclass': [0.12, 0.12, 0.12, 0.12], 'tau_z1': 0.25, 'tau_z0': 0.20},
46	    },
47	}
48	
49	DEFAULT_N_EXPERTS = [50, 100, 250, 500, 1000, 2000]
50	DEFAULT_K_LIST = [2, 4]
51	
52	
53	# ── DGP ───────────────────────────────────────────────────────────────────────
54	
55	def generate_data(regime_params, n_expert, k, seed):
56	    rng = np.random.RandomState(seed)
57	    labels = SUBGROUP_LABELS[k]
58	    T = rng.binomial(1, 0.5, N)
59	    Z = rng.binomial(1, 0.5, N)
60	    S = rng.choice(labels, N, p=[1.0 / k] * k)
61	    X = rng.randn(N, 5)
62	    tau = np.where(Z == 1, regime_params['tau_z1'], regime_params['tau_z0'])
63	    Y = 1 + tau * T + 0.5 * X[:, 0] + rng.randn(N)
64	    mc_rates = np.zeros(N)
65	    for i, s in enumerate(labels):
66	        mc_rates[S == s] = regime_params['misclass'][i]
67	    Z_hat = np.where(rng.rand(N) < mc_rates, 1 - Z, Z)
68	    idx = rng.choice(N, min(n_expert, N), replace=False)
69	    expert_mask = np.zeros(N, dtype=bool)
70	    expert_mask[idx] = True
71	    return dict(T=T, Z=Z, Z_hat=Z_hat, S=S, X=X, Y=Y, tau=tau, expert_mask=expert_mask)
72	
73	
74	# ── Helpers ───────────────────────────────────────────────────────────────────
75	
76	def diff_in_means(Y, T, mask):
77	    t1, t0 = mask & (T == 1), mask & (T == 0)
78	    n1, n0 = t1.sum(), t0.sum()
79	    if n1 < 2 or n0 < 2:
80	        return np.nan, np.nan
81	    y1, y0 = Y[t1], Y[t0]
82	    return y1.mean() - y0.mean(), np.sqrt(y1.var(ddof=1) / n1 + y0.var(ddof=1) / n0)
83	
84	
85	def get_counts(z_true, z_hat, subgroups, labels):
86	    """Confusion matrix counts per subgroup: (k, 2, 2) = [subgroup, true_z, z_hat]."""
87	    k = len(labels)
88	    counts = np.zeros((k, 2, 2), dtype=int)
89	    for i, s in enumerate(labels):
90	        ms = subgroups == s
91	        for z in [0, 1]:
92	            mz = ms & (z_true == z)
93	            counts[i, z, 0] = (z_hat[mz] == 0).sum()
94	            counts[i, z, 1] = (z_hat[mz] == 1).sum()
95	    return counts
96	
97	
98	def build_mixing_matrix(C):
99	    """C[z, z_hat] → M[z_hat, z] via Bayes rule (assuming P(Z=0)=P(Z=1)=0.5).
100	
101	    NOTE: This assumes P(Z=0)=P(Z=1)=0.5, which is correct for this experiment's
102	    DGP. For general P(Z), use the version in exp007 that takes p_z and p_z_hat.
103	    """
104	    M = np.zeros((2, 2))
105	    for zh in [0, 1]:
106	        cs = C[0, zh] + C[1, zh]
107	        if cs > 0:
108	            M[zh, 0] = C[0, zh] / cs
109	            M[zh, 1] = C[1, zh] / cs
110	        else:
111	            M[zh, :] = 0.5
112	    return M
113	
114	
115	def invert_mixing(M, tau_obs, se_obs):
116	    det = np.linalg.det(M)
117	    if abs(det) < 1e-10:
118	        return tau_obs.copy(), se_obs.copy()
119	    Mi = np.linalg.inv(M)
120	    tau_c = Mi @ tau_obs
121	    se_c = np.sqrt(np.maximum(np.diag(Mi @ np.diag(se_obs ** 2) @ Mi.T), 0))
122	    return tau_c, se_c
123	
124	
125	def safe_invert_correction(M_s, tau_obs, cond_threshold=100, fallback='naive'):
126	    """Invert mixing matrix with condition number guard.
127	
128	    When cond(M_s) > threshold, matrix inversion is numerically unstable.
129	    Falls back to naive (no correction) to avoid catastrophic amplification.
130	    """
131	    cond = np.linalg.cond(M_s)
132	    if cond > cond_threshold:
133	        return tau_obs.copy()
134	    return np.linalg.solve(M_s, tau_obs)
135	
136	
137	def invert_mixing_safe(M, tau_obs, se_obs, cond_threshold=100):
138	    """Like invert_mixing but with condition number guard."""
139	    cond = np.linalg.cond(M)
140	    if cond > cond_threshold:
141	        return tau_obs.copy(), se_obs.copy()
142	    det = np.linalg.det(M)
143	    if abs(det) < 1e-10:
144	        return tau_obs.copy(), se_obs.copy()
145	    Mi = np.linalg.inv(M)
146	    tau_c = Mi @ tau_obs
147	    se_c = np.sqrt(np.maximum(np.diag(Mi @ np.diag(se_obs ** 2) @ Mi.T), 0))
148	    return tau_c, se_c
149	
150	
151	# ── Confusion Matrix Estimators ───────────────────────────────────────────────
152	
153	def estimate_cm_mle(counts, labels):
154	    """Per-subgroup MLE with Laplace smoothing (add-1)."""
155	    C = {}
156	    for i, s in enumerate(labels):
157	        C_s = np.zeros((2, 2))
158	        for z in [0, 1]:
159	            n = counts[i, z, :].sum()
160	            for zh in [0, 1]:
161	                C_s[z, zh] = (counts[i, z, zh] + 1) / (n + 2) if n > 0 else 0.5
162	        C[s] = C_s
163	    return C
164	
165	
166	def _dirmult_neg_ll(alpha, counts_z):
167	    """Negative log marginal likelihood for Dirichlet-Multinomial."""
168	    a = alpha / 2.0
169	    if a < 1e-10:
170	        return 1e10
171	    ll = 0.0
172	    for c0, c1 in counts_z:
173	        n = c0 + c1
174	        if n == 0:
175	            continue
176	        ll += gammaln(c0 + a) + gammaln(c1 + a) - gammaln(n + 2 * a)
177	        ll -= 2 * gammaln(a) - gammaln(2 * a)
178	    return -ll
179	
180	
181	def estimate_cm_hb_eb(counts, labels):
182	    """Empirical Bayes HB: optimize shared Dirichlet concentration, posterior mean."""
183	    k = len(labels)
184	    alpha_opt = np.zeros(2)
185	    for z in [0, 1]:
186	        cl = [(int(counts[i, z, 0]), int(counts[i, z, 1])) for i in range(k)]
187	        total = sum(c0 + c1 for c0, c1 in cl)
188	        if total == 0:
189	            alpha_opt[z] = 2.0
190	            continue
191	        res = minimize_scalar(
192	            lambda a: _dirmult_neg_ll(a, cl), bounds=(0.01, 500), method='bounded')
193	        alpha_opt[z] = res.x
194	
195	    C = {}
196	    for i, s in enumerate(labels):
197	        C_s = np.zeros((2, 2))
198	        for z in [0, 1]:
199	            a = alpha_opt[z] / 2.0
200	            n = counts[i, z, :].sum()
201	            d = n + 2 * a
202	            C_s[z, 0] = (counts[i, z, 0] + a) / d if d > 0 else 0.5
203	            C_s[z, 1] = (counts[i, z, 1] + a) / d if d > 0 else 0.5
204	        C[s] = C_s
205	
206	    diag = {'rhat_max': np.nan, 'ess_min': np.nan, 'divergent_count': 0,
207	            'runtime_seconds': 0.0, 'hb_method': 'eb',
208	            'alpha_0_z0': alpha_opt[0], 'alpha_0_z1': alpha_opt[1]}
209	    return C, diag
210	
211	
212	def _split_rhat(chains):
213	    """Split R-hat for a scalar parameter. chains: (n_chains, n_draws)."""
214	    parts = []
215	    for c in range(chains.shape[0]):
216	        half = chains.shape[1] // 2
217	        parts.append(chains[c, :half])
218	        parts.append(chains[c, half:2 * half])
219	    parts = np.array(parts)
220	    m = parts.shape[0]
221	    n = parts.shape[1]
222	    chain_means = parts.mean(axis=1)
223	    W = np.mean(np.var(parts, axis=1, ddof=1))
224	    B = n * np.var(chain_means, ddof=1)
225	    if W < 1e-20:
226	        return 1.0
227	    var_hat = (1 - 1.0 / n) * W + B / n
228	    return float(np.sqrt(var_hat / W))
229	
230	
231	def _bulk_ess(chains):
232	    """Approximate bulk ESS via initial positive sequence. chains: (n_chains, n_draws)."""
233	    x = chains.ravel()
234	    n = len(x)
235	    mu = x.mean()
236	    xc = x - mu
237	    max_lag = min(n // 2, 300)
238	    c0 = np.dot(xc, xc)
239	    if c0 < 1e-20:
240	        return float(n)
241	    tau = 1.0
242	    for lag in range(1, max_lag - 1, 2):
243	        r1 = np.dot(xc[:n - lag], xc[lag:]) / c0
244	        r2 = np.dot(xc[:n - lag - 1], xc[lag + 1:]) / c0 if lag + 1 < n else 0
245	        pair = r1 + r2
246	        if pair < 0:
247	            break
248	        tau += 2 * pair
249	    return float(n / tau)
250	
251	
252	def _fast_diagnostics(alpha_arr, theta_arr, labels):
253	    """Compute R-hat and ESS over all parameters without arviz."""
254	    rhats, esss = [], []
255	    for d in range(alpha_arr.shape[2]):
256	        rhats.append(_split_rhat(alpha_arr[:, :, d]))
257	        esss.append(_bulk_ess(alpha_arr[:, :, d]))
258	    k = len(labels)
259	    for i in range(k):
260	        for z in [0, 1]:
261	            for zh in range(theta_arr.shape[4]):
262	                ch = theta_arr[:, :, i, z, zh]
263	                rhats.append(_split_rhat(ch))
264	                esss.append(_bulk_ess(ch))
265	    return max(rhats), min(esss)
266	
267	
268	def _log_target_alpha(alpha, theta_z, hp_a0=3.0, hp_b0=1.0):
269	    """Log posterior for alpha_0[z] in log-alpha space (includes Jacobian)."""
270	    if alpha < 1e-10:
271	        return -1e10
272	    a = alpha / 2.0
273	    k = theta_z.shape[0]
274	    lp = (hp_a0 - 1.0) * np.log(alpha) - hp_b0 * alpha
275	    lp += k * (gammaln(alpha) - 2.0 * gammaln(a))
276	    lp += (a - 1.0) * np.sum(np.log(np.clip(theta_z, 1e-300, None)))
277	    return lp
278	
279	
280	def estimate_cm_hb_gibbs(counts, labels, seed=42, n_iter=4000, n_warmup=2000, n_chains=4,
281	                         hp_a0=3.0, hp_b0=1.0):
282	    """Gibbs sampler for HB Dirichlet-Multinomial (conjugate + adaptive MH for alpha_0).
283	
284	    hp_a0, hp_b0: Gamma hyperprior shape/rate on alpha_0 (default Gamma(3,1)).
285	    """
286	    k = len(labels)
287	    chain_inits_pool = [np.array([1.0, 1.0]), np.array([5.0, 5.0]),
288	                        np.array([0.5, 0.5]), np.array([10.0, 10.0])]
289	    chain_inits = chain_inits_pool[:n_chains]
290	    all_alpha, all_theta = [], []
291	    t0 = time.time()
292	
293	    for chain in range(n_chains):
294	        rng = np.random.RandomState(seed * 31 + chain * 7919 + 1)
295	        alpha = chain_inits[chain].copy()
296	        theta = np.ones((k, 2, 2)) * 0.5
297	        mh_scale = np.array([0.3, 0.3])
298	        accept_ct = np.array([0, 0])
299	        attempt_ct = np.array([0, 0])
300	
301	        alpha_samples = np.zeros((n_iter, 2))
302	        theta_samples = np.zeros((n_iter, k, 2, 2))
303	
304	        for it in range(n_warmup + n_iter):
305	            for z in [0, 1]:
306	                post_a = counts[:, z, :].astype(float) + alpha[z] / 2.0
307	                post_a = np.maximum(post_a, 1e-6)
308	                g = rng.gamma(post_a)
309	                g_sum = g.sum(axis=1, keepdims=True)
310	                theta[:, z, :] = g / np.maximum(g_sum, 1e-300)
311	
312	            for z in [0, 1]:
313	                x_prop = np.log(alpha[z]) + rng.normal(0, mh_scale[z])
314	                a_prop = np.exp(x_prop)
315	                log_r = (_log_target_alpha(a_prop, theta[:, z, :], hp_a0, hp_b0) -
316	                         _log_target_alpha(alpha[z], theta[:, z, :], hp_a0, hp_b0))
317	                accepted = np.log(rng.rand()) < log_r
318	                if accepted:
319	                    alpha[z] = a_prop
320	                if it < n_warmup:
321	                    accept_ct[z] += int(accepted)
322	                    attempt_ct[z] += 1
323	
324	            if it < n_warmup and it > 0 and it % 100 == 0:
325	                for z in [0, 1]:
326	                    rate = accept_ct[z] / max(attempt_ct[z], 1)
327	                    if rate < 0.2:
328	                        mh_scale[z] *= 0.7
329	                    elif rate > 0.5:
330	                        mh_scale[z] *= 1.3
331	                    accept_ct[z] = 0
332	                    attempt_ct[z] = 0
333	
334	            if it >= n_warmup:
335	                idx = it - n_warmup
336	                alpha_samples[idx] = alpha.copy()
337	                theta_samples[idx] = theta.copy()
338	
339	        all_alpha.append(alpha_samples)
340	        all_theta.append(theta_samples)
341	
342	    runtime = time.time() - t0
343	    alpha_arr = np.stack(all_alpha)
344	    theta_arr = np.stack(all_theta)
345	
346	    C = {}
347	    for i, s in enumerate(labels):
348	        C[s] = theta_arr[:, :, i, :, :].mean(axis=(0, 1))
349	
350	    rhat_max, ess_min = _fast_diagnostics(alpha_arr, theta_arr, labels)
351	
352	    diag = {'rhat_max': rhat_max, 'ess_min': ess_min, 'divergent_count': 0,
353	            'runtime_seconds': runtime, 'hb_method': 'gibbs'}
354	    return C, diag
355	
356	
357	def estimate_cm_hb_mcmc(counts, labels, seed=42, draws=1000, tune=500, chains=2):
358	    """Full Bayesian HB with PyMC MCMC."""
359	    k = len(labels)
360	    n_per_sz = counts.sum(axis=2)
361	
362	    with pm.Model():
363	        alpha_0 = pm.Gamma('alpha_0', alpha=2, beta=1, shape=2)
364	        for z in [0, 1]:
365	            for i, s in enumerate(labels):
366	                nsz = int(n_per_sz[i, z])
367	                if nsz == 0:
368	                    continue
369	                a = pt.stack([alpha_0[z] / 2, alpha_0[z] / 2])
370	                theta = pm.Dirichlet(f'theta_{s}_z{z}', a=a)
371	                pm.Multinomial(f'obs_{s}_z{z}', n=nsz, p=theta,
372	                               observed=counts[i, z, :].astype('int32'))
373	        t0 = time.time()
374	        trace = pm.sample(draws=draws, tune=tune, chains=chains,
375	                          random_seed=seed, progressbar=False)
376	        runtime = time.time() - t0
377	
378	    C = {}
379	    for i, s in enumerate(labels):
380	        C_s = np.zeros((2, 2))
381	        for z in [0, 1]:
382	            vn = f'theta_{s}_z{z}'
383	            if vn in trace.posterior:
384	                C_s[z, :] = trace.posterior[vn].values.mean(axis=(0, 1))
385	            else:
386	                C_s[z, :] = 0.5
387	        C[s] = C_s
388	
389	    all_vars = list(trace.posterior.data_vars)
390	    try:
391	        summ = az.summary(trace, var_names=all_vars)
392	        rhat_max = float(summ['r_hat'].max())
393	        ess_min = float(summ['ess_bulk'].min())
394	    except Exception:
395	        rhat_max = ess_min = np.nan
396	    try:
397	        divergent = int(trace.sample_stats['diverging'].values.sum())
398	    except Exception:
399	        divergent = -1
400	
401	    diag = {'rhat_max': rhat_max, 'ess_min': ess_min,
402	            'divergent_count': divergent, 'runtime_seconds': runtime,
403	            'hb_method': 'mcmc'}
404	    return C, diag
405	
406	
407	# ── Single MC Run ─────────────────────────────────────────────────────────────
408	
409	def run_one_mc(regime_name, regime_params, n_expert, k, seed, hb_method='eb'):
410	    data = generate_data(regime_params, n_expert, k, seed)
411	    Y, T, Z, Z_hat, S = data['Y'], data['T'], data['Z'], data['Z_hat'], data['S']
412	    em = data['expert_mask']
413	    labels = SUBGROUP_LABELS[k]
414	    tau_z0, tau_z1 = regime_params['tau_z0'], regime_params['tau_z1']
415	
416	    counts = get_counts(Z[em], Z_hat[em], S[em], labels)
417	
418	    C_mle = estimate_cm_mle(counts, labels)
419	
420	    if hb_method == 'gibbs':
421	        C_hb, hb_diag = estimate_cm_hb_gibbs(counts, labels, seed=seed)
422	    elif hb_method == 'mcmc' and HAS_PYMC:
423	        try:
424	            C_hb, hb_diag = estimate_cm_hb_mcmc(counts, labels, seed=seed)
425	        except Exception:
426	            C_hb, hb_diag = estimate_cm_hb_eb(counts, labels)
427	            hb_diag['hb_method'] = 'eb_fallback'
428	    else:
429	        C_hb, hb_diag = estimate_cm_hb_eb(counts, labels)
430	
431	    # Global CM (pool all expert labels, Laplace)
432	    cg = counts.sum(axis=0)
433	    C_gl = np.zeros((2, 2))
434	    for z in [0, 1]:
435	        n = cg[z, :].sum()
436	        for zh in [0, 1]:
437	            C_gl[z, zh] = (cg[z, zh] + 1) / (n + 2) if n > 0 else 0.5
438	
439	    M_gl = build_mixing_matrix(C_gl)
440	    M_mle = {s: build_mixing_matrix(C_mle[s]) for s in labels}
441	    M_hb = {s: build_mixing_matrix(C_hb[s]) for s in labels}
442	
443	    base = {'regime': regime_name, 'n_expert': n_expert, 'k_subgroups': k, 'mc_run': seed}
444	    rows = []
445	
446	    for s in labels:
447	        sm = S == s
448	        th0_or, se0_or = diff_in_means(Y, T, sm & (Z == 0))
449	        th1_or, se1_or = diff_in_means(Y, T, sm & (Z == 1))
450	        th0_n, se0_n = diff_in_means(Y, T, sm & (Z_hat == 0))
451	        th1_n, se1_n = diff_in_means(Y, T, sm & (Z_hat == 1))
452	
453	        tau_obs = np.array([th0_n, th1_n])
454	        se_obs = np.array([se0_n, se1_n])
455	        if np.any(np.isnan(tau_obs)):
456	            continue
457	
458	        tgc, sgc = invert_mixing(M_gl, tau_obs, se_obs)
459	        tml, sml = invert_mixing(M_mle[s], tau_obs, se_obs)
460	        thb, shb = invert_mixing(M_hb[s], tau_obs, se_obs)
461	
462	        def mr(method, th0, th1, se0, se1):
463	            return {**base, 'subgroup': s, 'method': method,
464	                    'tau_hat_z0': th0, 'tau_hat_z1': th1,
465	                    'se_z0': se0, 'se_z1': se1,
466	                    'tau_true_z0': tau_z0, 'tau_true_z1': tau_z1}
467	
468	        rows.append(mr('oracle', th0_or, th1_or, se0_or, se1_or))
469	        rows.append(mr('naive', th0_n, th1_n, se0_n, se1_n))
470	        rows.append(mr('global_corrected', tgc[0], tgc[1], sgc[0], sgc[1]))
471	        rows.append(mr('mle_laplace', tml[0], tml[1], sml[0], sml[1]))
472	        rows.append(mr('hb_dirichlet', thb[0], thb[1], shb[0], shb[1]))
473	
474	    return rows, {**base, **hb_diag}
475	
476	
477	# ── Aggregation ───────────────────────────────────────────────────────────────
478	
479	def aggregate_results(df):
480	    rows = []
481	    grp_cols = ['regime', 'n_expert', 'k_subgroups', 'subgroup', 'method']
482	    for keys, grp in df.groupby(grp_cols):
483	        regime, n_expert, k, subgroup, method = keys
484	        row = {'regime': regime, 'n_expert': int(n_expert), 'k_subgroups': int(k),
485	               'subgroup': subgroup, 'method': method}
486	        n_mc = len(grp)
487	        for z in ['z0', 'z1']:
488	            err = grp[f'tau_hat_{z}'].values - grp[f'tau_true_{z}'].values
489	            bias = err.mean()
490	            mse = (err ** 2).mean()
491	            rmse = np.sqrt(mse)
492	            ci_lo = grp[f'tau_hat_{z}'].values - 1.96 * grp[f'se_{z}'].values
493	            ci_hi = grp[f'tau_hat_{z}'].values + 1.96 * grp[f'se_{z}'].values
494	            cov = ((ci_lo <= grp[f'tau_true_{z}'].values) &
495	                   (grp[f'tau_true_{z}'].values <= ci_hi)).mean()
496	            row[f'bias_{z}'] = bias
497	            row[f'rmse_{z}'] = rmse
498	            row[f'coverage_{z}'] = cov
499	            row[f'bias_{z}_se'] = err.std() / np.sqrt(n_mc)
500	            mse_se = (err ** 2).std() / np.sqrt(n_mc)
501	            row[f'rmse_{z}_se'] = mse_se / (2 * rmse) if rmse > 1e-10 else np.nan
502	        rows.append(row)
503	    return pd.DataFrame(rows)
504	
505	
506	# ── Output ────────────────────────────────────────────────────────────────────
507	
508	def print_summary(df_agg, df_diag):
509	    pd.set_option('display.float_format', '{:.4f}'.format)
510	
511	    # MCMC / Gibbs diagnostics
512	    if 'hb_method' in df_diag.columns:
513	        for method_label in ['gibbs', 'mcmc']:
514	            mrows = df_diag[df_diag['hb_method'] == method_label]
515	            if mrows.empty:
516	                continue
517	            print(f"\n── {method_label.upper()} Diagnostics ──────────────────────────────")
518	            print(f"  Runs:           {len(mrows)}")
519	            rh = mrows['rhat_max'].dropna()
520	            es = mrows['ess_min'].dropna()
521	            if not rh.empty:
522	                print(f"  R-hat max:      {rh.max():.4f} (target < 1.01)")
523	            if not es.empty:
524	                print(f"  ESS min:        {es.min():.0f} (target > 200)")
525	            print(f"  Divergent total:{int(mrows['divergent_count'].sum())}")
526	            print(f"  Runtime median: {mrows['runtime_seconds'].median():.2f}s")
527	
528	    # Per-config HB vs MLE comparison
529	    print("\n── HB vs MLE RMSE Comparison (subgroup-level, averaged) ──")
530	    for k in sorted(df_agg['k_subgroups'].unique()):
531	        print(f"\n  K = {int(k)} subgroups")
532	        for regime in ['extreme', 'moderate', 'homogeneous']:
533	            sub = df_agg[(df_agg['k_subgroups'] == k) & (df_agg['regime'] == regime)]
534	            if sub.empty:
535	                continue
536	            print(f"    {regime}:")
537	            print(f"    {'n_exp':>6s}  {'oracle':>8s}  {'naive':>8s}  {'global':>8s}  "
538	                  f"{'mle':>8s}  {'hb':>8s}  {'HB vs MLE':>10s}")
539	            for ne in sorted(sub['n_expert'].unique()):
540	                vals = {}
541	                for m in ['oracle', 'naive', 'global_corrected', 'mle_laplace', 'hb_dirichlet']:
542	                    ms = sub[(sub['method'] == m) & (sub['n_expert'] == ne)]
543	                    if ms.empty:
544	                        vals[m] = np.nan
545	                    else:
546	                        vals[m] = np.sqrt((ms['rmse_z0'].values ** 2 +
547	                                           ms['rmse_z1'].values ** 2).mean())
548	                mle_v, hb_v = vals['mle_laplace'], vals['hb_dirichlet']
549	                pct = (mle_v - hb_v) / mle_v * 100 if mle_v > 1e-10 else 0
550	                tag = f"{pct:+.1f}%"
551	                print(f"    {int(ne):6d}  {vals['oracle']:8.4f}  {vals['naive']:8.4f}  "
552	                      f"{vals['global_corrected']:8.4f}  {mle_v:8.4f}  {hb_v:8.4f}  {tag:>10s}")
553	
554	
555	# ── Sweep ─────────────────────────────────────────────────────────────────────
556	
557	def run_sweep(regime_names, n_experts, k_list, n_mc,
558	              hb_method='eb', mcmc_diag_runs=5, verbose=True):
559	    all_rows, all_diag = [], []
560	    total = sum(1 for k in k_list for r in regime_names if r in REGIMES[k]) * len(n_experts) * n_mc
561	    count = 0
562	    t0 = time.time()
563	
564	    for k in k_list:
565	        for rn in regime_names:
566	            if rn not in REGIMES[k]:
567	                continue
568	            rp = REGIMES[k][rn]
569	            for ne in n_experts:
570	                for mc in range(n_mc):
571	                    use = hb_method
572	                    if hb_method == 'auto':
573	                        use = 'mcmc' if mc < mcmc_diag_runs else 'eb'
574	                    try:
575	                        rows, diag = run_one_mc(rn, rp, ne, k, seed=mc, hb_method=use)
576	                        all_rows.extend(rows)
577	                        all_diag.append(diag)
578	                    except Exception as e:
579	                        if verbose:
580	                            print(f"  WARN: k={k} {rn} ne={ne} mc={mc} failed: {e}")
581	                        all_diag.append({
582	                            'regime': rn, 'n_expert': ne, 'k_subgroups': k,
583	                            'mc_run': mc, 'hb_method': 'error',
584	                            'rhat_max': np.nan, 'ess_min': np.nan,
585	                            'divergent_count': -1, 'runtime_seconds': 0.0})
586	                    count += 1
587	                    if verbose and count % max(1, total // 20) == 0:
588	                        el = time.time() - t0
589	                        eta = el / count * (total - count)
590	                        print(f"  [{count}/{total}] {el:.0f}s elapsed, ETA {eta:.0f}s | "
591	                              f"k={k} {rn} ne={ne} mc={mc}")
592	
593	    if verbose:
594	        print(f"  Sweep done: {time.time() - t0:.1f}s ({count} runs)")
595	    return pd.DataFrame(all_rows), pd.DataFrame(all_diag)
596	
597	
598	# ── Main ──────────────────────────────────────────────────────────────────────
599	
600	if __name__ == '__main__':
601	    parser = argparse.ArgumentParser()
602	    parser.add_argument('--n-mc', type=int, default=100)
603	    parser.add_argument('--dry-run', action='store_true')
604	    parser.add_argument('--hb-method', choices=['auto', 'mcmc', 'gibbs', 'eb'], default='auto')
605	    parser.add_argument('--mcmc-diag-runs', type=int, default=5)
606	    args = parser.parse_args()
607	
608	    n_mc = 5 if args.dry_run else args.n_mc
609	    regime_names = ['moderate'] if args.dry_run else ['extreme', 'moderate', 'homogeneous']
610	    n_experts = [100] if args.dry_run else DEFAULT_N_EXPERTS
611	    k_list = [2] if args.dry_run else DEFAULT_K_LIST
612	
613	    print(f"exp-001 HB Synthetic Validation | PyMC={HAS_PYMC}")
614	    print(f"N={N} n_mc={n_mc} hb={args.hb_method}")
615	    print(f"Regimes={regime_names} n_experts={n_experts} K={k_list}\n")
616	
617	    # Timing test
618	    effective_method = args.hb_method
619	    d = generate_data(REGIMES[2]['moderate'], 100, 2, seed=9999)
620	    em = d['expert_mask']
621	    tc = get_counts(d['Z'][em], d['Z_hat'][em], d['S'][em], ['A', 'B'])
622	
623	    if args.hb_method == 'auto':
624	        print("Timing Gibbs sampler...")
625	        t0 = time.time()
626	        _, dg = estimate_cm_hb_gibbs(tc, ['A', 'B'], seed=9999)
627	        gt = time.time() - t0
628	        print(f"  Gibbs: {gt:.2f}s | rhat={dg['rhat_max']:.3f} "
629	              f"ess={dg['ess_min']:.0f}")
630	        if gt < 5:
631	            effective_method = 'gibbs'
632	            print(f"  Fast enough → using Gibbs for all runs")
633	        else:
634	            effective_method = 'eb'
635	            print(f"  Slow → using EB")
636	    elif args.hb_method == 'mcmc' and HAS_PYMC:
637	        print("Timing PyMC MCMC...")
638	        t0 = time.time()
639	        try:
640	            _, dg = estimate_cm_hb_mcmc(tc, ['A', 'B'], seed=9999)
641	            mt = time.time() - t0
642	            print(f"  MCMC: {mt:.1f}s | rhat={dg['rhat_max']:.3f} "
643	                  f"ess={dg['ess_min']:.0f} div={dg['divergent_count']}")
644	        except Exception as e:
645	            print(f"  MCMC failed: {e} → falling back to Gibbs")
646	            effective_method = 'gibbs'
647	
648	    print(f"\nEffective method: {effective_method}\n")
649	
650	    df_raw, df_diag = run_sweep(
651	        regime_names, n_experts, k_list, n_mc,
652	        hb_method=effective_method, mcmc_diag_runs=args.mcmc_diag_runs)
653	
654	    df_agg = aggregate_results(df_raw)
655	
656	    os.makedirs('results', exist_ok=True)
657	    agg_cols = ['regime', 'n_expert', 'k_subgroups', 'subgroup', 'method',
658	                'bias_z0', 'rmse_z0', 'coverage_z0', 'bias_z1', 'rmse_z1', 'coverage_z1',
659	                'bias_z0_se', 'rmse_z0_se', 'bias_z1_se', 'rmse_z1_se']
660	    df_agg[agg_cols].to_csv('results/exp001_hb_results.csv', index=False)
661	
662	    diag_cols = ['regime', 'n_expert', 'k_subgroups', 'mc_run',
663	                 'rhat_max', 'ess_min', 'divergent_count', 'runtime_seconds']
664	    save_cols = [c for c in diag_cols if c in df_diag.columns]
665	    if 'hb_method' in df_diag.columns:
666	        save_cols.insert(4, 'hb_method')
667	    df_diag[save_cols].to_csv('results/exp001_hb_diagnostics.csv', index=False)
668	
669	    print_summary(df_agg, df_diag)
670	
671	    print(f"\nSaved: results/exp001_hb_results.csv ({len(df_agg)} rows)")
672	    print(f"Saved: results/exp001_hb_diagnostics.csv ({len(df_diag)} rows)")
673	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "2e52baba-897f-4905-a223-3500cfe857aa",
  "isSidechain": true,
  "promptId": "aeecb45f-e190-4fc9-9bb8-99f0f97968bf",
  "agentId": "a572c367cd941b852",
  "type": "user",
  "uuid": "031dd767-5ba5-47bc-b05d-f54e3bce7286",
  "sourceToolAssistantUUID": "2e52baba-897f-4905-a223-3500cfe857aa",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/ec_hte_llm_annotation",
  "sessionId": "59df5acf-1bd1-4ab3-a49d-fb4a8872a123",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 20 · 2026-05-21T14:37:55.744Z_

<details><summary>↩ Tool result · `toolu_01EqZuVgtqU6i8RTKi89R2m8`</summary>

```text
1	"""
2	exp-003 Phase A v3: Semi-synthetic benchmark on TweetEval sentiment.
3	Uses real text data with simulated LLM misclassification to validate EC-HTE
4	on realistic subgroup structures.
5	
6	v3: Added HB Dirichlet (partial pooling) confusion matrix estimator from exp-001
7	    Gibbs sampler alongside stratified MLE to validate Claim 2.
8	
9	Input: TweetEval sentiment (cardiffnlp/tweet_eval, sentiment split)
10	Output: results/exp003_phase_a_v3.csv, results/exp003_phase_a_v3_raw.csv, results/exp003_dgp_spec.md
11	"""
12	
13	import sys
14	import time
15	import warnings
16	import numpy as np
17	import pandas as pd
18	from datasets import load_dataset
19	from scipy.special import gammaln
20	
21	warnings.filterwarnings('ignore')
22	
23	# === Config ===
24	
25	N = 5000
26	N_MC = 100
27	N_EXPERTS = [50, 100, 250, 500]
28	SEED_BASE = 42
29	
30	MISCLASS_RATES = {
31	    'extreme': {'S0': 0.05, 'S1': 0.10, 'S2': 0.15, 'S3': 0.25},
32	    'moderate': {'S0': 0.08, 'S1': 0.10, 'S2': 0.12, 'S3': 0.15},
33	    'homogeneous': {'S0': 0.10, 'S1': 0.10, 'S2': 0.10, 'S3': 0.10},
34	}
35	
36	DELTA_S = {'S0': 0.4, 'S1': 0.3, 'S2': 0.2, 'S3': 0.1}
37	TAU_Z0 = 0.1
38	ALPHA = 1.0
39	BETA_LENGTH = 0.3
40	BETA_MENTION = 0.2
41	SUBGROUP_LABELS = ['S0', 'S1', 'S2', 'S3']
42	
43	
44	# === Data Loading ===
45	
46	def load_tweeteval_pool():
47	    """Load and merge TweetEval sentiment train+test into a single pool."""
48	    ds = load_dataset('cardiffnlp/tweet_eval', 'sentiment')
49	    texts, labels = [], []
50	    for split in ['train', 'test']:
51	        for row in ds[split]:
52	            texts.append(row['text'])
53	            labels.append(row['label'])
54	    return texts, np.array(labels)
55	
56	
57	def extract_features(texts):
58	    """Extract subgroup features from tweet texts."""
59	    has_hashtag = np.array(['#' in t for t in texts], dtype=int)
60	    text_lengths = np.array([len(t) for t in texts])
61	    has_mention = np.array(['@' in t for t in texts], dtype=int)
62	    return has_hashtag, text_lengths, has_mention
63	
64	
65	def assign_subgroups(has_hashtag, text_length_bin):
66	    """Assign K=4 subgroups based on hashtag × text_length_bin."""
67	    S = np.empty(len(has_hashtag), dtype='U2')
68	    S[(has_hashtag == 0) & (text_length_bin == 0)] = 'S0'
69	    S[(has_hashtag == 0) & (text_length_bin == 1)] = 'S1'
70	    S[(has_hashtag == 1) & (text_length_bin == 0)] = 'S2'
71	    S[(has_hashtag == 1) & (text_length_bin == 1)] = 'S3'
72	    return S
73	
74	
75	# === Core Estimators (reused from MVP) ===
76	
77	def diff_in_means(Y, T, mask):
78	    t1 = mask & (T == 1)
79	    t0 = mask & (T == 0)
80	    n1, n0 = t1.sum(), t0.sum()
81	    if n1 < 2 or n0 < 2:
82	        return np.nan, np.nan
83	    y1, y0 = Y[t1], Y[t0]
84	    tau_hat = y1.mean() - y0.mean()
85	    se = np.sqrt(y1.var(ddof=1) / n1 + y0.var(ddof=1) / n0)
86	    return tau_hat, se
87	
88	
89	def estimate_confusion_matrix(z_true, z_hat):
90	    C = np.zeros((2, 2))
91	    for zt in [0, 1]:
92	        mask = z_true == zt
93	        n = mask.sum()
94	        for zh in [0, 1]:
95	            C[zt, zh] = ((z_hat[mask] == zh).sum() + 1) / (n + 2) if n > 0 else 0.5
96	    return C
97	
98	
99	def build_mixing_matrix(C, p_z, p_z_hat):
100	    """M[z_hat, z] = P(Z=z | Z_hat=z_hat) via Bayes' rule.
101	
102	    Args:
103	        C: 2x2 confusion matrix, C[z, z_hat] = P(Z_hat=z_hat | Z=z)
104	        p_z: array [P(Z=0), P(Z=1)] - marginal distribution of true Z
105	        p_z_hat: array [P(Z_hat=0), P(Z_hat=1)] - marginal distribution of Z_hat
106	    """
107	    M = np.zeros((2, 2))
108	    for zh in [0, 1]:
109	        for z in [0, 1]:
110	            M[zh, z] = C[z, zh] * p_z[z] / p_z_hat[zh] if p_z_hat[zh] > 0 else 0.5
111	    return M
112	
113	
114	def invert_mixing_safe(M, tau_obs, se_obs, cond_threshold=100):
115	    """Like invert_mixing but with condition number guard."""
116	    cond = np.linalg.cond(M)
117	    if cond > cond_threshold:
118	        return tau_obs.copy(), se_obs.copy()
119	    det = np.linalg.det(M)
120	    if abs(det) < 1e-10:
121	        return tau_obs.copy(), se_obs.copy()
122	    Mi = np.linalg.inv(M)
123	    tau_c = Mi @ tau_obs
124	    se_c = np.sqrt(np.maximum(np.diag(Mi @ np.diag(se_obs ** 2) @ Mi.T), 0))
125	    return tau_c, se_c
126	
127	
128	# === HB Gibbs Sampler (from exp-001) ===
129	
130	def get_counts(z_true, z_hat, subgroups, labels):
131	    k = len(labels)
132	    counts = np.zeros((k, 2, 2), dtype=int)
133	    for i, s in enumerate(labels):
134	        ms = subgroups == s
135	        for z in [0, 1]:
136	            mz = ms & (z_true == z)
137	            counts[i, z, 0] = (z_hat[mz] == 0).sum()
138	            counts[i, z, 1] = (z_hat[mz] == 1).sum()
139	    return counts
140	
141	
142	def _split_rhat(chains):
143	    parts = []
144	    for c in range(chains.shape[0]):
145	        half = chains.shape[1] // 2
146	        parts.append(chains[c, :half])
147	        parts.append(chains[c, half:2 * half])
148	    parts = np.array(parts)
149	    m = parts.shape[0]
150	    n = parts.shape[1]
151	    chain_means = parts.mean(axis=1)
152	    W = np.mean(np.var(parts, axis=1, ddof=1))
153	    B = n * np.var(chain_means, ddof=1)
154	    if W < 1e-20:
155	        return 1.0
156	    var_hat = (1 - 1.0 / n) * W + B / n
157	    return float(np.sqrt(var_hat / W))
158	
159	
160	def _bulk_ess(chains):
161	    x = chains.ravel()
162	    n = len(x)
163	    mu = x.mean()
164	    xc = x - mu
165	    max_lag = min(n // 2, 300)
166	    c0 = np.dot(xc, xc)
167	    if c0 < 1e-20:
168	        return float(n)
169	    tau = 1.0
170	    for lag in range(1, max_lag - 1, 2):
171	        r1 = np.dot(xc[:n - lag], xc[lag:]) / c0
172	        r2 = np.dot(xc[:n - lag - 1], xc[lag + 1:]) / c0 if lag + 1 < n else 0
173	        pair = r1 + r2
174	        if pair < 0:
175	            break
176	        tau += 2 * pair
177	    return float(n / tau)
178	
179	
180	def _fast_diagnostics(alpha_arr, theta_arr, labels):
181	    rhats, esss = [], []
182	    for d in range(alpha_arr.shape[2]):
183	        rhats.append(_split_rhat(alpha_arr[:, :, d]))
184	        esss.append(_bulk_ess(alpha_arr[:, :, d]))
185	    k = len(labels)
186	    for i in range(k):
187	        for z in [0, 1]:
188	            for zh in range(theta_arr.shape[4]):
189	                ch = theta_arr[:, :, i, z, zh]
190	                rhats.append(_split_rhat(ch))
191	                esss.append(_bulk_ess(ch))
192	    return max(rhats), min(esss)
193	
194	
195	def _log_target_alpha(alpha, theta_z, hp_a0=3.0, hp_b0=1.0):
196	    if alpha < 1e-10:
197	        return -1e10
198	    a = alpha / 2.0
199	    k = theta_z.shape[0]
200	    lp = (hp_a0 - 1.0) * np.log(alpha) - hp_b0 * alpha
201	    lp += k * (gammaln(alpha) - 2.0 * gammaln(a))
202	    lp += (a - 1.0) * np.sum(np.log(np.clip(theta_z, 1e-300, None)))
203	    return lp
204	
205	
206	def estimate_cm_hb_gibbs(counts, labels, seed=42, n_iter=4000, n_warmup=2000, n_chains=4,
207	                         hp_a0=3.0, hp_b0=1.0):
208	    k = len(labels)
209	    chain_inits_pool = [np.array([1.0, 1.0]), np.array([5.0, 5.0]),
210	                        np.array([0.5, 0.5]), np.array([10.0, 10.0])]
211	    chain_inits = chain_inits_pool[:n_chains]
212	    all_alpha, all_theta = [], []
213	    t0 = time.time()
214	
215	    for chain in range(n_chains):
216	        rng = np.random.RandomState(seed * 31 + chain * 7919 + 1)
217	        alpha = chain_inits[chain].copy()
218	        theta = np.ones((k, 2, 2)) * 0.5
219	        mh_scale = np.array([0.3, 0.3])
220	        accept_ct = np.array([0, 0])
221	        attempt_ct = np.array([0, 0])
222	
223	        alpha_samples = np.zeros((n_iter, 2))
224	        theta_samples = np.zeros((n_iter, k, 2, 2))
225	
226	        for it in range(n_warmup + n_iter):
227	            for z in [0, 1]:
228	                post_a = counts[:, z, :].astype(float) + alpha[z] / 2.0
229	                post_a = np.maximum(post_a, 1e-6)
230	                g = rng.gamma(post_a)
231	                g_sum = g.sum(axis=1, keepdims=True)
232	                theta[:, z, :] = g / np.maximum(g_sum, 1e-300)
233	
234	            for z in [0, 1]:
235	                x_prop = np.log(alpha[z]) + rng.normal(0, mh_scale[z])
236	                a_prop = np.exp(x_prop)
237	                log_r = (_log_target_alpha(a_prop, theta[:, z, :], hp_a0, hp_b0) -
238	                         _log_target_alpha(alpha[z], theta[:, z, :], hp_a0, hp_b0))
239	                accepted = np.log(rng.rand()) < log_r
240	                if accepted:
241	                    alpha[z] = a_prop
242	                if it < n_warmup:
243	                    accept_ct[z] += int(accepted)
244	                    attempt_ct[z] += 1
245	
246	            if it < n_warmup and it > 0 and it % 100 == 0:
247	                for z in [0, 1]:
248	                    rate = accept_ct[z] / max(attempt_ct[z], 1)
249	                    if rate < 0.2:
250	                        mh_scale[z] *= 0.7
251	                    elif rate > 0.5:
252	                        mh_scale[z] *= 1.3
253	                    accept_ct[z] = 0
254	                    attempt_ct[z] = 0
255	
256	            if it >= n_warmup:
257	                idx = it - n_warmup
258	                alpha_samples[idx] = alpha.copy()
259	                theta_samples[idx] = theta.copy()
260	
261	        all_alpha.append(alpha_samples)
262	        all_theta.append(theta_samples)
263	
264	    runtime = time.time() - t0
265	    alpha_arr = np.stack(all_alpha)
266	    theta_arr = np.stack(all_theta)
267	
268	    C = {}
269	    for i, s in enumerate(labels):
270	        C[s] = theta_arr[:, :, i, :, :].mean(axis=(0, 1))
271	
272	    rhat_max, ess_min = _fast_diagnostics(alpha_arr, theta_arr, labels)
273	
274	    diag = {'rhat_max': rhat_max, 'ess_min': ess_min, 'divergent_count': 0,
275	            'runtime_seconds': runtime, 'hb_method': 'gibbs'}
276	    return C, diag
277	
278	
279	# === DGP ===
280	
281	def sample_from_pool(pool_texts, pool_labels, pool_has_hashtag, pool_text_lengths,
282	                     pool_has_mention, n, rng):
283	    """Sample n observations with approximate label balance from the pool."""
284	    idx_neg = np.where(pool_labels == 0)[0]
285	    idx_neu = np.where(pool_labels == 1)[0]
286	    idx_pos = np.where(pool_labels == 2)[0]
287	
288	    per_class = n // 3
289	    remainder = n - 3 * per_class
290	
291	    chosen_neg = rng.choice(idx_neg, per_class, replace=len(idx_neg) < per_class)
292	    chosen_neu = rng.choice(idx_neu, per_class, replace=len(idx_neu) < per_class)
293	    chosen_pos = rng.choice(idx_pos, per_class + remainder, replace=len(idx_pos) < per_class + remainder)
294	    idx = np.concatenate([chosen_neg, chosen_neu, chosen_pos])
295	    rng.shuffle(idx)
296	
297	    return (
298	        [pool_texts[i] for i in idx],
299	        pool_labels[idx],
300	        pool_has_hashtag[idx],
301	        pool_text_lengths[idx],
302	        pool_has_mention[idx],
303	    )
304	
305	
306	def generate_data(pool_texts, pool_labels, pool_has_hashtag, pool_text_lengths,
307	                  pool_has_mention, misclass_config, n_expert, seed):
308	    """Generate one MC dataset: sample tweets, assign Z, simulate misclass + outcome."""
309	    rng = np.random.RandomState(seed)
310	
311	    texts, labels, has_hashtag, text_lengths, has_mention = sample_from_pool(
312	        pool_texts, pool_labels, pool_has_hashtag, pool_text_lengths,
313	        pool_has_mention, N, rng
314	    )
315	
316	    median_len = np.median(text_lengths)
317	    text_length_bin = (text_lengths > median_len).astype(int)
318	
319	    S = assign_subgroups(has_hashtag, text_length_bin)
320	
321	    # Z: effect modifier from sentiment
322	    Z = (np.array(labels) == 2).astype(int)  # positive=1, else=0
323	
324	    # Misclassification
325	    mc_rates = np.array([misclass_config[s] for s in S])
326	    flip = rng.rand(N) < mc_rates
327	    Z_hat = np.where(flip, 1 - Z, Z)
328	
329	    # Treatment assignment (RCT)
330	    T = rng.binomial(1, 0.5, N)
331	
332	    # Outcome
333	    text_length_norm = (text_lengths - text_lengths.mean()) / (text_lengths.std() + 1e-8)
334	    delta_s = np.array([DELTA_S[s] for s in S])
335	    tau = np.where(Z == 1, TAU_Z0 + delta_s, TAU_Z0)
336	    eps = rng.randn(N)
337	    Y = ALPHA + tau * T + BETA_LENGTH * text_length_norm + BETA_MENTION * has_mention + eps
338	
339	    # Expert mask
340	    expert_idx = rng.choice(N, n_expert, replace=False)
341	    expert_mask = np.zeros(N, dtype=bool)
342	    expert_mask[expert_idx] = True
343	
344	    return {
345	        'T': T, 'Z': Z, 'Z_hat': Z_hat, 'S': S, 'Y': Y, 'tau': tau,
346	        'expert_mask': expert_mask, 'has_hashtag': has_hashtag,
347	        'text_length_bin': text_length_bin, 'text_lengths': text_lengths,
348	        'has_mention': has_mention, 'labels': np.array(labels),
349	    }
350	
351	
352	# === MC Runner ===
353	
354	def run_one_mc(data, regime_name, n_expert, seed):
355	    """Run one MC iteration: all methods × all subgroups + marginal."""
356	    Y, T, Z, Z_hat, S = data['Y'], data['T'], data['Z'], data['Z_hat'], data['S']
357	    expert_mask = data['expert_mask']
358	
359	    z_exp = Z[expert_mask]
360	    zh_exp = Z_hat[expert_mask]
361	    s_exp = S[expert_mask]
362	
363	    # Global marginals for mixing matrix
364	    p_z_global = np.array([(z_exp == 0).mean(), (z_exp == 1).mean()])
365	    p_zh_global = np.array([(Z_hat == 0).mean(), (Z_hat == 1).mean()])
366	
367	    # Global confusion matrix
368	    C_global = estimate_confusion_matrix(z_exp, zh_exp)
369	    M_global = build_mixing_matrix(C_global, p_z_global, p_zh_global)
370	
371	    # Per-subgroup confusion matrices
372	    C_sub, M_sub = {}, {}
373	    for s_val in SUBGROUP_LABELS:
374	        sm_exp = (s_exp == s_val)
375	        sm_all = (S == s_val)
376	        if sm_exp.sum() >= 4:
377	            C_sub[s_val] = estimate_confusion_matrix(z_exp[sm_exp], zh_exp[sm_exp])
378	            p_z_s = np.array([(z_exp[sm_exp] == 0).mean(), (z_exp[sm_exp] == 1).mean()])
379	        else:
380	            C_sub[s_val] = C_global
381	            p_z_s = p_z_global
382	        p_zh_s = np.array([(Z_hat[sm_all] == 0).mean(), (Z_hat[sm_all] == 1).mean()])
383	        M_sub[s_val] = build_mixing_matrix(C_sub[s_val], p_z_s, p_zh_s)
384	
385	    # HB Dirichlet confusion matrices (partial pooling via Gibbs sampler)
386	    counts = get_counts(z_exp, zh_exp, s_exp, SUBGROUP_LABELS)
387	    C_hb, _ = estimate_cm_hb_gibbs(counts, SUBGROUP_LABELS, seed=seed)
388	
389	    M_hb_sub = {}
390	    for s_val in SUBGROUP_LABELS:
391	        sm_exp = (s_exp == s_val)
392	        sm_all = (S == s_val)
393	        if sm_exp.sum() >= 4:
394	            p_z_s = np.array([(z_exp[sm_exp] == 0).mean(), (z_exp[sm_exp] == 1).mean()])
395	        else:
396	            p_z_s = p_z_global
397	        p_zh_s = np.array([(Z_hat[sm_all] == 0).mean(), (Z_hat[sm_all] == 1).mean()])
398	        M_hb_sub[s_val] = build_mixing_matrix(C_hb[s_val], p_z_s, p_zh_s)
399	
400	    # True tau per subgroup
401	    true_tau = {}
402	    for s_val in SUBGROUP_LABELS:
403	        true_tau[s_val] = {
404	            'z0': TAU_Z0,
405	            'z1': TAU_Z0 + DELTA_S[s_val],
406	        }
407	
408	    base = {'regime': regime_name, 'n_expert': n_expert, 'mc_run': seed}
409	    rows = []
410	
411	    def make_row(method, level, th0, th1, se0, se1, true_z0, true_z1):
412	        ci_lo0 = th0 - 1.96 * se0 if not np.isnan(se0) else np.nan
413	        ci_hi0 = th0 + 1.96 * se0 if not np.isnan(se0) else np.nan
414	        ci_lo1 = th1 - 1.96 * se1 if not np.isnan(se1) else np.nan
415	        ci_hi1 = th1 + 1.96 * se1 if not np.isnan(se1) else np.nan
416	        return {
417	            **base, 'method': method, 'level': level,
418	            'tau_hat_z0': th0, 'tau_hat_z1': th1,
419	            'tau_true_z0': true_z0, 'tau_true_z1': true_z1,
420	            'ci_lower_z0': ci_lo0, 'ci_upper_z0': ci_hi0,
421	            'ci_lower_z1': ci_lo1, 'ci_upper_z1': ci_hi1,
422	        }
423	
424	    # --- Subgroup-level estimates ---
425	    sub_obs, sub_se_obs = {}, {}
426	    sub_corrected_strat, sub_se_strat = {}, {}
427	    sub_corrected_hb, sub_se_hb = {}, {}
428	    sub_n = {}
429	
430	    for s_val in SUBGROUP_LABELS:
431	        s_mask = S == s_val
432	        sub_n[s_val] = s_mask.sum()
433	
434	        th0_obs, se0_obs = diff_in_means(Y, T, s_mask & (Z_hat == 0))
435	        th1_obs, se1_obs = diff_in_means(Y, T, s_mask & (Z_hat == 1))
436	        sub_obs[s_val] = np.array([th0_obs, th1_obs])
437	        sub_se_obs[s_val] = np.array([se0_obs, se1_obs])
438	
439	        tau_strat, se_strat = invert_mixing_safe(M_sub[s_val], sub_obs[s_val], sub_se_obs[s_val])
440	        sub_corrected_strat[s_val] = tau_strat
441	        sub_se_strat[s_val] = se_strat
442	
443	        tz0 = true_tau[s_val]['z0']
444	        tz1 = true_tau[s_val]['z1']
445	
446	        # Oracle
447	        th0_or, se0_or = diff_in_means(Y, T, s_mask & (Z == 0))
448	        th1_or, se1_or = diff_in_means(Y, T, s_mask & (Z == 1))
449	        rows.append(make_row('oracle', s_val, th0_or, th1_or, se0_or, se1_or, tz0, tz1))
450	
451	        # Naive
452	        rows.append(make_row('naive', s_val, th0_obs, th1_obs, se0_obs, se1_obs, tz0, tz1))
453	
454	        # Global-corrected
455	        if not np.any(np.isnan(sub_obs[s_val])):
456	            tau_gc, se_gc = invert_mixing_safe(M_global, sub_obs[s_val], sub_se_obs[s_val])
457	            rows.append(make_row('global_corrected', s_val, tau_gc[0], tau_gc[1], se_gc[0], se_gc[1], tz0, tz1))
458	        else:
459	            rows.append(make_row('global_corrected', s_val, np.nan, np.nan, np.nan, np.nan, tz0, tz1))
460	
461	        # Stratified MLE (= ec_hte placeholder)
462	        rows.append(make_row('stratified_mle', s_val, tau_strat[0], tau_strat[1], se_strat[0], se_strat[1], tz0, tz1))
463	
464	        # HB EC-HTE (partial pooling)
465	        tau_hb, se_hb = invert_mixing_safe(M_hb_sub[s_val], sub_obs[s_val], sub_se_obs[s_val])
466	        sub_corrected_hb[s_val] = tau_hb
467	        sub_se_hb[s_val] = se_hb
468	        rows.append(make_row('hb_ec_hte', s_val, tau_hb[0], tau_hb[1], se_hb[0], se_hb[1], tz0, tz1))
469	
470	    # --- Marginal-level estimates ---
471	    # True marginal tau: weighted average across subgroups
472	    total_n = sum(sub_n.values())
473	    w = {s: sub_n[s] / total_n for s in SUBGROUP_LABELS}
474	
475	    true_z0_marg = TAU_Z0
476	    true_z1_marg = TAU_Z0 + sum(w[s] * DELTA_S[s] for s in SUBGROUP_LABELS)
477	
478	    # Oracle marginal
479	    th0_or, se0_or = diff_in_means(Y, T, Z == 0)
480	    th1_or, se1_or = diff_in_means(Y, T, Z == 1)
481	    rows.append(make_row('oracle', 'marginal', th0_or, th1_or, se0_or, se1_or, true_z0_marg, true_z1_marg))
482	
483	    # Naive marginal
484	    th0_naive, se0_naive = diff_in_means(Y, T, Z_hat == 0)
485	    th1_naive, se1_naive = diff_in_means(Y, T, Z_hat == 1)
486	    rows.append(make_row('naive', 'marginal', th0_naive, th1_naive, se0_naive, se1_naive, true_z0_marg, true_z1_marg))
487	
488	    # Global-corrected marginal
489	    tau_gc_m, se_gc_m = invert_mixing_safe(M_global, np.array([th0_naive, th1_naive]), np.array([se0_naive, se1_naive]))
490	    rows.append(make_row('global_corrected', 'marginal', tau_gc_m[0], tau_gc_m[1], se_gc_m[0], se_gc_m[1], true_z0_marg, true_z1_marg))
491	
492	    # Stratified MLE marginal: weighted average of subgroup-corrected
493	    tau_strat_m = sum(w[s] * sub_corrected_strat[s] for s in SUBGROUP_LABELS)
494	    se_strat_m = np.sqrt(sum((w[s] * sub_se_strat[s]) ** 2 for s in SUBGROUP_LABELS))
495	    rows.append(make_row('stratified_mle', 'marginal', tau_strat_m[0], tau_strat_m[1], se_strat_m[0], se_strat_m[1], true_z0_marg, true_z1_marg))
496	
497	    # HB EC-HTE marginal: weighted average of subgroup-corrected (HB)
498	    tau_hb_m = sum(w[s] * sub_corrected_hb[s] for s in SUBGROUP_LABELS)
499	    se_hb_m = np.sqrt(sum((w[s] * sub_se_hb[s]) ** 2 for s in SUBGROUP_LABELS))
500	    rows.append(make_row('hb_ec_hte', 'marginal', tau_hb_m[0], tau_hb_m[1], se_hb_m[0], se_hb_m[1], true_z0_marg, true_z1_marg))
501	
502	    return rows
503	
504	
505	def aggregate_results(df):
506	    rows = []
507	    group_cols = ['regime', 'n_expert', 'method', 'level']
508	    for keys, grp in df.groupby(group_cols):
509	        row = dict(zip(group_cols, keys))
510	        for z in ['z0', 'z1']:
511	            err = grp[f'tau_hat_{z}'] - grp[f'tau_true_{z}']
512	            valid = err.dropna()
513	            if len(valid) == 0:
514	                row.update({f'bias_{z}': np.nan, f'rmse_{z}': np.nan, f'coverage_{z}': np.nan})
515	                continue
516	            row[f'bias_{z}'] = valid.mean()
517	            row[f'rmse_{z}'] = np.sqrt((valid ** 2).mean())
518	            covered = ((grp[f'ci_lower_{z}'] <= grp[f'tau_true_{z}']) &
519	                       (grp[f'tau_true_{z}'] <= grp[f'ci_upper_{z}'])).mean()
520	            row[f'coverage_{z}'] = covered
521	            row[f'bias_{z}_se'] = valid.std() / np.sqrt(len(valid))
522	        rows.append(row)
523	    return pd.DataFrame(rows)
524	
525	
526	def write_dgp_spec(pool_texts, pool_labels, pool_has_hashtag, pool_text_lengths):
527	    """Write DGP specification document."""
528	    n_total = len(pool_labels)
529	    n_neg = (pool_labels == 0).sum()
530	    n_neu = (pool_labels == 1).sum()
531	    n_pos = (pool_labels == 2).sum()
532	    pct_hashtag = pool_has_hashtag.mean() * 100
533	    median_len = np.median(pool_text_lengths)
534	
535	    spec = f"""# exp-003 Phase A: DGP Specification
536	
537	## Data Source
538	- **Dataset**: TweetEval sentiment (cardiffnlp/tweet_eval, sentiment split)
539	- **Reference**: Barbieri et al. (2020)
540	- **Pool size**: {n_total} tweets (train + test merged)
541	- **Label distribution**: negative={n_neg} ({n_neg/n_total*100:.1f}%), neutral={n_neu} ({n_neu/n_total*100:.1f}%), positive={n_pos} ({n_pos/n_total*100:.1f}%)
542	
543	## Sampling Strategy
544	- Each MC run samples N={N} tweets with approximate label balance (~{N//3} per class)
545	- Sampling with replacement from pool (pool size >> N, minimal collision)
546	
547	## Subgroup Definition (K=4)
548	
549	Two binary features define 4 subgroups:
550	
551	| Feature | Definition | Rationale |
552	|---------|-----------|-----------|
553	| `has_hashtag` | Text contains '#' | Hashtags shift LLM attention; informal/emphatic language may increase misclassification |
554	| `text_length_bin` | Above/below median length ({median_len:.0f} chars) | Longer texts provide more context but also more noise for sentiment classification |
555	
556	| Subgroup | has_hashtag | text_length_bin | Approx. proportion |
557	|----------|-------------|-----------------|---------------------|
558	| S0 | 0 (no) | 0 (short) | ~{(1-pool_has_hashtag.mean())*(pool_text_lengths<=median_len).mean()*100:.0f}% |
559	| S1 | 0 (no) | 1 (long) | ~{(1-pool_has_hashtag.mean())*(pool_text_lengths>median_len).mean()*100:.0f}% |
560	| S2 | 1 (yes) | 0 (short) | ~{pool_has_hashtag.mean()*(pool_text_lengths<=median_len).mean()*100:.0f}% |
561	| S3 | 1 (yes) | 1 (long) | ~{pool_has_hashtag.mean()*(pool_text_lengths>median_len).mean()*100:.0f}% |
562	
563	Prevalence of hashtag: {pct_hashtag:.1f}%
564	
565	## Effect Modifier Z
566	- Z=1 if sentiment == positive (label 2)
567	- Z=0 if sentiment != positive (label 0 or 1)
568	- P(Z=1) ≈ {n_pos/n_total*100:.1f}%
569	
570	## Misclassification Rates (Symmetric, A2 Assumption)
571	
572	P(Z_hat ≠ Z | S=s) = π_s
573	
574	| Regime | S0 | S1 | S2 | S3 | Rationale |
575	|--------|----|----|----|----|-----------|
576	| extreme | 0.05 | 0.10 | 0.15 | 0.25 | Large heterogeneity; hashtag texts are harder |
577	| moderate | 0.08 | 0.10 | 0.12 | 0.15 | Modest gradient |
578	| homogeneous | 0.10 | 0.10 | 0.10 | 0.10 | Null hypothesis (no heterogeneity) |
579	
580	Rates are informed by typical LLM sentiment accuracy on tweets (85-95% in literature),
581	with the gradient reflecting empirical findings that informal/hashtag-heavy text
582	degrades classifier performance.
583	
584	## Outcome Model
585	
586	Y = α + τ(Z, S) · T + β₁ · text_length_normalized + β₂ · has_mention + ε
587	
588	| Parameter | Value | Rationale |
589	|-----------|-------|-----------|
590	| α | {ALPHA} | Intercept |
591	| τ(Z=0, all S) | {TAU_Z0} | Baseline treatment effect |
592	| δ_S0 | {DELTA_S['S0']} | Additional effect for Z=1 in S0 |
593	| δ_S1 | {DELTA_S['S1']} | Additional effect for Z=1 in S1 |
594	| δ_S2 | {DELTA_S['S2']} | Additional effect for Z=1 in S2 |
595	| δ_S3 | {DELTA_S['S3']} | Additional effect for Z=1 in S3 |
596	| β₁ | {BETA_LENGTH} | Text length effect (normalized) |
597	| β₂ | {BETA_MENTION} | Mention (@) effect |
598	| ε | N(0, 1) | Noise |
599	| T | Bernoulli(0.5) | RCT |
600	
601	τ(Z=1, S=s) = {TAU_Z0} + δ_s, so treatment effects range from {TAU_Z0 + DELTA_S['S3']} (S3) to {TAU_Z0 + DELTA_S['S0']} (S0).
602	
603	## Expert Annotation
604	- n_expert ∈ {{{', '.join(str(x) for x in N_EXPERTS)}}}
605	- Randomly selected observations with both Z and Z_hat observed
606	
607	## Difference from Pure Synthetic DGP (MVP/exp-001/exp-002)
608	1. **Real text features**: Subgroups come from actual tweet characteristics, not random assignment
609	2. **Correlated subgroup sizes**: Subgroup proportions are data-driven and unbalanced
610	3. **Real covariates in outcome model**: text_length and has_mention are real text features
611	4. **Non-uniform Z prevalence**: P(Z=1) ≈ {n_pos/n_total*100:.1f}%, not 50%
612	5. **Subgroup-covariate correlation**: Text length correlates with hashtag presence and sentiment
613	"""
614	    with open('results/exp003_dgp_spec.md', 'w') as f:
615	        f.write(spec)
616	    print("Wrote results/exp003_dgp_spec.md")
617	
618	
619	# === Main ===
620	
621	if __name__ == '__main__':
622	    n_mc = int(sys.argv[1]) if len(sys.argv) > 1 else N_MC
623	
624	    print(f"exp-003 Phase A: Semi-synthetic benchmark on TweetEval sentiment")
625	    print(f"N={N}, N_MC={n_mc}, N_EXPERTS={N_EXPERTS}")
626	    print(f"Regimes: {list(MISCLASS_RATES.keys())}")
627	    print(f"Methods: oracle, naive, global_corrected, stratified_mle, hb_ec_hte")
628	    print()
629	
630	    # Load pool once
631	    print("Loading TweetEval sentiment dataset...")
632	    t_load = time.time()
633	    pool_texts, pool_labels = load_tweeteval_pool()
634	    pool_has_hashtag, pool_text_lengths, pool_has_mention = extract_features(pool_texts)
635	    print(f"  Pool size: {len(pool_texts)}, loaded in {time.time()-t_load:.1f}s")
636	    print(f"  Labels: neg={sum(pool_labels==0)}, neu={sum(pool_labels==1)}, pos={sum(pool_labels==2)}")
637	    print(f"  Hashtag prevalence: {pool_has_hashtag.mean()*100:.1f}%")
638	    print(f"  Median text length: {np.median(pool_text_lengths):.0f}")
639	    print()
640	
641	    # Write DGP spec
642	    write_dgp_spec(pool_texts, pool_labels, pool_has_hashtag, pool_text_lengths)
643	
644	    # Run MC simulation
645	    results = []
646	    configs = []
647	    for regime_name in MISCLASS_RATES:
648	        for ne in N_EXPERTS:
649	            configs.append((regime_name, ne))
650	
651	    total = len(configs) * n_mc
652	    count = 0
653	    t0 = time.time()
654	
655	    for regime_name, ne in configs:
656	        misclass_config = MISCLASS_RATES[regime_name]
657	        for mc in range(n_mc):
658	            seed = SEED_BASE + mc
659	            data = generate_data(
660	                pool_texts, pool_labels, pool_has_hashtag, pool_text_lengths,
661	                pool_has_mention, misclass_config, ne, seed
662	            )
663	            mc_rows = run_one_mc(data, regime_name, ne, seed)
664	            results.extend(mc_rows)
665	            count += 1
666	            if count % max(1, total // 20) == 0:
667	                elapsed = time.time() - t0
668	                eta = elapsed / count * (total - count)
669	                print(f"  [{count}/{total}] {elapsed:.0f}s elapsed, ETA {eta:.0f}s | {regime_name} ne={ne}")
670	
671	    elapsed = time.time() - t0
672	    print(f"\nTotal MC time: {elapsed:.1f}s")
673	
674	    df_raw = pd.DataFrame(results)
675	    df_agg = aggregate_results(df_raw)
676	
677	    # Save
678	    raw_path = 'results/exp003_phase_a_v3_raw.csv'
679	    agg_path = 'results/exp003_phase_a_v3.csv'
680	    df_raw.to_csv(raw_path, index=False)
681	    df_agg.to_csv(agg_path, index=False)
682	    print(f"Saved: {raw_path} ({len(df_raw)} rows)")
683	    print(f"Saved: {agg_path} ({len(df_agg)} rows)")
684	
685	    # Print summary
686	    pd.set_option('display.max_columns', 20)
687	    pd.set_option('display.width', 260)
688	    pd.set_option('display.float_format', '{:.4f}'.format)
689	
690	    for regime in MISCLASS_RATES:
691	        print(f"\n{'='*180}")
692	        pi = MISCLASS_RATES[regime]
693	        print(f"Regime: {regime} | misclass: S0={pi['S0']}, S1={pi['S1']}, S2={pi['S2']}, S3={pi['S3']}")
694	        print(f"{'='*180}")
695	        for level in ['marginal'] + SUBGROUP_LABELS:
696	            sub = df_agg[(df_agg['regime'] == regime) & (df_agg['level'] == level)]
697	            if sub.empty:
698	                continue
699	            sub = sub.sort_values(['n_expert', 'method'])
700	            cols = ['n_expert', 'method', 'level', 'bias_z0', 'rmse_z0', 'coverage_z0', 'bias_z1', 'rmse_z1', 'coverage_z1']
701	            print(sub[cols].to_string(index=False))
702	            print()
703	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "12d5f48d-d74e-4452-86eb-b50cab73adf7",
  "isSidechain": true,
  "promptId": "aeecb45f-e190-4fc9-9bb8-99f0f97968bf",
  "agentId": "a572c367cd941b852",
  "type": "user",
  "uuid": "64aa34c6-add5-485d-b0a2-6bd0e11c6891",
  "sourceToolAssistantUUID": "12d5f48d-d74e-4452-86eb-b50cab73adf7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/ec_hte_llm_annotation",
  "sessionId": "59df5acf-1bd1-4ab3-a49d-fb4a8872a123",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 21 · 2026-05-21T14:37:58.217Z_

Perfect! Now let me also check the markdown spec file for exp003 that was mentioned:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "64aa34c6-add5-485d-b0a2-6bd0e11c6891",
  "isSidechain": true,
  "agentId": "a572c367cd941b852",
  "requestId": "req_011CbFtFJbnW2HgZ1RJ2sa76",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "48190531-0324-4c2c-8c64-791512e914e3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/ec_hte_llm_annotation",
  "sessionId": "59df5acf-1bd1-4ab3-a49d-fb4a8872a123",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_017FwFbz8vCyprPgvtRybgDe",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 4798,
      "cache_creation_input_tokens": 29038,
      "cache_read_input_tokens": 21010,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 29038,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool call

_source line 22 · 2026-05-21T14:37:58.672Z_

<details open><summary>🔧 Tool call — Read · `toolu_01A6ASpX1XsrpfGXfWZqeZqo`</summary>

```json
{
  "file_path": "/home/ubuntu/ec_hte_llm_annotation/results/exp003_dgp_spec.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "48190531-0324-4c2c-8c64-791512e914e3",
  "isSidechain": true,
  "agentId": "a572c367cd941b852",
  "requestId": "req_011CbFtFJbnW2HgZ1RJ2sa76",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "d6169b0d-0881-4880-a7b7-3bd728867c89",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/ec_hte_llm_annotation",
  "sessionId": "59df5acf-1bd1-4ab3-a49d-fb4a8872a123",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_017FwFbz8vCyprPgvtRybgDe",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 4798,
      "cache_creation_input_tokens": 29038,
      "cache_read_input_tokens": 21010,
      "output_tokens": 98,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 29038
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 4798,
          "output_tokens": 98,
          "cache_read_input_tokens": 21010,
          "cache_creation_input_tokens": 29038,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 29038,
            "ephemeral_1h_input_tokens": 0
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

_source line 23 · 2026-05-21T14:37:58.676Z_

<details><summary>↩ Tool result · `toolu_01A6ASpX1XsrpfGXfWZqeZqo`</summary>

```text
1	# exp-003 Phase A: DGP Specification
2	
3	## Data Source
4	- **Dataset**: TweetEval sentiment (cardiffnlp/tweet_eval, sentiment split)
5	- **Reference**: Barbieri et al. (2020)
6	- **Pool size**: 57899 tweets (train + test merged)
7	- **Label distribution**: negative=11065 (19.1%), neutral=26610 (46.0%), positive=20224 (34.9%)
8	
9	## Sampling Strategy
10	- Each MC run samples N=5000 tweets with approximate label balance (~1666 per class)
11	- Sampling with replacement from pool (pool size >> N, minimal collision)
12	
13	## Subgroup Definition (K=4)
14	
15	Two binary features define 4 subgroups:
16	
17	| Feature | Definition | Rationale |
18	|---------|-----------|-----------|
19	| `has_hashtag` | Text contains '#' | Hashtags shift LLM attention; informal/emphatic language may increase misclassification |
20	| `text_length_bin` | Above/below median length (110 chars) | Longer texts provide more context but also more noise for sentiment classification |
21	
22	| Subgroup | has_hashtag | text_length_bin | Approx. proportion |
23	|----------|-------------|-----------------|---------------------|
24	| S0 | 0 (no) | 0 (short) | ~39% |
25	| S1 | 0 (no) | 1 (long) | ~38% |
26	| S2 | 1 (yes) | 0 (short) | ~12% |
27	| S3 | 1 (yes) | 1 (long) | ~11% |
28	
29	Prevalence of hashtag: 23.1%
30	
31	## Effect Modifier Z
32	- Z=1 if sentiment == positive (label 2)
33	- Z=0 if sentiment != positive (label 0 or 1)
34	- P(Z=1) ≈ 34.9%
35	
36	## Misclassification Rates (Symmetric, A2 Assumption)
37	
38	P(Z_hat ≠ Z | S=s) = π_s
39	
40	| Regime | S0 | S1 | S2 | S3 | Rationale |
41	|--------|----|----|----|----|-----------|
42	| extreme | 0.05 | 0.10 | 0.15 | 0.25 | Large heterogeneity; hashtag texts are harder |
43	| moderate | 0.08 | 0.10 | 0.12 | 0.15 | Modest gradient |
44	| homogeneous | 0.10 | 0.10 | 0.10 | 0.10 | Null hypothesis (no heterogeneity) |
45	
46	Rates are informed by typical LLM sentiment accuracy on tweets (85-95% in literature),
47	with the gradient reflecting empirical findings that informal/hashtag-heavy text
48	degrades classifier performance.
49	
50	## Outcome Model
51	
52	Y = α + τ(Z, S) · T + β₁ · text_length_normalized + β₂ · has_mention + ε
53	
54	| Parameter | Value | Rationale |
55	|-----------|-------|-----------|
56	| α | 1.0 | Intercept |
57	| τ(Z=0, all S) | 0.1 | Baseline treatment effect |
58	| δ_S0 | 0.4 | Additional effect for Z=1 in S0 |
59	| δ_S1 | 0.3 | Additional effect for Z=1 in S1 |
60	| δ_S2 | 0.2 | Additional effect for Z=1 in S2 |
61	| δ_S3 | 0.1 | Additional effect for Z=1 in S3 |
62	| β₁ | 0.3 | Text length effect (normalized) |
63	| β₂ | 0.2 | Mention (@) effect |
64	| ε | N(0, 1) | Noise |
65	| T | Bernoulli(0.5) | RCT |
66	
67	τ(Z=1, S=s) = 0.1 + δ_s, so treatment effects range from 0.2 (S3) to 0.5 (S0).
68	
69	## Expert Annotation
70	- n_expert ∈ {50, 100, 250, 500}
71	- Randomly selected observations with both Z and Z_hat observed
72	
73	## Difference from Pure Synthetic DGP (MVP/exp-001/exp-002)
74	1. **Real text features**: Subgroups come from actual tweet characteristics, not random assignment
75	2. **Correlated subgroup sizes**: Subgroup proportions are data-driven and unbalanced
76	3. **Real covariates in outcome model**: text_length and has_mention are real text features
77	4. **Non-uniform Z prevalence**: P(Z=1) ≈ 34.9%, not 50%
78	5. **Subgroup-covariate correlation**: Text length correlates with hashtag presence and sentiment
79	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d6169b0d-0881-4880-a7b7-3bd728867c89",
  "isSidechain": true,
  "promptId": "aeecb45f-e190-4fc9-9bb8-99f0f97968bf",
  "agentId": "a572c367cd941b852",
  "type": "user",
  "uuid": "87ca2537-eeb8-4076-b0de-950cef011bd8",
  "sourceToolAssistantUUID": "d6169b0d-0881-4880-a7b7-3bd728867c89",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/ec_hte_llm_annotation",
  "sessionId": "59df5acf-1bd1-4ab3-a49d-fb4a8872a123",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 24 · 2026-05-21T14:38:14.345Z_

Excellent! Now I have all the information needed. Let me compile the confusion matrix parameters for all three experiments.

## Summary of Confusion Matrix / Misclassification Parameters

Based on my search of the codebase, here are the exact parameters used in the three simulation experiments:

---

### **EXP-001: Hierarchical Bayesian Synthetic Validation**

**Source**: `/home/ubuntu/ec_hte_llm_annotation/exp001_hb_synthetic.py`

**Misclassification Rates (Symmetric, A2 Assumption)**:
- **Per-subgroup** (asymmetric across subgroups, symmetric within each)
- **Regime: extreme (K=2)**
  - Subgroup A: 0.25
  - Subgroup B: 0.05
  
- **Regime: moderate (K=2)**
  - Subgroup A: 0.15
  - Subgroup B: 0.10
  
- **Regime: homogeneous (K=2)**
  - Subgroup A: 0.12
  - Subgroup B: 0.12

- **Regime: extreme (K=4)**
  - Subgroup A: 0.30
  - Subgroup B: 0.20
  - Subgroup C: 0.10
  - Subgroup D: 0.03
  
- **Regime: moderate (K=4)**
  - Subgroup A: 0.20
  - Subgroup B: 0.15
  - Subgroup C: 0.10
  - Subgroup D: 0.05
  
- **Regime: homogeneous (K=4)**
  - Subgroup A: 0.12
  - Subgroup B: 0.12
  - Subgroup C: 0.12
  - Subgroup D: 0.12

**P(Z=1)**: 0.5 (uniform, from `Z = rng.binomial(1, 0.5, N)` at line 59)

**K values**: 2, 4 (K=subgroups; see `DEFAULT_K_LIST = [2, 4]` at line 50)

**Confusion Matrix Structure**:
- Estimated per-subgroup (stratified), not global
- Confusion matrix definition: `C[z, z_hat]` = P(Z_hat=z_hat | Z=z)
- Estimated via MLE with Laplace smoothing (add-1) and HB Dirichlet (partial pooling via Gibbs sampler)
- Mixing matrix computed as: `M[z_hat, z] = C[z, z_hat] / sum_z(C[z, z_hat])` (assuming P(Z=0)=P(Z=1)=0.5)

---

### **EXP-003: Semi-synthetic Benchmark on TweetEval Sentiment**

**Source**: `/home/ubuntu/ec_hte_llm_annotation/exp003_tweeteval.py` and `/home/ubuntu/ec_hte_llm_annotation/results/exp003_dgp_spec.md`

**Misclassification Rates (Symmetric, A2 Assumption)**:
- **Per-subgroup** (asymmetric across subgroups)
- **Regime: extreme**
  - S0: 0.05
  - S1: 0.10
  - S2: 0.15
  - S3: 0.25
  
- **Regime: moderate**
  - S0: 0.08
  - S1: 0.10
  - S2: 0.12
  - S3: 0.15
  
- **Regime: homogeneous**
  - S0: 0.10
  - S1: 0.10
  - S2: 0.10
  - S3: 0.10

**P(Z=1)**: 0.349 (34.9%, computed from pool: Z=1 if sentiment == positive; `P(Z=1) ≈ 34.9%` per spec)

**K values**: 4 (subgroups defined by hashtag presence × text length binary features)

**Confusion Matrix Structure**:
- Estimated per-subgroup (stratified)
- Confusion matrix definition: `C[zt, zh]` = P(Z_hat=zh | Z=zt) with add-1 Laplace smoothing
- Mixing matrix computed with general Bayes rule: `M[zh, z] = C[z, zh] * P(Z=z) / P(Z_hat=zh)` (handling non-uniform Z)
- Estimated via MLE (stratified per-subgroup) and HB Dirichlet (Gibbs sampler for partial pooling)

---

### **EXP-013: Boundary Condition Test**

**Source**: `/home/ubuntu/ec_hte_llm_annotation/exp013_boundary_condition.py`

**Config**:
- **K**: 4 (subgroups)
- **Regime**: extreme
- **Regime parameters** (from exp001 REGIMES[4]['extreme']):
  - Misclass: [0.30, 0.20, 0.10, 0.03]
  - Subgroup A: 0.30
  - Subgroup B: 0.20
  - Subgroup C: 0.10
  - Subgroup D: 0.03

**P(Z=1)**: 0.5 (uniform, from synthetic DGP: `Z = rng.binomial(1, 0.5, N)`)

**Confusion Matrix Structure**:
- Per-subgroup (stratified)
- Same structure as exp-001: `C[z, z_hat]` with `M[z_hat, z]` computed assuming P(Z=0)=P(Z=1)=0.5
- Estimated via MLE (Laplace smoothing) and HB EB (Empirical Bayes with Dirichlet-Multinomial)
- Note: boundary condition = n_expert=50 with K=4, so ~12.5 labels per subgroup (high variance regime)

---

**Key Differences Across Experiments**:

| Aspect | exp-001 | exp-003 | exp-013 |
|--------|---------|---------|---------|
| **Data** | Pure synthetic | Semi-synthetic (real TweetEval text) | Pure synthetic |
| **Rates** | Asymmetric per-subgroup, K∈{2,4} | Asymmetric per-subgroup, K=4 | Asymmetric per-subgroup, K=4 |
| **P(Z=1)** | 0.5 (uniform) | 0.349 (non-uniform) | 0.5 (uniform) |
| **CM Estimators** | MLE, HB Dirichlet Gibbs, HB EB | MLE (stratified), HB Dirichlet Gibbs | MLE, HB EB |
| **Expert labels** | 50, 100, 250, 500, 1000, 2000 | 50, 100, 250, 500 | 50 (boundary condition) |

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "87ca2537-eeb8-4076-b0de-950cef011bd8",
  "isSidechain": true,
  "agentId": "a572c367cd941b852",
  "requestId": "req_011CbFtFXp2nPUdeXW3hMHRf",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "fe2ac380-f401-409b-9ce9-8155ee048433",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/ec_hte_llm_annotation",
  "sessionId": "59df5acf-1bd1-4ab3-a49d-fb4a8872a123",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01EvX4m3nq6uJEEL9g2JhRv6",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 5,
      "cache_creation_input_tokens": 6288,
      "cache_read_input_tokens": 50048,
      "output_tokens": 1775,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 6288
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 5,
          "output_tokens": 1775,
          "cache_read_input_tokens": 50048,
          "cache_creation_input_tokens": 6288,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 6288,
            "ephemeral_1h_input_tokens": 0
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
