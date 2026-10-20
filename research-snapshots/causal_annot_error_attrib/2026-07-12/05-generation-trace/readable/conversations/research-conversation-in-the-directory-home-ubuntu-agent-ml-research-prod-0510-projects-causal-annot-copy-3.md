# Research conversation: In the directory /home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib, find the Python file(s) t

**Multi-Class Annotation Errors in Causal Inference: Topology-Dependent Bias, Sensitivity, and Correction (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 16
- **Recorded user turns:** 1
- **Tool calls:** 6
- **Original source:** `logs/chats/exported-trajectories/account-1/agent-a4ddc290a1e5d82db.jsonl`
- **Structured JSON:** [`86c245fed26f165af7cd.json`](../../sessions/86/86c245fed26f165af7cd.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Round 1

16 recorded events

### User

_source line 1 · 2026-05-22T11:10:07.465Z_

In the directory /home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib, find the Python file(s) that contain the functions `make_dgp_params` and `compute_plim`. Also find `_BETA_POOL`. These are referenced as being in plan006_asv_empirical.py but the file may be at a different location. Search broadly across artifacts/ and the project root.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": true,
  "promptId": "417df0a2-cc01-4fb5-9f46-ee96dfc8be6b",
  "agentId": "a4ddc290a1e5d82db",
  "type": "user",
  "uuid": "707bae4f-4fc5-4864-9200-3dcb32ce02b9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "ba945ca1-7c3c-4181-a307-80decba09cd0",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 2 · 2026-05-22T11:10:08.909Z_

I'll search for these functions and variables across the project directory structure.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "707bae4f-4fc5-4864-9200-3dcb32ce02b9",
  "isSidechain": true,
  "agentId": "a4ddc290a1e5d82db",
  "requestId": "req_011CbHWD8ZS8xLSt29F1fdVi",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "88522f1b-dfea-4c60-8ad1-034a83f6f419",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "ba945ca1-7c3c-4181-a307-80decba09cd0",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01UZB429X15qX1XquZvXbwhZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 17860,
      "cache_read_input_tokens": 0,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 17860,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 3,
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

_source line 3 · 2026-05-22T11:10:09.340Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01GBUHvJv1LPAGdFaUHGJ8fk`</summary>

```json
{
  "pattern": "**/*.py",
  "path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "88522f1b-dfea-4c60-8ad1-034a83f6f419",
  "isSidechain": true,
  "agentId": "a4ddc290a1e5d82db",
  "requestId": "req_011CbHWD8ZS8xLSt29F1fdVi",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "8bb3846b-bbe2-4372-8cd2-f6bdc9689f7c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "ba945ca1-7c3c-4181-a307-80decba09cd0",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01UZB429X15qX1XquZvXbwhZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 17860,
      "cache_read_input_tokens": 0,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 17860,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 3,
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

_source line 4 · 2026-05-22T11:10:09.357Z_

<details><summary>↩ Tool result · `toolu_01GBUHvJv1LPAGdFaUHGJ8fk`</summary>

```text
artifacts/_project/data/mvp_confounding_dag.py
artifacts/mvp_confounding_dag.py
artifacts/_project/data/mvp_exposure_dag.py
artifacts/mvp_exposure_dag.py
artifacts/_project/report/mvp_exposure_dirichlet_subspace.py
artifacts/mvp_exposure_dirichlet_subspace.py
artifacts/preprocess.py
plan_001_collider_mbias_iv.py
plan_001_mediation_frontdoor.py
patch_metrics.py
plan_008_binarization_collapse.py
artifacts/plan008_binarization_collapse/report/plan_008_binarization_collapse.py
plan_005_asv_extended.py
artifacts/plan_005_asv_extended_fixed.py
plan_002_k57_extension.py
artifacts/plan_002_k57_extended_7topo.py
figures/paper/gen_fig4.py
artifacts/plan_009_pathological_matrices.py
figures/paper/gen_fig1.py
plan_009_pathological_matrices.py
plan_007_correction_guidance.py
figures/paper/gen_fig3.py
figures/paper/gen_fig2.py
plan_006_asv_empirical.py
annot_sensitivity/utils.py
annot_sensitivity/confusion.py
annot_sensitivity/dgp.py
annot_sensitivity/asv.py
annot_sensitivity/correction.py
annot_sensitivity/__init__.py
annot_sensitivity/examples/confounding_k3.py
annot_sensitivity/tests/__init__.py
annot_sensitivity/bias.py
annot_sensitivity/tests/test_core.py
artifacts/mvp_iv_dirichlet_subspace.py
artifacts/nondiff_stress_test.py
figures/paper/gen_diagnostic_plots.py
artifacts/compute_theory_empirical_mape.py
figures/paper/gen_fig7.py
plan_010_ppi_empirical_validation.py
artifacts/compute_all_tasks.py
artifacts/compute_ppi_empirical.py
artifacts/plan011_frontier_annotations/scripts/prepare_data.py
artifacts/plan011_frontier_annotations/scripts/annotate_frontier.py
artifacts/_project/intermediate/case_study_analysis.py
artifacts/plan012_case_study/case_study_analysis.py
artifacts/plan011_frontier_annotations/scripts/compute_results.py
artifacts/compute_delta_max.py
artifacts/annotate.py
artifacts/compute_updated_empirical.py
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "8bb3846b-bbe2-4372-8cd2-f6bdc9689f7c",
  "isSidechain": true,
  "promptId": "417df0a2-cc01-4fb5-9f46-ee96dfc8be6b",
  "agentId": "a4ddc290a1e5d82db",
  "type": "user",
  "uuid": "c0af6684-0105-4c31-82ce-e02e42a11289",
  "sourceToolAssistantUUID": "8bb3846b-bbe2-4372-8cd2-f6bdc9689f7c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "ba945ca1-7c3c-4181-a307-80decba09cd0",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-22T11:10:09.610Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01KZKtycV4LvHC2kF4yV27Xd`</summary>

```json
{
  "pattern": "def make_dgp_params",
  "path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "type": "py"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c0af6684-0105-4c31-82ce-e02e42a11289",
  "isSidechain": true,
  "agentId": "a4ddc290a1e5d82db",
  "requestId": "req_011CbHWD8ZS8xLSt29F1fdVi",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "caa27786-bee1-4066-9416-be47cd9f49e9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "ba945ca1-7c3c-4181-a307-80decba09cd0",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01UZB429X15qX1XquZvXbwhZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 17860,
      "cache_read_input_tokens": 0,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 17860,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 3,
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

_source line 6 · 2026-05-22T11:10:09.633Z_

<details><summary>↩ Tool result · `toolu_01KZKtycV4LvHC2kF4yV27Xd`</summary>

```text
Found 2 files
artifacts/compute_ppi_empirical.py
plan_006_asv_empirical.py
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "caa27786-bee1-4066-9416-be47cd9f49e9",
  "isSidechain": true,
  "promptId": "417df0a2-cc01-4fb5-9f46-ee96dfc8be6b",
  "agentId": "a4ddc290a1e5d82db",
  "type": "user",
  "uuid": "5f097793-b18a-463b-8184-a05d5536f6d3",
  "sourceToolAssistantUUID": "caa27786-bee1-4066-9416-be47cd9f49e9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "ba945ca1-7c3c-4181-a307-80decba09cd0",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-22T11:10:10.000Z_

<details open><summary>🔧 Tool call — Grep · `toolu_015X3uank3hyjDwGYjySrUCu`</summary>

```json
{
  "pattern": "def compute_plim",
  "path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "type": "py"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5f097793-b18a-463b-8184-a05d5536f6d3",
  "isSidechain": true,
  "agentId": "a4ddc290a1e5d82db",
  "requestId": "req_011CbHWD8ZS8xLSt29F1fdVi",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "75fe7125-69bf-439d-a92e-4fc2b295c39c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "ba945ca1-7c3c-4181-a307-80decba09cd0",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01UZB429X15qX1XquZvXbwhZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 17860,
      "cache_read_input_tokens": 0,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 17860,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 3,
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

_source line 8 · 2026-05-22T11:10:10.018Z_

<details><summary>↩ Tool result · `toolu_015X3uank3hyjDwGYjySrUCu`</summary>

```text
Found 1 file
plan_006_asv_empirical.py
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "75fe7125-69bf-439d-a92e-4fc2b295c39c",
  "isSidechain": true,
  "promptId": "417df0a2-cc01-4fb5-9f46-ee96dfc8be6b",
  "agentId": "a4ddc290a1e5d82db",
  "type": "user",
  "uuid": "de650822-ff4e-4438-90fe-a1bc59f4622b",
  "sourceToolAssistantUUID": "75fe7125-69bf-439d-a92e-4fc2b295c39c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "ba945ca1-7c3c-4181-a307-80decba09cd0",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-22T11:10:10.199Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01JRYf3TqP12ekLPw6ahdPqc`</summary>

```json
{
  "pattern": "_BETA_POOL",
  "path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "type": "py"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "de650822-ff4e-4438-90fe-a1bc59f4622b",
  "isSidechain": true,
  "agentId": "a4ddc290a1e5d82db",
  "requestId": "req_011CbHWD8ZS8xLSt29F1fdVi",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "2d7d7da3-409d-4024-8456-f23708d283bf",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "ba945ca1-7c3c-4181-a307-80decba09cd0",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01UZB429X15qX1XquZvXbwhZ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 17860,
      "cache_read_input_tokens": 0,
      "output_tokens": 416,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 17860
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 416,
          "cache_read_input_tokens": 0,
          "cache_creation_input_tokens": 17860,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 17860,
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

_source line 10 · 2026-05-22T11:10:10.220Z_

<details><summary>↩ Tool result · `toolu_01JRYf3TqP12ekLPw6ahdPqc`</summary>

```text
Found 7 files
artifacts/compute_ppi_empirical.py
plan_010_ppi_empirical_validation.py
plan_006_asv_empirical.py
plan_009_pathological_matrices.py
artifacts/plan_009_pathological_matrices.py
artifacts/plan_002_k57_extended_7topo.py
plan_002_k57_extension.py
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "2d7d7da3-409d-4024-8456-f23708d283bf",
  "isSidechain": true,
  "promptId": "417df0a2-cc01-4fb5-9f46-ee96dfc8be6b",
  "agentId": "a4ddc290a1e5d82db",
  "type": "user",
  "uuid": "236b79d8-5f33-4ec0-9eff-fcfd8ab27650",
  "sourceToolAssistantUUID": "2d7d7da3-409d-4024-8456-f23708d283bf",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "ba945ca1-7c3c-4181-a307-80decba09cd0",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 11 · 2026-05-22T11:10:11.636Z_

Good, I found references to the functions. Now let me read the main file and the compute_ppi_empirical.py file to get the exact locations and definitions:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "236b79d8-5f33-4ec0-9eff-fcfd8ab27650",
  "isSidechain": true,
  "agentId": "a4ddc290a1e5d82db",
  "requestId": "req_011CbHWDLG9AE6JT8m4LDgkQ",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "333cf45e-1d27-4ee3-a0da-c41d3de70d9a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "ba945ca1-7c3c-4181-a307-80decba09cd0",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01CaGgLrcpberLLNBLGhcKLU",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 7,
      "cache_creation_input_tokens": 2125,
      "cache_read_input_tokens": 17860,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 2125,
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

_source line 12 · 2026-05-22T11:10:12.464Z_

<details open><summary>🔧 Tool call — Read · `toolu_01KqSYqU9Q572sUckq9uUA4t`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/plan_006_asv_empirical.py"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "333cf45e-1d27-4ee3-a0da-c41d3de70d9a",
  "isSidechain": true,
  "agentId": "a4ddc290a1e5d82db",
  "requestId": "req_011CbHWDLG9AE6JT8m4LDgkQ",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "51bcb46c-8751-4c79-a803-201cc9f181ad",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "ba945ca1-7c3c-4181-a307-80decba09cd0",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01CaGgLrcpberLLNBLGhcKLU",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 7,
      "cache_creation_input_tokens": 2125,
      "cache_read_input_tokens": 17860,
      "output_tokens": 204,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 2125
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 7,
          "output_tokens": 204,
          "cache_read_input_tokens": 17860,
          "cache_creation_input_tokens": 2125,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 2125,
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

### Tool call

_source line 13 · 2026-05-22T11:10:12.489Z_

<details open><summary>🔧 Tool call — Read · `toolu_01KAjUY7MY7z6gxLeg3oE3YU`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/compute_ppi_empirical.py"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "51bcb46c-8751-4c79-a803-201cc9f181ad",
  "isSidechain": true,
  "agentId": "a4ddc290a1e5d82db",
  "requestId": "req_011CbHWDLG9AE6JT8m4LDgkQ",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "850a9867-a36f-46cf-95a7-b04c810d20be",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "ba945ca1-7c3c-4181-a307-80decba09cd0",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01CaGgLrcpberLLNBLGhcKLU",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 7,
      "cache_creation_input_tokens": 2125,
      "cache_read_input_tokens": 17860,
      "output_tokens": 204,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 2125
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 7,
          "output_tokens": 204,
          "cache_read_input_tokens": 17860,
          "cache_creation_input_tokens": 2125,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 2125,
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

_source line 14 · 2026-05-22T11:10:12.496Z_

<details><summary>↩ Tool result · `toolu_01KAjUY7MY7z6gxLeg3oE3YU`</summary>

```text
1	#!/usr/bin/env python3
2	"""
3	Empirical Correction Validation — HumAID K=10
4	
5	Loads 8 valid HumAID confusion matrices from asv_empirical_results.json,
6	generates synthetic MC data using plan_006's K=10 DGP for each of 7 topologies,
7	runs all 5 correction methods (PPI++, naive plug-in, DSL, MC-SIMEX, MLA),
8	and reports empirical bias reduction per topology × method.
9	
10	Input:  artifacts/plan006/asv_empirical_results.json
11	Output: artifacts/ppi_empirical_validation.json
12	
13	Dependencies: numpy, annot_sensitivity (local package)
14	"""
15	
16	import sys
17	import os
18	import json
19	import time
20	import numpy as np
21	
22	PROJECT_ROOT = os.path.dirname(os.path.dirname(os.path.abspath(__file__)))
23	sys.path.insert(0, PROJECT_ROOT)
24	
25	from annot_sensitivity.correction import (
26	    correct_ppi, correct_naive_plugin, correct_dsl, correct_mcsimex, correct_mla
27	)
28	from annot_sensitivity.utils import misclassify, make_dummies, ols, ols_with_se
29	
30	# ── Plan 006 DGP Infrastructure (K-general) ────────────────────────
31	
32	_ALPHA_POOL = [1.5, -1.0, 0.8, -0.5, 1.2, -0.7, 0.9, -0.4, 0.6]
33	_BETA_A_POOL = [1.0, -0.5, 0.7, -0.3, 0.5, -0.2, 0.4, -0.15, 0.3]
34	_BETA_POOL = [0.0, 1.0, -0.5, 0.7, -0.3, 0.5, -0.2, 0.4, -0.15, 0.3]
35	_GAMMA_POOL = [0.0, 0.5, -0.3, 0.4, -0.2, 0.3, -0.1, 0.2, -0.05, 0.1]
36	_DELTA_POOL = [0.0, 0.8, -0.6, 0.5, -0.4, 0.3, -0.2, 0.15, -0.1, 0.05]
37	_DT_POOL = [0.0, 0.5, -0.3, 0.4, -0.2, 0.3, -0.1, 0.2, -0.05, 0.1]
38	_DY_POOL = [0.0, 0.8, 0.6, -0.5, 0.4, -0.3, 0.2, 0.15, -0.1, 0.05]
39	
40	
41	def softmax_rows(logits):
42	    e = np.exp(logits - logits.max(axis=1, keepdims=True))
43	    return e / e.sum(axis=1, keepdims=True)
44	
45	
46	def sample_cat(probs, rng):
47	    cum = np.cumsum(probs, axis=1)
48	    u = rng.uniform(size=probs.shape[0])[:, None]
49	    return (u >= cum[:, :-1]).sum(axis=1).astype(int)
50	
51	
52	def make_p_A(K):
53	    if K == 2:
54	        return np.array([0.55, 0.45])
55	    elif K == 3:
56	        return np.array([0.40, 0.35, 0.25])
57	    else:
58	        raw = np.array([1.0 / (i + 1) for i in range(K)])
59	        return raw / raw.sum()
60	
61	
62	def make_dgp_params(K):
63	    p_A = make_p_A(K)
64	    params = {
65	        'confounding': {
66	            'p_A': p_A,
67	            'alpha': np.array(_ALPHA_POOL[:K - 1]),
68	            'beta_A': np.array(_BETA_A_POOL[:K - 1]),
69	            'beta_T': 2.0,
70	            'sigma_T': 1.0,
71	        },
72	        'mediation': {
73	            'tau': 0.5,
74	            'gamma': np.array(_GAMMA_POOL[:K]),
75	            'delta': np.array(_DELTA_POOL[:K]),
76	            'beta': np.array(_BETA_POOL[:K]),
77	        },
78	        'collider': {
79	            'tau': 1.0,
80	            'g': np.zeros(K),
81	            'dT': np.array(_DT_POOL[:K]),
82	            'dY': np.array(_DY_POOL[:K]),
83	        },
84	        'exposure': {
85	            'beta': np.array(_BETA_POOL[:K]),
86	            'p_A': p_A,
87	        },
88	    }
89	    if K == 3:
90	        params['mbias'] = {
91	            'tau': 0.5, 'delta_coef': 1.0, 'lam': 1.0,
92	            'g': np.zeros(3),
93	            'a_U1': np.array([0.0, 0.8, -0.5]),
94	            'a_U2': np.array([0.0, 0.6, 0.9]),
95	        }
96	        params['iv'] = {
97	            'lam': 1.0, 'beta': np.array([0.0, 0.5, -0.25]),
98	            'g': np.zeros(3),
99	            'dZ': np.array([0.0, 1.0, -0.5]),
100	            'dU': np.array([0.0, 0.8, 0.6]),
101	        }
102	        params['frontdoor'] = {
103	            'alpha_U': 1.0, 'lambda_U': 1.0,
104	            'gamma': np.array([0.0, 0.5, -0.3]),
105	            'delta_fd': np.array([0.0, 1.0, -0.8]),
106	            'beta': np.array([0.0, 1.0, -0.5]),
107	        }
108	    else:
109	        params['mbias'] = {
110	            'tau': 0.5, 'delta_coef': 1.0, 'lam': 1.0,
111	            'g': np.zeros(K),
112	            'a_U1': np.array([0.0] + [_ALPHA_POOL[i] * 0.6 for i in range(K - 1)]),
113	            'a_U2': np.array([0.0] + [_BETA_A_POOL[i] * 0.8 for i in range(K - 1)]),
114	        }
115	        iv_beta = np.array(_BETA_POOL[:K]) * 0.5
116	        iv_beta[0] = 0.0
117	        params['iv'] = {
118	            'lam': 1.0, 'beta': iv_beta,
119	            'g': np.zeros(K),
120	            'dZ': np.array([0.0] + [_ALPHA_POOL[i] * 0.7 for i in range(K - 1)]),
121	            'dU': np.array([0.0] + [_BETA_A_POOL[i] * 0.6 for i in range(K - 1)]),
122	        }
123	        fd_delta = np.array(_DELTA_POOL[:K])
124	        fd_delta[0] = 0.0
125	        params['frontdoor'] = {
126	            'alpha_U': 1.0, 'lambda_U': 1.0,
127	            'gamma': np.array(_GAMMA_POOL[:K]),
128	            'delta_fd': fd_delta,
129	            'beta': np.array(_BETA_POOL[:K]),
130	        }
131	    return params
132	
133	
134	# ── DGP Generators ──────────────────────────────────────────────────
135	
136	def gen_confounding(K, N, p, rng):
137	    A = rng.choice(K, size=N, p=p['p_A'])
138	    D = np.zeros((N, K - 1))
139	    for j in range(K - 1):
140	        D[:, j] = (A == j + 1).astype(float)
141	    T = D @ p['alpha'] + rng.normal(0, p['sigma_T'], N)
142	    Y = p['beta_T'] * T + D @ p['beta_A'] + rng.normal(0, 1, N)
143	    return T, Y, A
144	
145	
146	def gen_mediation(K, N, p, rng):
147	    T = rng.binomial(1, 0.5, N).astype(float)
148	    logits = p['gamma'][None, :] + p['delta'][None, :] * T[:, None]
149	    probs = softmax_rows(logits)
150	    A = sample_cat(probs, rng)
151	    D = np.zeros((N, K - 1))
152	    for j in range(K - 1):
153	        D[:, j] = (A == j + 1).astype(float)
154	    Y = p['beta'][0] + D @ p['beta'][1:] + p['tau'] * T + rng.normal(0, 1, N)
155	    return T, Y, A
156	
157	
158	def gen_collider(K, N, p, rng):
159	    T = rng.normal(0, 1, N)
160	    Y = p['tau'] * T + rng.normal(0, 1, N)
161	    logits = (p['g'][None, :] + p['dT'][None, :] * T[:, None]
162	              + p['dY'][None, :] * Y[:, None])
163	    probs = softmax_rows(logits)
164	    A = sample_cat(probs, rng)
165	    return T, Y, A
166	
167	
168	def gen_exposure(K, N, p, rng):
169	    A = rng.choice(K, size=N, p=p['p_A'])
170	    D = np.zeros((N, K - 1))
171	    for j in range(K - 1):
172	        D[:, j] = (A == j + 1).astype(float)
173	    Y = p['beta'][0] + D @ p['beta'][1:] + rng.normal(0, 1, N)
174	    return None, Y, A
175	
176	
177	def gen_mbias(K, N, p, rng):
178	    U1 = rng.normal(0, 1, N)
179	    U2 = rng.normal(0, 1, N)
180	    T = p['delta_coef'] * U1 + rng.normal(0, 1, N)
181	    Y = p['tau'] * T + p['lam'] * U2 + rng.normal(0, 1, N)
182	    logits = (p['g'][None, :] + p['a_U1'][None, :] * U1[:, None]
183	              + p['a_U2'][None, :] * U2[:, None])
184	    probs = softmax_rows(logits)
185	    A = sample_cat(probs, rng)
186	    return T, Y, A
187	
188	
189	def gen_iv(K, N, p, rng):
190	    Z = rng.binomial(1, 0.5, N).astype(float)
191	    U = rng.normal(0, 1, N)
192	    logits = (p['g'][None, :] + p['dZ'][None, :] * Z[:, None]
193	              + p['dU'][None, :] * U[:, None])
194	    probs = softmax_rows(logits)
195	    A = sample_cat(probs, rng)
196	    D = np.zeros((N, K - 1))
197	    for j in range(K - 1):
198	        D[:, j] = (A == j + 1).astype(float)
199	    Y = D @ p['beta'][1:] + p['lam'] * U + rng.normal(0, 1, N)
200	    return Z, Y, A
201	
202	
203	def gen_frontdoor(K, N, p, rng):
204	    U = rng.normal(0, 1, N)
205	    T = p['alpha_U'] * U + rng.normal(0, 1, N)
206	    logits = p['gamma'][None, :] + p['delta_fd'][None, :] * T[:, None]
207	    probs = softmax_rows(logits)
208	    M = sample_cat(probs, rng)
209	    D = np.zeros((N, K - 1))
210	    for j in range(K - 1):
211	        D[:, j] = (M == j + 1).astype(float)
212	    Y = D @ p['beta'][1:] + p['lambda_U'] * U + rng.normal(0, 1, N)
213	    return T, Y, M
214	
215	
216	GEN_FNS = {
217	    'confounding': gen_confounding, 'mediation': gen_mediation,
218	    'collider': gen_collider, 'exposure': gen_exposure,
219	    'mbias': gen_mbias, 'iv': gen_iv, 'frontdoor': gen_frontdoor,
220	}
221	
222	HAS_TREATMENT = {'confounding', 'mediation', 'collider', 'mbias', 'frontdoor'}
223	
224	
225	# ── Wald Estimator ──────────────────────────────────────────────────
226	
227	def wald_est(Z, Y, A_or_Astar, k=1):
228	    z1 = Z == 1; z0 = Z == 0
229	    n1, n0 = float(z1.sum()), float(z0.sum())
230	    if n1 < 2 or n0 < 2:
231	        return np.nan
232	    RF = Y[z1].mean() - Y[z0].mean()
233	    FS = (A_or_Astar[z1] == k).astype(float).mean() - \
234	         (A_or_Astar[z0] == k).astype(float).mean()
235	    if abs(FS) < 1e-8:
236	        return np.nan
237	    return RF / FS
238	
239	
240	def ppi_wald(Z, Y, A, Astar, gold_mask, k=1, rng=None, n_boot=50):
241	    """PPI++ for Wald estimator (IV topology)."""
242	    if rng is None:
243	        rng = np.random.default_rng()
244	    gold_idx = np.where(gold_mask)[0]
245	    n_gold = len(gold_idx)
246	
247	    tau_all_star = wald_est(Z, Y, Astar, k)
248	    tau_gold_true = wald_est(Z[gold_mask], Y[gold_mask], A[gold_mask], k)
249	    tau_gold_star = wald_est(Z[gold_mask], Y[gold_mask], Astar[gold_mask], k)
250	
251	    if np.isnan(tau_gold_true) or np.isnan(tau_all_star):
252	        return np.nan, False
253	
254	    tau_true_boot = np.zeros(n_boot)
255	    tau_rect_boot = np.zeros(n_boot)
256	    for b in range(n_boot):
257	        idx = rng.choice(gold_idx, size=n_gold, replace=True)
258	        bt = wald_est(Z[idx], Y[idx], A[idx], k)
259	        bs = wald_est(Z[idx], Y[idx], Astar[idx], k)
260	        tau_true_boot[b] = bt
261	        tau_rect_boot[b] = bs - bt
262	
263	    valid = np.isfinite(tau_true_boot) & np.isfinite(tau_rect_boot)
264	    if valid.sum() > 5:
265	        var_r = np.var(tau_rect_boot[valid])
266	        cov_tr = np.cov(tau_true_boot[valid], tau_rect_boot[valid])[0, 1]
267	        lam = np.clip(-cov_tr / var_r, 0, 1) if var_r > 1e-12 else 1.0
268	    else:
269	        lam = 1.0
270	
271	    tau_ppi = tau_gold_true + lam * (tau_all_star - tau_gold_star)
272	    return float(tau_ppi), True
273	
274	
275	# ── True Parameter Computation ──────────────────────────────────────
276	
277	def compute_tau_true(K, topology, params, N_large=500_000, seed=99):
278	    """Compute true tau by running estimator on very large uncontaminated sample."""
279	    rng = np.random.default_rng(seed)
280	    first_var, Y, A = GEN_FNS[topology](K, N_large, params[topology], rng)
281	
282	    if topology == 'iv':
283	        return wald_est(first_var, Y, A, k=1)
284	    elif topology == 'exposure':
285	        D = make_dummies(A, K)
286	        X = np.column_stack([np.ones(N_large), D])
287	        beta = np.linalg.lstsq(X, Y, rcond=None)[0]
288	        return float(beta[1])
289	    else:
290	        T = first_var
291	        D = make_dummies(A, K)
292	        X = np.column_stack([np.ones(N_large), T, D])
293	        beta = np.linalg.lstsq(X, Y, rcond=None)[0]
294	        return float(beta[1])
295	
296	
297	# ── MC-SIMEX for IV (custom) ────────────────────────────────────────
298	
299	def mcsimex_wald(Z, Y, Astar, C, k=1, rng=None, n_B=50,
300	                 lambdas_extra=(0.5, 1.0, 1.5, 2.0)):
301	    """MC-SIMEX for IV Wald estimator."""
302	    if rng is None:
303	        rng = np.random.default_rng()
304	    K = C.shape[0]
305	    try:
306	        eigvals, eigvecs = np.linalg.eig(C)
307	        eigvecs_inv = np.linalg.inv(eigvecs)
308	    except np.linalg.LinAlgError:
309	        return np.nan, False
310	
311	    lambdas = np.array([0.0] + list(lambdas_extra))
312	    tau_lam = np.zeros(len(lambdas))
313	
314	    for li, lam_val in enumerate(lambdas):
315	        if lam_val == 0.0:
316	            tau_lam[li] = wald_est(Z, Y, Astar, k)
317	        else:
318	            C_lam_raw = np.real((eigvecs * (eigvals ** lam_val)) @ eigvecs_inv)
319	            C_lam = np.clip(C_lam_raw, 0, None)
320	            cs = C_lam.sum(axis=0)
321	            cs[cs == 0] = 1.0
322	            C_lam /= cs
323	
324	            tau_b = np.zeros(n_B)
325	            for b in range(n_B):
326	                A_extra = misclassify(Astar, C_lam, rng)
327	                tau_b[b] = wald_est(Z, Y, A_extra, k)
328	            ok = np.isfinite(tau_b)
329	            if ok.sum() < n_B // 2:
330	                return np.nan, False
331	            tau_lam[li] = tau_b[ok].mean()
332	
333	    try:
334	        coeffs = np.polyfit(lambdas, tau_lam, 2)
335	        return float(np.polyval(coeffs, -1.0)), True
336	    except Exception:
337	        return np.nan, False
338	
339	
340	# ── Main ────────────────────────────────────────────────────────────
341	
342	N_SAMPLES = 10_000
343	N_REPS = 30
344	GOLD_FRACTION = 0.10
345	SEED = 42
346	TOPOLOGIES = ['confounding', 'mediation', 'collider', 'exposure',
347	              'mbias', 'iv', 'frontdoor']
348	METHODS = ['ppi', 'naive_plugin', 'dsl', 'mcsimex', 'mla']
349	
350	JSON_PATH = os.path.join(PROJECT_ROOT, 'artifacts', 'plan006',
351	                         'asv_empirical_results.json')
352	
353	
354	def load_valid_humaid_configs():
355	    with open(JSON_PATH) as f:
356	        data = json.load(f)
357	
358	    zero_configs = {(e['model'], e['prompt'])
359	                    for e in data['f1_vs_bias'] if e['macro_f1'] == 0}
360	
361	    cms = {}
362	    for key, mat in data['confusion_matrices'].items():
363	        parts = key.split('_')
364	        if parts[0] != 'humaid':
365	            continue
366	        model = parts[1]
367	        prompt = '_'.join(parts[2:])
368	        if (model, prompt) in zero_configs:
369	            continue
370	        cms[key] = np.array(mat)
371	    return cms
372	
373	
374	def run_single_rep(K, topology, params, C, tau_true, rng, gold_frac):
375	    """Run one MC replication: generate data, misclassify, run corrections."""
376	    first_var, Y, A = GEN_FNS[topology](K, N_SAMPLES, params[topology], rng)
377	    Astar = misclassify(A, C, rng)
378	
379	    N = len(Y)
380	    n_gold = max(int(N * gold_frac), 50)
381	    gold_idx = rng.choice(N, size=n_gold, replace=False)
382	    gold_mask = np.zeros(N, dtype=bool)
383	    gold_mask[gold_idx] = True
384	
385	    results = {}
386	
387	    if topology == 'iv':
388	        Z = first_var
389	        tau_naive = wald_est(Z, Y, Astar, k=1)
390	        results['naive'] = float(tau_naive) if np.isfinite(tau_naive) else None
391	
392	        tau_ppi, ok = ppi_wald(Z, Y, A, Astar, gold_mask, k=1, rng=rng)
393	        results['ppi'] = float(tau_ppi) if ok and np.isfinite(tau_ppi) else None
394	
395	        tau_sim, ok = mcsimex_wald(Z, Y, Astar, C, k=1, rng=rng)
396	        results['mcsimex'] = float(tau_sim) if ok and np.isfinite(tau_sim) else None
397	
398	        results['naive_plugin'] = None
399	        results['dsl'] = None
400	        results['mla'] = None
401	
402	    elif topology == 'exposure':
403	        X_other = np.ones((N, 1))
404	        D_star = make_dummies(Astar, K)
405	        X_full = np.column_stack([X_other, D_star])
406	        try:
407	            beta_naive = np.linalg.lstsq(X_full, Y, rcond=None)[0]
408	            tau_naive = float(beta_naive[1])
409	        except Exception:
410	            tau_naive = np.nan
411	        results['naive'] = float(tau_naive) if np.isfinite(tau_naive) else None
412	
413	        for method in METHODS:
414	            if method == 'ppi':
415	                tau, se, ok = correct_ppi(X_other, Y, Astar, A, gold_mask,
416	                                          tau_idx=1, rng=rng)
417	            elif method == 'naive_plugin':
418	                tau, se, ok = correct_naive_plugin(X_other, Y, Astar, C, tau_idx=1)
419	            elif method == 'dsl':
420	                tau, se, ok = correct_dsl(X_other, Y, Astar, A, gold_mask, tau_idx=1)
421	            elif method == 'mcsimex':
422	                tau, se, ok = correct_mcsimex(X_other, Y, Astar, C, tau_idx=1, rng=rng)
423	            elif method == 'mla':
424	                tau, se, ok = correct_mla(X_other, Y, Astar, C, tau_idx=1)
425	            else:
426	                continue
427	            results[method] = float(tau) if ok and np.isfinite(tau) else None
428	
429	    else:
430	        T = first_var
431	        X_other = np.column_stack([np.ones(N), T])
432	        D_star = make_dummies(Astar, K)
433	        X_full = np.column_stack([X_other, D_star])
434	        try:
435	            beta_naive = np.linalg.lstsq(X_full, Y, rcond=None)[0]
436	            tau_naive = float(beta_naive[1])
437	        except Exception:
438	            tau_naive = np.nan
439	        results['naive'] = float(tau_naive) if np.isfinite(tau_naive) else None
440	
441	        for method in METHODS:
442	            if method == 'ppi':
443	                tau, se, ok = correct_ppi(X_other, Y, Astar, A, gold_mask,
444	                                          tau_idx=1, rng=rng)
445	            elif method == 'naive_plugin':
446	                tau, se, ok = correct_naive_plugin(X_other, Y, Astar, C, tau_idx=1)
447	            elif method == 'dsl':
448	                tau, se, ok = correct_dsl(X_other, Y, Astar, A, gold_mask, tau_idx=1)
449	            elif method == 'mcsimex':
450	                tau, se, ok = correct_mcsimex(X_other, Y, Astar, C, tau_idx=1, rng=rng)
451	            elif method == 'mla':
452	                tau, se, ok = correct_mla(X_other, Y, Astar, C, tau_idx=1)
453	            else:
454	                continue
455	            results[method] = float(tau) if ok and np.isfinite(tau) else None
456	
457	    results['tau_true'] = tau_true
458	    return results
459	
460	
461	def main():
462	    t_start = time.time()
463	    K = 10
464	    print("=" * 70)
465	    print("Empirical Correction Validation — HumAID K=10")
466	    print("=" * 70)
467	    print(f"N={N_SAMPLES}, N_REPS={N_REPS}, gold_fraction={GOLD_FRACTION}")
468	
469	    configs = load_valid_humaid_configs()
470	    print(f"Loaded {len(configs)} valid HumAID confusion matrices")
471	
472	    params = make_dgp_params(K)
473	    rng_master = np.random.default_rng(SEED)
474	
475	    print("\nComputing tau_true for each topology (N=500k)...")
476	    tau_true = {}
477	    for topo in TOPOLOGIES:
478	        tau_true[topo] = compute_tau_true(K, topo, params)
479	        print(f"  {topo}: tau_true = {tau_true[topo]:.6f}")
480	
481	    all_results = {}
482	    per_topo_method = {topo: {m: [] for m in METHODS}
483	                       for topo in TOPOLOGIES}
484	
485	    for ci, (config_name, C) in enumerate(configs.items()):
486	        print(f"\n[{ci+1}/{len(configs)}] {config_name}")
487	        config_results = {}
488	
489	        for topo in TOPOLOGIES:
490	            topo_reps = []
491	            for rep in range(N_REPS):
492	                seed_rep = rng_master.integers(0, 2**31)
493	                rng_rep = np.random.default_rng(seed_rep)
494	                res = run_single_rep(K, topo, params, C, tau_true[topo],
495	                                     rng_rep, GOLD_FRACTION)
496	                topo_reps.append(res)
497	
498	            naive_biases = []
499	            method_biases = {m: [] for m in METHODS}
500	            for res in topo_reps:
501	                tt = res['tau_true']
502	                if res['naive'] is not None:
503	                    naive_biases.append(res['naive'] - tt)
504	                for m in METHODS:
505	                    if res.get(m) is not None:
506	                        method_biases[m].append(res[m] - tt)
507	
508	            avg_naive_bias = np.mean(np.abs(naive_biases)) if naive_biases else None
509	            topo_summary = {
510	                'tau_true': tau_true[topo],
511	                'n_reps': N_REPS,
512	                'naive_mean_abs_bias': float(avg_naive_bias) if avg_naive_bias else None,
513	                'methods': {},
514	            }
515	
516	            for m in METHODS:
517	                biases = method_biases[m]
518	                if biases:
519	                    avg_abs = float(np.mean(np.abs(biases)))
520	                    mean_bias = float(np.mean(biases))
521	                    if avg_naive_bias and avg_naive_bias > 1e-8:
522	                        reduction = 1.0 - avg_abs / avg_naive_bias
523	                    else:
524	                        reduction = None
525	                    topo_summary['methods'][m] = {
526	                        'mean_abs_bias': avg_abs,
527	                        'mean_bias': mean_bias,
528	                        'bias_reduction': float(reduction) if reduction is not None else None,
529	                        'n_valid': len(biases),
530	                    }
531	                    per_topo_method[topo][m].append(
532	                        float(reduction) if reduction is not None else None
533	                    )
534	                else:
535	                    topo_summary['methods'][m] = {
536	                        'mean_abs_bias': None,
537	                        'mean_bias': None,
538	                        'bias_reduction': None,
539	                        'n_valid': 0,
540	                    }
541	
542	            config_results[topo] = topo_summary
543	            ppi_info = topo_summary['methods'].get('ppi', {})
544	            ppi_red = ppi_info.get('bias_reduction')
545	            ppi_str = f"{100*ppi_red:.1f}%" if ppi_red is not None else "N/A"
546	            print(f"  {topo:12s}: naive_bias={avg_naive_bias:.4f}" if avg_naive_bias else
547	                  f"  {topo:12s}: naive_bias=N/A", end="")
548	            print(f"  PPI++={ppi_str}")
549	
550	        all_results[config_name] = config_results
551	
552	    grand_summary = {}
553	    print("\n" + "=" * 70)
554	    print("GRAND SUMMARY: Mean bias reduction across 8 configs")
555	    print("=" * 70)
556	    print(f"\n{'Topology':14s}", end="")
557	    for m in METHODS:
558	        print(f"  {m:14s}", end="")
559	    print()
560	    print("-" * (14 + 16 * len(METHODS)))
561	
562	    for topo in TOPOLOGIES:
563	        grand_summary[topo] = {}
564	        print(f"{topo:14s}", end="")
565	        for m in METHODS:
566	            vals = [v for v in per_topo_method[topo][m] if v is not None]
567	            if vals:
568	                mean_red = float(np.mean(vals))
569	                grand_summary[topo][m] = {
570	                    'mean_reduction': mean_red,
571	                    'std_reduction': float(np.std(vals)),
572	                    'n_configs': len(vals),
573	                }
574	                print(f"  {100*mean_red:+12.1f}%", end="")
575	            else:
576	                grand_summary[topo][m] = None
577	                print(f"  {'N/A':>13s}", end="")
578	        print()
579	
580	    overall_ppi = []
581	    for topo in TOPOLOGIES:
582	        gs = grand_summary[topo].get('ppi')
583	        if gs:
584	            overall_ppi.append(gs['mean_reduction'])
585	    if overall_ppi:
586	        print(f"\nGrand mean PPI++ bias reduction: {100*np.mean(overall_ppi):.1f}%")
587	
588	    output = {
589	        'meta': {
590	            'scope': 'HumAID K=10, 8 valid configs',
591	            'n_samples': N_SAMPLES,
592	            'n_reps': N_REPS,
593	            'gold_fraction': GOLD_FRACTION,
594	            'seed': SEED,
595	            'topologies': TOPOLOGIES,
596	            'methods': METHODS,
597	            'n_configs': len(configs),
598	            'configs': list(configs.keys()),
599	        },
600	        'tau_true': {t: float(tau_true[t]) for t in TOPOLOGIES},
601	        'per_config': all_results,
602	        'grand_summary': grand_summary,
603	    }
604	
605	    out_path = os.path.join(PROJECT_ROOT, 'artifacts',
606	                            'ppi_empirical_validation.json')
607	    with open(out_path, 'w') as f:
608	        json.dump(output, f, indent=2)
609	
610	    elapsed = time.time() - t_start
611	    print(f"\nResults saved to: {out_path}")
612	    print(f"Total runtime: {elapsed:.1f}s")
613	
614	
615	if __name__ == '__main__':
616	    main()
617	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "850a9867-a36f-46cf-95a7-b04c810d20be",
  "isSidechain": true,
  "promptId": "417df0a2-cc01-4fb5-9f46-ee96dfc8be6b",
  "agentId": "a4ddc290a1e5d82db",
  "type": "user",
  "uuid": "4c0250d8-b378-42ad-a17c-b2129a44caaf",
  "sourceToolAssistantUUID": "850a9867-a36f-46cf-95a7-b04c810d20be",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "ba945ca1-7c3c-4181-a307-80decba09cd0",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool result

_source line 15 · 2026-05-22T11:10:12.750Z_

<details><summary>↩ Tool result · `toolu_01KqSYqU9Q572sUckq9uUA4t`</summary>

```text
1	#!/usr/bin/env python3
2	"""
3	plan_006: Empirical ASV Calibration with LLM Annotation Confusion Matrices
4	
5	Uses empirical confusion matrices from LLM annotations (3 LLMs × 3 datasets × 3 prompts
6	= 27 C matrices) to compute:
7	  1. Downstream causal bias across 7 DAG topologies
8	  2. ASV sensitivity metrics (magnitude, significance, sign-flip)
9	  3. F1 vs bias disconnect analysis (Baumann 2025 verification)
10	  4. Type I/II error rates before/after ASV filtering
11	  5. Inter-model error correlation
12	
13	Input:  data/{dataset}/{model}_{prompt}_annotations.jsonl
14	        Each line: {"true_label": int, "predicted_label": int}
15	
16	Output: artifacts/plan006/asv_empirical_results.json
17	
18	Dependencies: numpy (required), matplotlib (optional for plots)
19	"""
20	
21	import numpy as np
22	import json
23	import argparse
24	import os
25	import time
26	from collections import OrderedDict
27	
28	try:
29	    import matplotlib
30	    matplotlib.use('Agg')
31	    import matplotlib.pyplot as plt
32	    HAS_MPL = True
33	except ImportError:
34	    HAS_MPL = False
35	
36	# ============================================================================
37	# Constants
38	# ============================================================================
39	
40	DATASETS = OrderedDict([
41	    ('civil_comments', {'K': 2}),
42	    ('vast', {'K': 3}),
43	    ('humaid', {'K': 10}),
44	])
45	
46	MODELS = ['llama4', 'qwen3', 'deepseek']
47	PROMPTS = ['zero-shot', 'few-shot-3', 'few-shot-5']
48	
49	TOPOLOGIES = ['confounding', 'mediation', 'collider', 'exposure',
50	              'mbias', 'iv', 'frontdoor']
51	
52	N_PRECOMP = 2_000_000
53	
54	# Parameter pools — K=3 values match plan_001/plan_005
55	_ALPHA_POOL = [1.5, -1.0, 0.8, -0.5, 1.2, -0.7, 0.9, -0.4, 0.6]
56	_BETA_A_POOL = [1.0, -0.5, 0.7, -0.3, 0.5, -0.2, 0.4, -0.15, 0.3]
57	_BETA_POOL = [0.0, 1.0, -0.5, 0.7, -0.3, 0.5, -0.2, 0.4, -0.15, 0.3]
58	_GAMMA_POOL = [0.0, 0.5, -0.3, 0.4, -0.2, 0.3, -0.1, 0.2, -0.05, 0.1]
59	_DELTA_POOL = [0.0, 0.8, -0.6, 0.5, -0.4, 0.3, -0.2, 0.15, -0.1, 0.05]
60	_DT_POOL = [0.0, 0.5, -0.3, 0.4, -0.2, 0.3, -0.1, 0.2, -0.05, 0.1]
61	_DY_POOL = [0.0, 0.8, 0.6, -0.5, 0.4, -0.3, 0.2, 0.15, -0.1, 0.05]
62	
63	
64	# ============================================================================
65	# Utility Functions
66	# ============================================================================
67	
68	def softmax_rows(logits):
69	    e = np.exp(logits - logits.max(axis=1, keepdims=True))
70	    return e / e.sum(axis=1, keepdims=True)
71	
72	
73	def sample_cat(probs, rng):
74	    cum = np.cumsum(probs, axis=1)
75	    u = rng.uniform(size=probs.shape[0])[:, None]
76	    return (u >= cum[:, :-1]).sum(axis=1).astype(int)
77	
78	
79	def generate_Astar(A, C, rng):
80	    probs = C[:, A]
81	    cum = np.cumsum(probs, axis=0)
82	    u = rng.uniform(size=len(A))
83	    return (u[None, :] >= cum[:-1]).sum(axis=0).astype(int)
84	
85	
86	def ols_with_dummies(Y, T, Astar, K):
87	    N = len(Y)
88	    D = np.zeros((N, K - 1))
89	    for k in range(1, K):
90	        D[:, k - 1] = (Astar == k).astype(float)
91	    X = np.column_stack([np.ones(N), T, D])
92	    try:
93	        beta = np.linalg.lstsq(X, Y, rcond=None)[0]
94	        resid = Y - X @ beta
95	        sigma2 = np.sum(resid**2) / max(N - X.shape[1], 1)
96	        XtX_inv = np.linalg.inv(X.T @ X)
97	        se = np.sqrt(np.maximum(sigma2 * np.diag(XtX_inv), 0))
98	    except np.linalg.LinAlgError:
99	        beta = np.full(X.shape[1], np.nan)
100	        se = np.full(X.shape[1], np.nan)
101	    return beta, se
102	
103	
104	def ols_no_T(Y, Astar, K):
105	    N = len(Y)
106	    D = np.zeros((N, K - 1))
107	    for k in range(1, K):
108	        D[:, k - 1] = (Astar == k).astype(float)
109	    X = np.column_stack([np.ones(N), D])
110	    try:
111	        beta = np.linalg.lstsq(X, Y, rcond=None)[0]
112	        resid = Y - X @ beta
113	        sigma2 = np.sum(resid**2) / max(N - X.shape[1], 1)
114	        XtX_inv = np.linalg.inv(X.T @ X)
115	        se = np.sqrt(np.maximum(sigma2 * np.diag(XtX_inv), 0))
116	    except np.linalg.LinAlgError:
117	        beta = np.full(X.shape[1], np.nan)
118	        se = np.full(X.shape[1], np.nan)
119	    return beta, se
120	
121	
122	def wald_estimator(Z, Y, Astar, k=1):
123	    z1 = Z == 1; z0 = Z == 0
124	    n1, n0 = float(z1.sum()), float(z0.sum())
125	    if n1 < 2 or n0 < 2:
126	        return np.nan, np.nan
127	    RF = Y[z1].mean() - Y[z0].mean()
128	    var_RF = Y[z1].var() / n1 + Y[z0].var() / n0
129	    Dk_z1 = (Astar[z1] == k).astype(float).mean()
130	    Dk_z0 = (Astar[z0] == k).astype(float).mean()
131	    FS = Dk_z1 - Dk_z0
132	    var_FS = Dk_z1 * (1 - Dk_z1) / n1 + Dk_z0 * (1 - Dk_z0) / n0
133	    if abs(FS) < 1e-8:
134	        return np.nan, np.nan
135	    W = RF / FS
136	    var_W = var_RF / FS**2 + RF**2 * var_FS / FS**4
137	    return W, np.sqrt(max(var_W, 0))
138	
139	
140	# ============================================================================
141	# DGP Parameters (general K, K=3 matches plan_001/plan_005)
142	# ============================================================================
143	
144	def make_p_A(K):
145	    if K == 2:
146	        return np.array([0.55, 0.45])
147	    elif K == 3:
148	        return np.array([0.40, 0.35, 0.25])
149	    else:
150	        raw = np.array([1.0 / (i + 1) for i in range(K)])
151	        return raw / raw.sum()
152	
153	
154	def make_dgp_params(K):
155	    p_A = make_p_A(K)
156	    params = {
157	        'confounding': {
158	            'p_A': p_A,
159	            'alpha': np.array(_ALPHA_POOL[:K - 1]),
160	            'beta_A': np.array(_BETA_A_POOL[:K - 1]),
161	            'beta_T': 2.0,
162	            'sigma_T': 1.0,
163	        },
164	        'mediation': {
165	            'tau': 0.5,
166	            'gamma': np.array(_GAMMA_POOL[:K]),
167	            'delta': np.array(_DELTA_POOL[:K]),
168	            'beta': np.array(_BETA_POOL[:K]),
169	        },
170	        'collider': {
171	            'tau': 1.0,
172	            'g': np.zeros(K),
173	            'dT': np.array(_DT_POOL[:K]),
174	            'dY': np.array(_DY_POOL[:K]),
175	        },
176	        'exposure': {
177	            'beta': np.array(_BETA_POOL[:K]),
178	            'p_A': p_A,
179	        },
180	    }
181	    if K == 3:
182	        params['mbias'] = {
183	            'tau': 0.5, 'delta_coef': 1.0, 'lam': 1.0,
184	            'g': np.zeros(3),
185	            'a_U1': np.array([0.0, 0.8, -0.5]),
186	            'a_U2': np.array([0.0, 0.6, 0.9]),
187	        }
188	        params['iv'] = {
189	            'lam': 1.0, 'beta': np.array([0.0, 0.5, -0.25]),
190	            'g': np.zeros(3),
191	            'dZ': np.array([0.0, 1.0, -0.5]),
192	            'dU': np.array([0.0, 0.8, 0.6]),
193	        }
194	        params['frontdoor'] = {
195	            'alpha_U': 1.0, 'lambda_U': 1.0,
196	            'gamma': np.array([0.0, 0.5, -0.3]),
197	            'delta_fd': np.array([0.0, 1.0, -0.8]),
198	            'beta': np.array([0.0, 1.0, -0.5]),
199	        }
200	    else:
201	        params['mbias'] = {
202	            'tau': 0.5, 'delta_coef': 1.0, 'lam': 1.0,
203	            'g': np.zeros(K),
204	            'a_U1': np.array([0.0] + [_ALPHA_POOL[i] * 0.6 for i in range(K - 1)]),
205	            'a_U2': np.array([0.0] + [_BETA_A_POOL[i] * 0.8 for i in range(K - 1)]),
206	        }
207	        iv_beta = np.array(_BETA_POOL[:K]) * 0.5
208	        iv_beta[0] = 0.0
209	        params['iv'] = {
210	            'lam': 1.0, 'beta': iv_beta,
211	            'g': np.zeros(K),
212	            'dZ': np.array([0.0] + [_ALPHA_POOL[i] * 0.7 for i in range(K - 1)]),
213	            'dU': np.array([0.0] + [_BETA_A_POOL[i] * 0.6 for i in range(K - 1)]),
214	        }
215	        fd_delta = np.array(_DELTA_POOL[:K])
216	        fd_delta[0] = 0.0
217	        params['frontdoor'] = {
218	            'alpha_U': 1.0, 'lambda_U': 1.0,
219	            'gamma': np.array(_GAMMA_POOL[:K]),
220	            'delta_fd': fd_delta,
221	            'beta': np.array(_BETA_POOL[:K]),
222	        }
223	    return params
224	
225	
226	def make_dgp_params_H0(K, params):
227	    p0 = {}
228	    for topo, p in params.items():
229	        if topo == 'confounding':
230	            p0[topo] = dict(p, beta_T=0.0)
231	        elif topo == 'mediation':
232	            p0[topo] = dict(p, tau=0.0)
233	        elif topo == 'collider':
234	            p0[topo] = dict(p, tau=0.0)
235	        elif topo == 'exposure':
236	            p0[topo] = dict(p, beta=np.zeros(K))
237	        elif topo == 'mbias':
238	            p0[topo] = dict(p, tau=0.0)
239	        elif topo == 'iv':
240	            p0[topo] = dict(p, beta=np.zeros(K))
241	        elif topo == 'frontdoor':
242	            p0[topo] = dict(p, lambda_U=0.0, alpha_U=0.0,
243	                            delta_fd=np.zeros(K), beta=np.zeros(K))
244	    return p0
245	
246	
247	# ============================================================================
248	# DGP Generators (general K)
249	# ============================================================================
250	
251	def gen_confounding(K, N, p, rng):
252	    A = rng.choice(K, size=N, p=p['p_A'])
253	    D = np.zeros((N, K - 1))
254	    for j in range(K - 1):
255	        D[:, j] = (A == j + 1).astype(float)
256	    T = D @ p['alpha'] + rng.normal(0, p['sigma_T'], N)
257	    Y = p['beta_T'] * T + D @ p['beta_A'] + rng.normal(0, 1, N)
258	    return T, Y, A
259	
260	
261	def gen_mediation(K, N, p, rng):
262	    T = rng.binomial(1, 0.5, N).astype(float)
263	    logits = p['gamma'][None, :] + p['delta'][None, :] * T[:, None]
264	    probs = softmax_rows(logits)
265	    A = sample_cat(probs, rng)
266	    D = np.zeros((N, K - 1))
267	    for j in range(K - 1):
268	        D[:, j] = (A == j + 1).astype(float)
269	    Y = p['beta'][0] + D @ p['beta'][1:] + p['tau'] * T + rng.normal(0, 1, N)
270	    return T, Y, A
271	
272	
273	def gen_collider(K, N, p, rng):
274	    T = rng.normal(0, 1, N)
275	    Y = p['tau'] * T + rng.normal(0, 1, N)
276	    logits = (p['g'][None, :] + p['dT'][None, :] * T[:, None]
277	              + p['dY'][None, :] * Y[:, None])
278	    probs = softmax_rows(logits)
279	    A = sample_cat(probs, rng)
280	    return T, Y, A
281	
282	
283	def gen_exposure(K, N, p, rng):
284	    A = rng.choice(K, size=N, p=p['p_A'])
285	    D = np.zeros((N, K - 1))
286	    for j in range(K - 1):
287	        D[:, j] = (A == j + 1).astype(float)
288	    Y = p['beta'][0] + D @ p['beta'][1:] + rng.normal(0, 1, N)
289	    return None, Y, A
290	
291	
292	def gen_mbias(K, N, p, rng):
293	    U1 = rng.normal(0, 1, N)
294	    U2 = rng.normal(0, 1, N)
295	    T = p['delta_coef'] * U1 + rng.normal(0, 1, N)
296	    Y = p['tau'] * T + p['lam'] * U2 + rng.normal(0, 1, N)
297	    logits = (p['g'][None, :] + p['a_U1'][None, :] * U1[:, None]
298	              + p['a_U2'][None, :] * U2[:, None])
299	    probs = softmax_rows(logits)
300	    A = sample_cat(probs, rng)
301	    return T, Y, A
302	
303	
304	def gen_iv(K, N, p, rng):
305	    Z = rng.binomial(1, 0.5, N).astype(float)
306	    U = rng.normal(0, 1, N)
307	    logits = (p['g'][None, :] + p['dZ'][None, :] * Z[:, None]
308	              + p['dU'][None, :] * U[:, None])
309	    probs = softmax_rows(logits)
310	    A = sample_cat(probs, rng)
311	    D = np.zeros((N, K - 1))
312	    for j in range(K - 1):
313	        D[:, j] = (A == j + 1).astype(float)
314	    Y = D @ p['beta'][1:] + p['lam'] * U + rng.normal(0, 1, N)
315	    return Z, Y, A
316	
317	
318	def gen_frontdoor(K, N, p, rng):
319	    U = rng.normal(0, 1, N)
320	    T = p['alpha_U'] * U + rng.normal(0, 1, N)
321	    logits = p['gamma'][None, :] + p['delta_fd'][None, :] * T[:, None]
322	    probs = softmax_rows(logits)
323	    M = sample_cat(probs, rng)
324	    D = np.zeros((N, K - 1))
325	    for j in range(K - 1):
326	        D[:, j] = (M == j + 1).astype(float)
327	    Y = D @ p['beta'][1:] + p['lambda_U'] * U + rng.normal(0, 1, N)
328	    return T, Y, M
329	
330	
331	GEN_FNS = {
332	    'confounding': gen_confounding, 'mediation': gen_mediation,
333	    'collider': gen_collider, 'exposure': gen_exposure,
334	    'mbias': gen_mbias, 'iv': gen_iv, 'frontdoor': gen_frontdoor,
335	}
336	
337	
338	# ============================================================================
339	# Sufficient Statistics & Plim (general K)
340	# ============================================================================
341	
342	def precompute_suff_stats(K, topology, params, N=N_PRECOMP, seed=42):
343	    rng = np.random.default_rng(seed)
344	    first_var, Y, A = GEN_FNS[topology](K, N, params, rng)
345	    DA = np.zeros((N, K))
346	    for k in range(K):
347	        DA[:, k] = (A == k).astype(float)
348	
349	    if topology == 'iv':
350	        Z = first_var
351	        z1 = Z == 1; z0 = Z == 0
352	        RF = Y[z1].mean() - Y[z0].mean()
353	        FS = np.zeros(K)
354	        for k in range(K):
355	            FS[k] = (A[z1] == k).mean() - (A[z0] == k).mean()
356	        return dict(RF=RF, FS=FS, topology='iv')
357	    elif topology == 'exposure':
358	        return dict(p_A=DA.mean(0), E_Y=Y.mean(),
359	                    E_YD=(DA * Y[:, None]).mean(0), topology='exposure')
360	    else:
361	        T = first_var
362	        return dict(
363	            p_A=DA.mean(0), E_T=T.mean(), E_T2=(T**2).mean(),
364	            E_Y=Y.mean(), E_TY=(T * Y).mean(),
365	            E_TD=(DA * T[:, None]).mean(0),
366	            E_YD=(DA * Y[:, None]).mean(0), topology=topology)
367	
368	
369	def compute_plim(C, st, K):
370	    if st['topology'] == 'iv':
371	        FS_star = C @ st['FS']
372	        if abs(FS_star[1]) < 1e-8:
373	            return np.nan
374	        return st['RF'] / FS_star[1]
375	    elif st['topology'] == 'exposure':
376	        q = C @ st['p_A']
377	        cy = C @ st['E_YD']
378	        EZZ = np.zeros((K, K))
379	        EZZ[0, 0] = 1.0
380	        for j in range(1, K):
381	            EZZ[0, j] = EZZ[j, 0] = q[j]
382	            EZZ[j, j] = q[j]
383	        EZY = np.zeros(K)
384	        EZY[0] = st['E_Y']
385	        for j in range(1, K):
386	            EZY[j] = cy[j]
387	        try:
388	            return np.linalg.solve(EZZ, EZY)
389	        except np.linalg.LinAlgError:
390	            return np.full(K, np.nan)
391	    else:
392	        q = C @ st['p_A']
393	        ct = C @ st['E_TD']
394	        cy = C @ st['E_YD']
395	        dim = K + 1
396	        EZZ = np.zeros((dim, dim))
397	        EZZ[0, 0] = 1.0
398	        EZZ[0, 1] = EZZ[1, 0] = st['E_T']
399	        EZZ[1, 1] = st['E_T2']
400	        for j in range(1, K):
401	            EZZ[0, j + 1] = EZZ[j + 1, 0] = q[j]
402	            EZZ[1, j + 1] = EZZ[j + 1, 1] = ct[j]
403	            EZZ[j + 1, j + 1] = q[j]
404	        EZY = np.zeros(dim)
405	        EZY[0] = st['E_Y']
406	        EZY[1] = st['E_TY']
407	        for j in range(1, K):
408	            EZY[j + 1] = cy[j]
409	        try:
410	            return np.linalg.solve(EZZ, EZY)
411	        except np.linalg.LinAlgError:
412	            return np.full(dim, np.nan)
413	
414	
415	def extract_tau(plim_result, topology):
416	    if topology == 'iv':
417	        return float(plim_result) if np.isfinite(plim_result) else np.nan
418	    if isinstance(plim_result, np.ndarray):
419	        return float(plim_result[1]) if np.isfinite(plim_result[1]) else np.nan
420	    return np.nan
421	
422	
423	# ============================================================================
424	# 1. Data Loading & Confusion Matrix
425	# ============================================================================
426	
427	def load_confusion_matrix_npz(data_dir, dataset, model, prompt, K):
428	    path = os.path.join(data_dir, dataset, f"{model}_{prompt}_confusion_matrix.npz")
429	    d = np.load(path, allow_pickle=True)
430	    C = d['C']
431	    assert C.shape == (K, K), f"Expected ({K},{K}), got {C.shape}"
432	    return C
433	
434	
435	def load_annotations(data_dir, dataset, model, prompt):
436	    for suffix in ['_annotations.jsonl', '.jsonl']:
437	        path = os.path.join(data_dir, dataset, f"{model}_{prompt}{suffix}")
438	        if os.path.exists(path):
439	            break
440	    else:
441	        raise FileNotFoundError(f"No annotation file for {dataset}/{model}_{prompt}")
442	    records = []
443	    label_set = set()
444	    with open(path) as f:
445	        for line in f:
446	            rec = json.loads(line.strip())
447	            gl = rec.get('true_label', rec.get('gold_label'))
448	            pl = rec.get('predicted_label', rec.get('pred_label'))
449	            if gl is not None and pl is not None:
450	                label_set.add(gl)
451	                label_set.add(pl)
452	                records.append((gl, pl))
453	    if records and isinstance(records[0][0], str):
454	        sorted_labels = sorted(label_set)
455	        label_map = {l: i for i, l in enumerate(sorted_labels)}
456	        records = [(label_map[g], label_map[p]) for g, p in records]
457	    else:
458	        records = [(int(g), int(p)) for g, p in records]
459	    return records
460	
461	
462	def build_confusion_matrix(records, K):
463	    counts = np.zeros((K, K))
464	    for true_k, pred_k in records:
465	        if 0 <= true_k < K and 0 <= pred_k < K:
466	            counts[pred_k, true_k] += 1
467	    col_sums = counts.sum(axis=0)
468	    col_sums = np.where(col_sums < 1, 1, col_sums)
469	    return counts / col_sums
470	
471	
472	def load_all_confusion_matrices(data_dir, dataset_filter=None):
473	    matrices = {}
474	    for dataset, info in DATASETS.items():
475	        if dataset_filter and dataset not in dataset_filter:
476	            continue
477	        K = info['K']
478	        for model in MODELS:
479	            for prompt in PROMPTS:
480	                try:
481	                    C = load_confusion_matrix_npz(data_dir, dataset, model, prompt, K)
482	                    matrices[(dataset, model, prompt)] = C
483	                except (FileNotFoundError, Exception):
484	                    try:
485	                        records = load_annotations(data_dir, dataset, model, prompt)
486	                        C = build_confusion_matrix(records, K)
487	                        matrices[(dataset, model, prompt)] = C
488	                    except FileNotFoundError:
489	                        print(f"  [WARN] Missing: {dataset}/{model}_{prompt}")
490	    return matrices
491	
492	
493	# ============================================================================
494	# 2. Downstream Causal Bias
495	# ============================================================================
496	
497	def compute_bias_for_topology(C, K, topology, st, tau_true):
498	    plim_result = compute_plim(C, st, K)
499	    tau_hat = extract_tau(plim_result, topology)
500	    if np.isnan(tau_hat) or np.isnan(tau_true):
501	        return {'tau_hat': None, 'bias': None, 'bias_pct': None, 'sign_flip': False}
502	    bias = tau_hat - tau_true
503	    bias_pct = abs(bias) / abs(tau_true) if abs(tau_true) > 1e-12 else None
504	    sign_flip = bool(np.sign(tau_hat) != np.sign(tau_true) and abs(tau_true) > 1e-12)
505	    return {
506	        'tau_hat': float(tau_hat), 'bias': float(bias),
507	        'bias_pct': float(bias_pct) if bias_pct is not None else None,
508	        'sign_flip': sign_flip,
509	    }
510	
511	
512	def compute_all_biases(confusion_matrices, all_suff_stats, all_tau_true):
513	    results = []
514	    for (dataset, model, prompt), C in confusion_matrices.items():
515	        K = DATASETS[dataset]['K']
516	        for topology in TOPOLOGIES:
517	            st = all_suff_stats[(K, topology)]
518	            tau_true = all_tau_true[(K, topology)]
519	            info = compute_bias_for_topology(C, K, topology, st, tau_true)
520	            results.append({
521	                'dataset': dataset, 'model': model, 'prompt': prompt,
522	                'K': K, 'topology': topology, **info,
523	            })
524	    return results
525	
526	
527	# ============================================================================
528	# 3. ASV Computation
529	# ============================================================================
530	
531	def C_interpolated(C0, delta, K):
532	    C_d = (1 - delta) * np.eye(K) + delta * C0
533	    C_d = np.maximum(C_d, 0.0)
534	    col_sums = C_d.sum(axis=0)
535	    col_sums = np.where(col_sums < 1e-10, 1.0, col_sums)
536	    return C_d / col_sums
537	
538	
539	def compute_delta_max(C0):
540	    min_diag = np.diag(C0).min()
541	    if min_diag >= 1.0:
542	        return 10.0
543	    return min(1.0 / (1.0 - min_diag), 10.0)
544	
545	
546	def compute_asv_for_matrix(C0, K, topology, st, tau_true, asv_type,
547	                           n_grid=1500, se_ref=None):
548	    dmax = compute_delta_max(C0)
549	    deltas = np.linspace(0, dmax, n_grid)
550	    tau_curve = np.zeros(n_grid)
551	    for i, d in enumerate(deltas):
552	        C_d = C_interpolated(C0, d, K)
553	        plim_result = compute_plim(C_d, st, K)
554	        tau_curve[i] = extract_tau(plim_result, topology)
555	
556	    bias_abs = np.abs(tau_curve - tau_true)
557	    envelope = np.zeros(n_grid)
558	    running_max = 0.0
559	    for i in range(n_grid):
560	        if np.isfinite(bias_abs[i]):
561	            running_max = max(running_max, bias_abs[i])
562	        envelope[i] = running_max
563	
564	    if asv_type == 'sign_flip':
565	        if abs(tau_true) < 1e-12:
566	            return None
567	        baseline_sign = np.sign(tau_true)
568	        for i in range(n_grid):
569	            if np.isfinite(tau_curve[i]) and np.sign(tau_curve[i]) != baseline_sign:
570	                return float(deltas[i])
571	        return None
572	    elif asv_type == 'magnitude':
573	        if abs(tau_true) < 1e-12:
574	            return None
575	        thresh = 0.1 * abs(tau_true)
576	        for i in range(n_grid):
577	            if envelope[i] > thresh:
578	                return float(deltas[i])
579	        return None
580	    elif asv_type == 'significance':
581	        if se_ref is None or se_ref < 1e-12:
582	            return None
583	        for i in range(n_grid):
584	            if np.isfinite(tau_curve[i]) and abs(tau_curve[i]) < 1.96 * se_ref:
585	                return float(deltas[i])
586	        return None
587	    return None
588	
589	
590	def estimate_reference_se(K, topology, params, N_ref=5000, n_mc=50, seed=999):
591	    gen_fn = GEN_FNS[topology]
592	    rng = np.random.default_rng(seed)
593	    tau_hats = []
594	    for _ in range(n_mc):
595	        first_var, Y, A = gen_fn(K, N_ref, params, rng)
596	        if topology == 'iv':
597	            th, _ = wald_estimator(first_var, Y, A, k=1)
598	        elif topology == 'exposure':
599	            b, _ = ols_no_T(Y, A, K)
600	            th = b[1]
601	        else:
602	            b, _ = ols_with_dummies(Y, first_var, A, K)
603	            th = b[1]
604	        if np.isfinite(th):
605	            tau_hats.append(th)
606	    return float(np.std(tau_hats)) if len(tau_hats) > 2 else np.nan
607	
608	
609	def compute_all_asvs(confusion_matrices, all_suff_stats, all_tau_true, all_se_ref):
610	    results = []
611	    for (dataset, model, prompt), C in confusion_matrices.items():
612	        K = DATASETS[dataset]['K']
613	        for topology in TOPOLOGIES:
614	            st = all_suff_stats[(K, topology)]
615	            tau_true = all_tau_true[(K, topology)]
616	            se_ref = all_se_ref.get((K, topology))
617	            for asv_type in ['magnitude', 'significance', 'sign_flip']:
618	                asv = compute_asv_for_matrix(C, K, topology, st, tau_true,
619	                                             asv_type, se_ref=se_ref)
620	                results.append({
621	                    'dataset': dataset, 'model': model, 'prompt': prompt,
622	                    'K': K, 'topology': topology, 'asv_type': asv_type,
623	                    'asv': asv,
624	                })
625	    return results
626	
627	
628	# ============================================================================
629	# 4. F1 vs Downstream Bias
630	# ============================================================================
631	
632	def compute_f1_from_C(C, K, p_A=None):
633	    if p_A is None:
634	        p_A = np.ones(K) / K
635	    precision = np.zeros(K)
636	    recall = np.zeros(K)
637	    f1 = np.zeros(K)
638	    for i in range(K):
639	        recall[i] = C[i, i]
640	        denom = sum(C[i, j] * p_A[j] for j in range(K))
641	        precision[i] = C[i, i] * p_A[i] / denom if denom > 1e-12 else 0
642	        if precision[i] + recall[i] > 1e-12:
643	            f1[i] = 2 * precision[i] * recall[i] / (precision[i] + recall[i])
644	    return {
645	        'macro_f1': float(f1.mean()),
646	        'weighted_f1': float((p_A * f1).sum()),
647	        'per_class_f1': f1.tolist(),
648	    }
649	
650	
651	def f1_vs_bias_analysis(confusion_matrices, biases):
652	    results = []
653	    for b in biases:
654	        key = (b['dataset'], b['model'], b['prompt'])
655	        if key not in confusion_matrices:
656	            continue
657	        C = confusion_matrices[key]
658	        K = b['K']
659	        p_A = make_p_A(K)
660	        f1_info = compute_f1_from_C(C, K, p_A)
661	        abs_bias = abs(b['bias']) if b['bias'] is not None else None
662	        results.append({
663	            'dataset': b['dataset'], 'model': b['model'], 'prompt': b['prompt'],
664	            'K': K, 'topology': b['topology'],
665	            'macro_f1': f1_info['macro_f1'], 'weighted_f1': f1_info['weighted_f1'],
666	            'abs_bias': abs_bias, 'bias_pct': b['bias_pct'],
667	            'sign_flip': b['sign_flip'],
668	        })
669	    return results
670	
671	
672	# ============================================================================
673	# 5. Type I/II Error Rates
674	# ============================================================================
675	
676	def compute_type1_type2_for_C(C, K, topology, params_H1, params_H0,
677	                              st_H1, tau_true,
678	                              n_sim=100, N_sample=5000, seed=42):
679	    gen_fn = GEN_FNS[topology]
680	    rng = np.random.default_rng(seed)
681	
682	    masv = compute_asv_for_matrix(C, K, topology, st_H1, tau_true, 'magnitude')
683	    asv_safe = (masv is None or masv > 1.0)
684	
685	    def _run_mc(params_t, n):
686	        valid = 0; rej = 0
687	        for _ in range(n):
688	            fv, Y, A = gen_fn(K, N_sample, params_t, rng)
689	            Astar = generate_Astar(A, C, rng)
690	            if topology == 'iv':
691	                th, se = wald_estimator(fv, Y, Astar, k=1)
692	            elif topology == 'exposure':
693	                b, svec = ols_no_T(Y, Astar, K)
694	                th, se = b[1], svec[1]
695	            else:
696	                b, svec = ols_with_dummies(Y, fv, Astar, K)
697	                th, se = b[1], svec[1]
698	            if np.isfinite(th) and np.isfinite(se) and se > 1e-10:
699	                valid += 1
700	                if abs(th / se) > 1.96:
701	                    rej += 1
702	        return rej / max(valid, 1), valid
703	
704	    type1_before, v0 = _run_mc(params_H0[topology], n_sim)
705	    power_before, v1 = _run_mc(params_H1[topology], n_sim)
706	    type1_after = type1_before if asv_safe else 0.0
707	    power_after = power_before if asv_safe else 0.0
708	
709	    return {
710	        'type1_before': float(type1_before), 'type1_after': float(type1_after),
711	        'power_before': float(power_before), 'power_after': float(power_after),
712	        'asv_safe': bool(asv_safe), 'magnitude_asv': masv,
713	        'valid_h0': int(v0), 'valid_h1': int(v1),
714	    }
715	
716	
717	# ============================================================================
718	# 6. Inter-model Error Correlation
719	# ============================================================================
720	
721	def compute_inter_model_correlation(confusion_matrices, K, dataset, prompt,
722	                                    n_samples=1000, seed=42):
723	    rng = np.random.default_rng(seed)
724	    p_A = make_p_A(K)
725	    true_labels = rng.choice(K, size=n_samples, p=p_A)
726	
727	    predictions = {}
728	    for model in MODELS:
729	        key = (dataset, model, prompt)
730	        if key in confusion_matrices:
731	            predictions[model] = generate_Astar(true_labels,
732	                                                confusion_matrices[key], rng)
733	        else:
734	            predictions[model] = true_labels.copy()
735	
736	    pairs = [(MODELS[i], MODELS[j]) for i in range(3) for j in range(i + 1, 3)]
737	    results = {}
738	    for m1, m2 in pairs:
739	        p1, p2 = predictions[m1], predictions[m2]
740	        agreement = float((p1 == p2).mean())
741	        observed = agreement
742	        expected = sum((p1 == c).mean() * (p2 == c).mean() for c in range(K))
743	        kappa = float((observed - expected) / (1 - expected)
744	                      ) if expected < 1 - 1e-10 else 0.0
745	        err1 = (p1 != true_labels).astype(float)
746	        err2 = (p2 != true_labels).astype(float)
747	        if err1.std() > 1e-10 and err2.std() > 1e-10:
748	            error_corr = float(np.corrcoef(err1, err2)[0, 1])
749	        else:
750	            error_corr = 0.0
751	        results[f"{m1}-{m2}"] = {
752	            'agreement': agreement,
753	            'kappa': kappa,
754	            'error_correlation': error_corr if np.isfinite(error_corr) else 0.0,
755	        }
756	    return results
757	
758	
759	# ============================================================================
760	# Mock Data Generation
761	# ============================================================================
762	
763	def generate_mock_C(K, rng, diag_range):
764	    C = np.zeros((K, K))
765	    for j in range(K):
766	        diag_val = rng.uniform(diag_range[0], diag_range[1])
767	        remaining = 1.0 - diag_val
768	        if K > 2:
769	            dists = np.abs(np.arange(K) - j).astype(float)
770	            dists[j] = np.inf
771	            weights = 1.0 / dists
772	            weights[j] = 0
773	            noise = rng.uniform(0.5, 1.5, K)
774	            noise[j] = 0
775	            weights = weights * noise
776	            weights /= weights.sum()
777	            C[:, j] = remaining * weights
778	        else:
779	            C[1 - j, j] = remaining
780	        C[j, j] = diag_val
781	    return C
782	
783	
784	def generate_mock_confusion_matrices(seed=12345):
785	    rng = np.random.default_rng(seed)
786	    matrices = {}
787	    diag_ranges = {
788	        'civil_comments': (0.85, 0.95),
789	        'vast': (0.70, 0.90),
790	        'humaid': (0.60, 0.85),
791	    }
792	    for dataset, info in DATASETS.items():
793	        K = info['K']
794	        dr = diag_ranges[dataset]
795	        for model in MODELS:
796	            for prompt in PROMPTS:
797	                matrices[(dataset, model, prompt)] = generate_mock_C(K, rng, dr)
798	    return matrices
799	
800	
801	# ============================================================================
802	# Diagnostic Plots (optional)
803	# ============================================================================
804	
805	def save_f1_vs_bias_plot(f1_bias, output_dir):
806	    if not HAS_MPL:
807	        return
808	    fig, axes = plt.subplots(2, 4, figsize=(20, 10))
809	    axes = axes.flatten()
810	    for idx, topo in enumerate(TOPOLOGIES):
811	        ax = axes[idx]
812	        subset = [r for r in f1_bias if r['topology'] == topo
813	                  and r['abs_bias'] is not None]
814	        if not subset:
815	            ax.set_title(topo)
816	            continue
817	        f1s = [r['macro_f1'] for r in subset]
818	        biases = [r['abs_bias'] for r in subset]
819	        colors = ['red' if r['sign_flip'] else 'steelblue' for r in subset]
820	        ax.scatter(f1s, biases, c=colors, alpha=0.7, s=30)
821	        ax.axvline(0.93, color='gray', linestyle='--', alpha=0.5)
822	        ax.set_xlabel('Macro F1')
823	        ax.set_ylabel('|bias|')
824	        ax.set_title(topo)
825	    if len(TOPOLOGIES) < 8:
826	        axes[-1].axis('off')
827	    fig.suptitle('F1 vs |Downstream Bias| (red=sign flip)', fontsize=14)
828	    fig.tight_layout(rect=[0, 0, 1, 0.96])
829	    fig.savefig(os.path.join(output_dir, 'f1_vs_bias.png'), dpi=150)
830	    plt.close(fig)
831	
832	
833	def save_asv_heatmap(asvs, output_dir):
834	    if not HAS_MPL:
835	        return
836	    mag_asvs = [r for r in asvs if r['asv_type'] == 'magnitude']
837	    datasets_list = list(DATASETS.keys())
838	    fig, axes = plt.subplots(1, 3, figsize=(18, 6))
839	    for didx, dataset in enumerate(datasets_list):
840	        ax = axes[didx]
841	        subset = [r for r in mag_asvs if r['dataset'] == dataset]
842	        configs = sorted(set((r['model'], r['prompt']) for r in subset))
843	        grid = np.full((len(TOPOLOGIES), len(configs)), np.nan)
844	        for r in subset:
845	            ti = TOPOLOGIES.index(r['topology'])
846	            ci = configs.index((r['model'], r['prompt']))
847	            grid[ti, ci] = r['asv'] if r['asv'] is not None else np.nan
848	        im = ax.imshow(grid, cmap='RdYlGn', aspect='auto',
849	                       vmin=0, vmax=2)
850	        ax.set_xticks(range(len(configs)))
851	        ax.set_xticklabels([f"{m[:3]}_{p[:3]}" for m, p in configs],
852	                           rotation=45, ha='right', fontsize=7)
853	        ax.set_yticks(range(len(TOPOLOGIES)))
854	        ax.set_yticklabels(TOPOLOGIES, fontsize=8)
855	        ax.set_title(f'{dataset} (K={DATASETS[dataset]["K"]})')
856	        plt.colorbar(im, ax=ax, shrink=0.8)
857	    fig.suptitle('Magnitude ASV (green=safe, red=fragile)', fontsize=14)
858	    fig.tight_layout(rect=[0, 0, 1, 0.96])
859	    fig.savefig(os.path.join(output_dir, 'asv_heatmap.png'), dpi=150)
860	    plt.close(fig)
861	
862	
863	# ============================================================================
864	# JSON Serialization
865	# ============================================================================
866	
867	def _to_json_safe(obj):
868	    if isinstance(obj, np.integer):
869	        return int(obj)
870	    elif isinstance(obj, np.floating):
871	        v = float(obj)
872	        return None if (np.isnan(v) or np.isinf(v)) else v
873	    elif isinstance(obj, np.ndarray):
874	        return _to_json_safe(obj.tolist())
875	    elif isinstance(obj, dict):
876	        return {str(k): _to_json_safe(v) for k, v in obj.items()}
877	    elif isinstance(obj, list):
878	        return [_to_json_safe(v) for v in obj]
879	    elif isinstance(obj, (bool, np.bool_)):
880	        return bool(obj)
881	    elif isinstance(obj, float):
882	        return None if (np.isnan(obj) or np.isinf(obj)) else obj
883	    return obj
884	
885	
886	# ============================================================================
887	# Main
888	# ============================================================================
889	
890	def main():
891	    parser = argparse.ArgumentParser(description='plan_006: Empirical ASV calibration')
892	    parser.add_argument('--data-dir', default='data/')
893	    parser.add_argument('--output-dir', default='artifacts/plan006/')
894	    parser.add_argument('--mock', action='store_true', help='Use mock data for dry-run')
895	    parser.add_argument('--datasets', type=str, default=None,
896	                        help='Comma-separated dataset filter (e.g. humaid,vast)')
897	    parser.add_argument('--n-sim', type=int, default=1000)
898	    parser.add_argument('--device', type=str, default='cpu')
899	    args = parser.parse_args()
900	
901	    os.makedirs(args.output_dir, exist_ok=True)
902	    t_total = time.time()
903	    n_precomp = 500_000 if args.mock else N_PRECOMP
904	
905	    dataset_filter = None
906	    if args.datasets:
907	        dataset_filter = [d.strip() for d in args.datasets.split(',')]
908	
909	    print("=" * 70)
910	    print("plan_006: Empirical ASV Calibration")
911	    if dataset_filter:
912	        print(f"  Dataset filter: {dataset_filter}")
913	    print("=" * 70)
914	
915	    # --- 1. Confusion matrices ---
916	    if args.mock:
917	        print("\n[1/6] Generating mock confusion matrices...")
918	        confusion_matrices = generate_mock_confusion_matrices()
919	        if dataset_filter:
920	            confusion_matrices = {k: v for k, v in confusion_matrices.items()
921	                                  if k[0] in dataset_filter}
922	    else:
923	        print("\n[1/6] Loading confusion matrices...")
924	        confusion_matrices = load_all_confusion_matrices(args.data_dir,
925	                                                         dataset_filter=dataset_filter)
926	
927	    print(f"  {len(confusion_matrices)} matrices loaded")
928	    for (ds, m, p), C in list(confusion_matrices.items())[:3]:
929	        K = DATASETS[ds]['K']
930	        print(f"    {ds}/{m}/{p}: K={K}, diag_mean={np.diag(C).mean():.3f}")
931	
932	    # --- 2. Precompute sufficient statistics ---
933	    print("\n[2/6] Precomputing sufficient statistics...")
934	    active_datasets = dataset_filter if dataset_filter else list(DATASETS.keys())
935	    K_values = sorted(set(DATASETS[ds]['K'] for ds in active_datasets if ds in DATASETS))
936	    all_suff_stats = {}
937	    all_tau_true = {}
938	    all_params = {}
939	    all_params_H0 = {}
940	    all_se_ref = {}
941	
942	    for K in K_values:
943	        params = make_dgp_params(K)
944	        params_H0 = make_dgp_params_H0(K, params)
945	        all_params[K] = params
946	        all_params_H0[K] = params_H0
947	        for topology in TOPOLOGIES:
948	            seed = K * 1000 + abs(hash(topology)) % 1000
949	            st = precompute_suff_stats(K, topology, params[topology],
950	                                       N=n_precomp, seed=seed)
951	            plim_I = compute_plim(np.eye(K), st, K)
952	            tau_true = extract_tau(plim_I, topology)
953	            all_suff_stats[(K, topology)] = st
954	            all_tau_true[(K, topology)] = tau_true
955	
956	            se = estimate_reference_se(K, topology, params[topology],
957	                                       N_ref=5000,
958	                                       n_mc=min(args.n_sim, 30),
959	                                       seed=seed + 500)
960	            all_se_ref[(K, topology)] = se
961	            se_s = f"{se:.4f}" if np.isfinite(se) else "N/A"
962	            print(f"    K={K:>2} {topology:<13} tau_true={tau_true:>9.6f}  SE_ref={se_s}")
963	
964	    biases = compute_all_biases(confusion_matrices, all_suff_stats, all_tau_true)
965	    n_sign_flips = sum(1 for b in biases if b['sign_flip'])
966	    print(f"  {len(biases)} bias values ({n_sign_flips} sign flips)")
967	
968	    # --- 3. ASV ---
969	    print("\n[3/6] Computing ASV values...")
970	    t3 = time.time()
971	    asvs = compute_all_asvs(confusion_matrices, all_suff_stats,
972	                            all_tau_true, all_se_ref)
973	    print(f"  {len(asvs)} ASV values ({time.time() - t3:.1f}s)")
974	    for at in ['magnitude', 'sign_flip', 'significance']:
975	        sub = [r['asv'] for r in asvs if r['asv_type'] == at and r['asv'] is not None]
976	        if sub:
977	            print(f"    {at}: min={min(sub):.3f} median={np.median(sub):.3f} "
978	                  f"max={max(sub):.3f} ({len(sub)} non-None)")
979	
980	    # --- 4. F1 vs bias ---
981	    print("\n[4/6] F1 vs bias analysis...")
982	    f1_bias = f1_vs_bias_analysis(confusion_matrices, biases)
983	    total_high_f1 = [r for r in f1_bias if r['macro_f1'] is not None and r['macro_f1'] > 0.93]
984	    high_f1_high_bias = [r for r in total_high_f1
985	                         if r['abs_bias'] is not None and r['abs_bias'] > 0.05]
986	    if total_high_f1:
987	        pct = len(high_f1_high_bias) / len(total_high_f1) * 100
988	        print(f"  Baumann check: F1>0.93 with |bias|>0.05: "
989	              f"{len(high_f1_high_bias)}/{len(total_high_f1)} = {pct:.1f}%")
990	    # Sample rows
991	    for r in f1_bias[:3]:
992	        print(f"    {r['dataset']}/{r['model']}/{r['prompt']} {r['topology']}: "
993	              f"F1={r['macro_f1']:.3f} |bias|={r['abs_bias']}")
994	
995	    # --- 5. Type I/II ---
996	    print("\n[5/6] Type I/II error rates...")
997	    t5 = time.time()
998	    type1_type2_results = []
999	    n_configs = len(confusion_matrices) * len(TOPOLOGIES)
1000	    idx = 0
1001	    for (dataset, model, prompt), C in confusion_matrices.items():
1002	        K = DATASETS[dataset]['K']
1003	        for topology in TOPOLOGIES:
1004	            idx += 1
1005	            st = all_suff_stats[(K, topology)]
1006	            tau_true = all_tau_true[(K, topology)]
1007	            r = compute_type1_type2_for_C(
1008	                C, K, topology, all_params[K], all_params_H0[K],
1009	                st, tau_true,
1010	                n_sim=args.n_sim, N_sample=5000, seed=idx * 100)
1011	            type1_type2_results.append({
1012	                'dataset': dataset, 'model': model, 'prompt': prompt,
1013	                'K': K, 'topology': topology, **r,
1014	            })
1015	            if idx % 50 == 0:
1016	                print(f"    {idx}/{n_configs}...")
1017	    print(f"  {len(type1_type2_results)} records ({time.time() - t5:.1f}s)")
1018	    unsafe = sum(1 for r in type1_type2_results if not r['asv_safe'])
1019	    print(f"  ASV-unsafe: {unsafe}/{len(type1_type2_results)}")
1020	
1021	    # --- 6. Inter-model correlation ---
1022	    print("\n[6/6] Inter-model error correlation...")
1023	    inter_model_results = {}
1024	    for dataset in DATASETS:
1025	        K = DATASETS[dataset]['K']
1026	        for prompt in PROMPTS:
1027	            r = compute_inter_model_correlation(
1028	                confusion_matrices, K, dataset, prompt,
1029	                n_samples=1000, seed=abs(hash((dataset, prompt))) % 10000)
1030	            inter_model_results[f"{dataset}_{prompt}"] = r
1031	    print(f"  {len(inter_model_results)} (dataset, prompt) pairs")
1032	    for key, pairs in list(inter_model_results.items())[:2]:
1033	        for pair, vals in pairs.items():
1034	            print(f"    {key} {pair}: agree={vals['agreement']:.3f} "
1035	                  f"kappa={vals['kappa']:.3f} err_corr={vals['error_correlation']:.3f}")
1036	
1037	    # --- Summary ---
1038	    summary = {
1039	        'f1_gt_093_total': len(total_high_f1),
1040	        'f1_gt_093_with_high_bias_pct': (
1041	            len(high_f1_high_bias) / max(len(total_high_f1), 1) * 100),
1042	        'ppi_recommended_scenarios': unsafe,
1043	        'total_scenarios': len(type1_type2_results),
1044	        'ppi_recommended_pct': unsafe / max(len(type1_type2_results), 1) * 100,
1045	    }
1046	
1047	    # --- Save ---
1048	    output = _to_json_safe({
1049	        'confusion_matrices': {
1050	            f"{ds}_{m}_{p}": C.tolist()
1051	            for (ds, m, p), C in confusion_matrices.items()
1052	        },
1053	        'biases': biases,
1054	        'asvs': asvs,
1055	        'f1_vs_bias': f1_bias,
1056	        'type1_type2': type1_type2_results,
1057	        'inter_model_correlation': inter_model_results,
1058	        'summary': summary,
1059	    })
1060	
1061	    out_path = os.path.join(args.output_dir, 'asv_empirical_results.json')
1062	    with open(out_path, 'w') as f:
1063	        json.dump(output, f, indent=2, default=str)
1064	    print(f"\nResults saved to {out_path}")
1065	
1066	    # --- Plots ---
1067	    save_f1_vs_bias_plot(f1_bias, args.output_dir)
1068	    save_asv_heatmap(asvs, args.output_dir)
1069	    if HAS_MPL:
1070	        print(f"Plots saved to {args.output_dir}")
1071	
1072	    # --- Validation ---
1073	    with open(out_path) as f:
1074	        data = json.load(f)
1075	    n_null = str(data).count('null')
1076	    print(f"\nValidation: JSON has {n_null} null values "
1077	          f"(expected for NaN/None ASV entries)")
1078	    for section in ['biases', 'asvs', 'f1_vs_bias', 'type1_type2']:
1079	        print(f"  {section}: {len(data[section])} records")
1080	
1081	    elapsed = time.time() - t_total
1082	    print(f"\nTotal time: {elapsed:.1f}s ({elapsed / 60:.1f}min)")
1083	    print(f"\nSummary:")
1084	    print(f"  F1>0.93 with high bias: {summary['f1_gt_093_with_high_bias_pct']:.1f}%")
1085	    print(f"  PPI++ recommended: {summary['ppi_recommended_scenarios']}/"
1086	          f"{summary['total_scenarios']} ({summary['ppi_recommended_pct']:.1f}%)")
1087	    print("=" * 70)
1088	
1089	
1090	if __name__ == "__main__":
1091	    main()
1092	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "51bcb46c-8751-4c79-a803-201cc9f181ad",
  "isSidechain": true,
  "promptId": "417df0a2-cc01-4fb5-9f46-ee96dfc8be6b",
  "agentId": "a4ddc290a1e5d82db",
  "type": "user",
  "uuid": "c93bb12a-8b56-435e-98db-aa017bfcc86f",
  "sourceToolAssistantUUID": "51bcb46c-8751-4c79-a803-201cc9f181ad",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "ba945ca1-7c3c-4181-a307-80decba09cd0",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 16 · 2026-05-22T11:10:18.933Z_

Perfect! I've found all three items. Here's a summary of my findings:

## Summary

All three items you're looking for are located in **two main files**:

### 1. **Primary Location: `/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/plan_006_asv_empirical.py`**

- **`make_dgp_params(K)`** - Function defined at **line 154**
  - Generates DGP (Data Generating Process) parameters for different causal topologies
  - Returns a dictionary of parameters keyed by topology name
  
- **`compute_plim(C, st, K)`** - Function defined at **line 369**
  - Computes the probability limit under confusion matrix C
  - Takes confusion matrix C, sufficient statistics st, and number of classes K
  
- **`_BETA_POOL`** - Variable defined at **line 57**
  - List of 10 parameter values: `[0.0, 1.0, -0.5, 0.7, -0.3, 0.5, -0.2, 0.4, -0.15, 0.3]`
  - Used to construct parameters for mediation and exposure topologies

### 2. **Secondary Location: `/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib/artifacts/compute_ppi_empirical.py`**

This file contains **duplicate implementations** of the same components:
- **`make_dgp_params(K)`** - Defined at **line 62** (identical to plan_006_asv_empirical.py)
- **`_BETA_POOL`** - Defined at **line 34** (same values)
- **`compute_plim` is NOT in this file** (only the first two items are duplicated here)

The functions in `compute_ppi_empirical.py` appear to be copied from `plan_006_asv_empirical.py` to support empirical validation work, but the original canonical implementations are in `plan_006_asv_empirical.py`.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c93bb12a-8b56-435e-98db-aa017bfcc86f",
  "isSidechain": true,
  "agentId": "a4ddc290a1e5d82db",
  "requestId": "req_011CbHWDX61Rc2unvoeGcqNZ",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "d8162f2e-8fd6-4030-a891-58ac5066fe1a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-prod_0510/projects/causal_annot_error_attrib",
  "sessionId": "ba945ca1-7c3c-4181-a307-80decba09cd0",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01DT25S9qztMPssM6h8SzYZD",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 9856,
      "cache_creation_input_tokens": 17528,
      "cache_read_input_tokens": 19985,
      "output_tokens": 518,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 17528
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 9856,
          "output_tokens": 518,
          "cache_read_input_tokens": 19985,
          "cache_creation_input_tokens": 17528,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 17528,
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
