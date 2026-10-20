# Research conversation: You are auditing a research paper for numerical accuracy before submission. Verify every number in the following appendi

**OntoCoDec: Type-Constrained Information Extraction via Compiled Schema Constraints (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 12
- **Recorded user turns:** 1
- **Tool calls:** 4
- **Original source:** `logs/chats/exported-trajectories/account-2/agent-af50a5a1a4547801d.jsonl`
- **Structured JSON:** [`7fd24024766dfdc66ac8.json`](../../sessions/7f/7fd24024766dfdc66ac8.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Round 1

12 recorded events

### User

_source line 1 · 2026-05-24T04:32:50.275Z_

You are auditing a research paper for numerical accuracy before submission. Verify every number in the following appendix .tex files against the registry data I'll provide. For each number, report: [file:line] number → [source exp_id] value → ✅ or ❌ (actual value X).

FILES TO CHECK (read each one):
1. /home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper/appendix_70b_ablation.tex
2. /home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper/appendix_beam_search.tex  
3. /home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper/appendix_quantization.tex
4. /home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper/appendix_discussion.tex

REGISTRY DATA for verification (key experiments):

**70B zero-shot:**
- eval_70b_zs_scierc_unconstrained: DR=6.4%, RV=0.6%, CF=0, R_F1=11.23, E_F1=35.22
- eval_70b_zs_scierc_grammar_only: DR=6.33%, CF=0, R_F1=11.23
- eval_70b_zs_scierc_semantic_only: DR=1.01%, CF=76, RV=0.6%, R_F1=11.37
- 70b_scierc_constrained (full S1): DR=0%, CF=3.66% (86 count), R_F1=11.24, E_F1=35.14
- r16_70b_scierc_zs_s1: DR=0%, CF=3.5%, R_F1=11.24, E_F1=35.19
- eval_70b_zs_docred_200_unconstrained: DR=13.45%, RV=7.88%, CF=0, R_F1=13.25, E_F1=70.14
- eval_70b_zs_docred_200_grammar_only: DR=17.03%, R_F1=13.23
- eval_70b_zs_docred_200_semantic_only: DR=1.66%, CF=4.07%, RV=8.24%, R_F1=13.05
- eval_70b_zs_docred_200_full_s1: DR=0%, CF=5.34%, R_F1=13.25, E_F1=70.05
- r16_70b_docred_zs_s1: DR=0%, CF=0.04%, R_F1=13.05, E_F1=69.11 (998 docs)

**70B LoRA:**
- eval_70b_lora_scierc_unconstrained: DR=1.5%, CF=0, R_F1=44.73, E_F1=64.86
- eval_70b_lora_scierc_grammar_only: DR=1.5% (0.015), R_F1=44.63, E_F1=64.82
- eval_70b_lora_scierc_semantic_only: DR=0.6%, CF=9, R_F1=44.73, E_F1=64.86
- eval_70b_lora_scierc_s1_constrained: DR=0%, CF=15, R_F1=44.53 (0.4453), E_F1=64.76 (0.6476)
- eval_70b_lora_scierc_full_s2: DR=0%, CF=18, R_F1=36.28, E_F1=62.35
- eval_70b_lora_scierc_beam4_s1: DR=0%, CF=1, R_F1=44.81, E_F1=64.89
- eval_70b_lora_docred_200_unconstrained: DR=0.22%, RV=0.57%, CF=0.06%, R_F1=43.8, E_F1=80.34, parse_fail=10%
- eval_70b_lora_docred_200_grammar_only: DR=0.38%, CF=0.06%, R_F1=43.96, E_F1=80.13, parse_fail=10.5%
- eval_70b_lora_docred_200_semantic_only: DR=0%, CF=0.21%, RV=0.51%, R_F1=43.61, E_F1=80.06, parse_fail=11%
- eval_70b_lora_docred_200_s1_constrained: DR=0%, CF=0.18%, R_F1=43.95, E_F1=79.38, parse_fail=12.5%
- eval_70b_lora_docred_200_beam4_s1: DR=0%, CF=0%, R_F1=48.14, E_F1=85.57, parse_fail=0.5%
- eval_70b_lora_docred_200_full_s2: DR=0%, CF=0.34%, R_F1=36.45, E_F1=84.96

**Beam sweep (Qwen3-8B SciERC):**
- d066_beam_sweep: k1_unc DR=2.11 CF=0 R_F1=42.95 avg_time=2.494; k1_con DR=0 CF=0.5 R_F1=42.95 avg_time=2.932; k2_unc DR=1.54 CF=0 R_F1=44.75 avg_time=2.954; k2_con DR=0 CF=0.11 R_F1=44.60 avg_time=3.463; k4_unc DR=1.89 CF=0 R_F1=43.72 avg_time=3.485; k4_con DR=0 CF=0 R_F1=43.60 avg_time=4.069; k8_unc DR=1.77 CF=0 R_F1=43.17 avg_time=4.194; k8_con DR=0 CF=0 R_F1=43.65 avg_time=5.058
- d062_beam_latency: greedy_constrained=2.873s, beam4_constrained=4.013s, ratio=1.397, greedy_unc=2.612s, beam4_unc=3.446s

**Quantization (INT4):**
- sf2_qwen_int4_scierc_s1: DR=0%, CF=1.1%, R_F1=41.71, E_F1=67.05
- sf2_qwen_int4_docred_s1: DR=0%, CF=0.1%, R_F1=40.07, E_F1=74.84
- sf2_llama_int4_scierc_s1: DR=0%, CF=0.94%, R_F1=43.98, E_F1=67.54
- sf2_llama_int4_docred_s1: DR=0%, CF=0.22%, R_F1=48.04, E_F1=84.18

Report ALL discrepancies. Be thorough - check every percentage, F1 score, violation rate, latency multiplier, and count.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": true,
  "promptId": "4ef057c6-ed80-4dae-9126-cc738ba56a17",
  "agentId": "af50a5a1a4547801d",
  "type": "user",
  "uuid": "e102d09d-dac3-4a60-902c-ac672fe73863",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/.claude/sessions/agent_f7c2f8cc",
  "sessionId": "d74ed321-94ae-476c-899f-c11688aa3239",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "jiggly-watching-nygaard"
}
```

</details>

---

### Runtime record

_source line 2 · 2026-05-24T04:32:50.391Z_

```json
{
  "parentUuid": "e102d09d-dac3-4a60-902c-ac672fe73863",
  "isSidechain": true,
  "agentId": "af50a5a1a4547801d",
  "attachment": {
    "type": "deferred_tools_delta",
    "addedNames": [
      "EnterWorktree",
      "ExitWorktree",
      "Monitor",
      "NotebookEdit",
      "TaskStop",
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
      "EnterWorktree",
      "ExitWorktree",
      "Monitor",
      "NotebookEdit",
      "TaskStop",
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
  "uuid": "63500365-77b1-4fcb-87e4-42e18b068702",
  "timestamp": "2026-05-24T04:32:50.391Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/.claude/sessions/agent_f7c2f8cc",
  "sessionId": "d74ed321-94ae-476c-899f-c11688aa3239",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "jiggly-watching-nygaard"
}
```

---

### Assistant

_source line 3 · 2026-05-24T04:32:53.392Z_



I'll read all four appendix files and then systematically verify every number against the registry data.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "63500365-77b1-4fcb-87e4-42e18b068702",
  "isSidechain": true,
  "agentId": "af50a5a1a4547801d",
  "requestId": "req_011CbLmXpxJngzaG45MdNLR6",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "e8709b78-6088-43d6-a1fc-2d5f1f364bb2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/.claude/sessions/agent_f7c2f8cc",
  "sessionId": "d74ed321-94ae-476c-899f-c11688aa3239",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "jiggly-watching-nygaard",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019Pjt6cCisCN66A6rdvzBWa",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 30334,
      "cache_read_input_tokens": 0,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 30334,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 4,
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

_source line 4 · 2026-05-24T04:32:55.928Z_

<details open><summary>🔧 Tool call — Read · `toolu_01B9HDpcoK2QtB4XhxRbis4z`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper/appendix_70b_ablation.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e8709b78-6088-43d6-a1fc-2d5f1f364bb2",
  "isSidechain": true,
  "agentId": "af50a5a1a4547801d",
  "requestId": "req_011CbLmXpxJngzaG45MdNLR6",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "d577346a-80f4-4440-bc09-d54bfaab7daf",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/.claude/sessions/agent_f7c2f8cc",
  "sessionId": "d74ed321-94ae-476c-899f-c11688aa3239",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "jiggly-watching-nygaard",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019Pjt6cCisCN66A6rdvzBWa",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 30334,
      "cache_read_input_tokens": 0,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 30334,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 4,
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

_source line 5 · 2026-05-24T04:32:55.933Z_

<details><summary>↩ Tool result · `toolu_01B9HDpcoK2QtB4XhxRbis4z`</summary>

```text
1	% Appendix: 70B-Class LoRA Ablation on SciERC
2	% exp_ids: eval_70b_lora_scierc_unconstrained, eval_70b_lora_scierc_grammar_only,
3	%          eval_70b_lora_scierc_semantic_only, eval_70b_lora_scierc_s1_constrained,
4	%          eval_70b_lora_scierc_s2_constrained, eval_70b_lora_scierc_beam4_s1
5	
6	\paragraph{70B-class fine-tuned ablation.}
7	\label{app:70b-ablation}
8	
9	Table~\ref{tab:70b-ft-ablation} presents the constraint ablation on Llama-3.1-70B-Instruct (AWQ INT4) with LoRA fine-tuning on SciERC (551 documents).
10	
11	\begin{table}[h]
12	\centering
13	\small
14	\setlength{\tabcolsep}{3.6pt}
15	\begin{tabular}{@{}l rrrr rr@{}}
16	\toprule
17	\textbf{Mode}
18	  & \textbf{DR\,$\downarrow$} & \textbf{RV\,$\downarrow$} & \textbf{ET\,$\downarrow$} & \textbf{CF}
19	  & \textbf{R-F1\,$\uparrow$} & \textbf{E-F1\,$\uparrow$} \\
20	\midrule
21	Unconstrained & 1.50 & 0 & 0 & 0    & 44.73 & 64.86 \\
22	Grammar       & 1.50 & 0 & 0 & 0    & 44.63 & 64.82 \\
23	Semantic      & 0.60 & 0 & 0 & 9    & 44.73 & 64.86 \\
24	S1            & \textbf{0} & 0 & 0 & 15 & 44.53 & 64.76 \\
25	S2            & \textbf{0} & 0 & 0 & 18 & 36.28 & 62.35 \\
26	Beam4 S1      & \textbf{0} & 0 & 0 & \textbf{1} & \textbf{44.81} & \textbf{64.89} \\
27	\bottomrule
28	\end{tabular}
29	\caption{70B-class (Llama-3.1-70B-Instruct (AWQ INT4)) LoRA ablation on SciERC (551 docs).
30	CF: violation count. F1 $\times$100.}
31	\label{tab:70b-ft-ablation}
32	\end{table}
33	
34	The grammar layer provides no independent DR benefit at 70B (1.50\%\,$\to$\,1.50\% on SciERC; on DocRED zero-shot, DR actually increases $+$3.58\,pp due to RV$\to$DR conversion in the high-$\bar{\kappa}$ schema; Table~\ref{tab:70b-docred-zs-ablation}).
35	The semantic layer is the sole effective defense (1.50\%\,$\to$\,0.60\%, 60\% reduction) with no R-F1 cost ($\Delta{=}$0\,pp), and full S1 eliminates all DR.
36	S2 eliminates DR but causes severe R-F1 degradation ($-$8.45\,pp), indicating that optimal constraint granularity is scale-dependent: the additional S2 constraints become overly restrictive at 70B, where stronger baseline generation makes fine-grained intervention counterproductive.
37	Beam ($k{=}4$) S1 remains the optimal configuration (DR${=}$0\%, CF${=}$1, R-F1${=}$44.81).
38	Notably, S2 increases CF from 15 (S1) to 18 despite its cross-field consistency design, suggesting that over-constraining induces cascading generation degradation that creates new violations.
39	
40	% exp_ids: eval_70b_lora_docred_200_unconstrained, eval_70b_lora_docred_200_grammar_only,
41	%          eval_70b_lora_docred_200_semantic_only, eval_70b_lora_docred_200_s1_constrained,
42	%          eval_70b_lora_docred_200_full_s2, eval_70b_lora_docred_200_beam4_s1
43	\paragraph{70B-class DocRED results.}
44	\label{app:70b-docred}
45	
46	Table~\ref{tab:70b-docred-ablation} presents the six-way constraint ablation on Llama-3.1-70B-Instruct (AWQ INT4) with LoRA fine-tuning on DocRED (998 documents).
47	
48	\begin{table}[h]
49	\centering
50	\small
51	\setlength{\tabcolsep}{3.6pt}
52	\begin{tabular}{@{}l rrrr rr@{}}
53	\toprule
54	\textbf{Mode}
55	  & \textbf{DR\,$\downarrow$} & \textbf{RV\,$\downarrow$} & \textbf{ET\,$\downarrow$} & \textbf{CF}
56	  & \textbf{R-F1\,$\uparrow$} & \textbf{E-F1\,$\uparrow$} \\
57	\midrule
58	Unconstrained & 0.22 & 0.57 & 0 & 2      & 43.80 & 80.34 \\
59	Grammar       & 0.38 & 0    & 0 & 0.06\%$^\dagger$ & 43.96 & 80.13 \\
60	Semantic      & \textbf{0} & 0.51 & 0 & 0.21\%$^\dagger$ & 43.61 & 80.06 \\
61	S1            & \textbf{0} & 0 & 0 & 0.18\%$^\dagger$ & 43.95 & 79.38 \\
62	S2            & \textbf{0} & 0 & 0 & 0.34\%$^\dagger$ & 36.45 & 84.96 \\
63	Beam4 S1      & \textbf{0} & 0 & 0 & \textbf{0} & \textbf{48.14} & \textbf{85.57} \\
64	\bottomrule
65	\end{tabular}
66	\caption{70B-class (Llama-3.1-70B-Instruct (AWQ INT4)) LoRA ablation on DocRED (998 docs).
67	CF: violation count except $^\dagger$reported as percentage (raw count unavailable).
68	F1 $\times$100.
69	PF: greedy S1 12.5\% (25/200 docs), S2 0\% (0/200), beam4 S1 0.5\% (1/200).}
70	\label{tab:70b-docred-ablation}
71	\end{table}
72	
73	The DocRED LoRA ablation mirrors the SciERC pattern: grammar eliminates RV (0.57\%\,$\to$\,0\%) but DR increases slightly ($+$0.16\,pp); semantic-only independently eliminates DR (0.22\%\,$\to$\,0\%) but retains RV (0.51\%).
74	The complementary layer interaction is stable across datasets under LoRA fine-tuning.
75	S2 eliminates DR and parse failures (PF${=}$0\%) but causes severe R-F1 degradation ($-$7.50\,pp vs.\ S1), mirroring the SciERC pattern ($-$8.45\,pp; Table~\ref{tab:70b-ft-ablation}): at 70B, the repair layer over-constrains relation predictions where baseline DR is already near-zero (0.22\%).
76	CF increases from 0.18\% (S1) to 0.34\% (S2), confirming that over-constraining induces cascading inconsistencies across datasets.
77	The $+$4.19\,pp R-F1 gain from beam search (43.95\,$\to$\,48.14) is largely attributable to parse failure recovery: greedy S1 fails to parse 12.5\% of documents (25/200), while beam reduces this to 0.5\% (1/200), recovering $\sim$24 documents that contribute no triples under greedy decoding.
78	The controlled comparison on SciERC---where both greedy and beam achieve 0\% parse failure---isolates the pure beam quality gain at $+$0.28\,pp, consistent with the 8B pattern (Appendix~\ref{app:beam-search}).
79	
80	% exp_ids: r16_70b_docred_zs_unconstrained, r16_70b_docred_zs_grammar_only,
81	%          r16_70b_docred_zs_semantic_only
82	\paragraph{70B-class DocRED zero-shot ablation.}
83	\label{app:70b-docred-zs}
84	
85	Table~\ref{tab:70b-docred-zs-ablation} presents the layer ablation on DocRED under zero-shot decoding at 70B.
86	
87	\begin{table}[h]
88	\centering
89	\small
90	\setlength{\tabcolsep}{3.6pt}
91	\begin{tabular}{@{}l rrrr rr@{}}
92	\toprule
93	\textbf{Mode}
94	  & \textbf{DR\,$\downarrow$} & \textbf{RV\,$\downarrow$} & \textbf{ET\,$\downarrow$} & \textbf{CF}
95	  & \textbf{R-F1\,$\uparrow$} & \textbf{E-F1\,$\uparrow$} \\
96	\midrule
97	Unconstrained & 13.45 & 7.88 & 0 & 0    & 13.25 & 70.14 \\
98	Grammar       & 17.03 & 0    & 0 & 0    & 13.23 & 70.12 \\
99	Semantic      & 1.66  & 8.24 & 0.12 & 132  & 13.05 & 70.10 \\
100	S1            & \textbf{0} & 0 & 0 & 173  & 13.25 & 70.05 \\
101	\bottomrule
102	\end{tabular}
103	\caption{70B-class zero-shot layer ablation on DocRED (200-document subset; baseline DR differs from \S\ref{sec:70b-results}'s 998-document evaluation).
104	CF: violation count. F1 $\times$100.}
105	\label{tab:70b-docred-zs-ablation}
106	\end{table}
107	
108	Grammar-only eliminates RV (7.88\%\,$\to$\,0\%) but DR increases by $+$3.58\,pp (13.45\%\,$\to$\,17.03\%): forced vocabulary mapping in DocRED's high-$\bar{\kappa}$ schema ($\bar{\kappa}{=}0.842$, ${\sim}$16\% type pairs valid) converts RV into DR violations.
109	Semantic-only independently achieves 87.7\% DR reduction (13.45\%\,$\to$\,1.66\%) with no R-F1 cost, confirming the pattern from SciERC (84\%; Table~\ref{tab:70b-ft-ablation}).
110	Full S1 eliminates all DR (13.45\%\,$\to$\,0\%) with zero R-F1 cost (13.25\,$=$\,13.25), confirming that the two layers compose correctly despite their opposing individual DR effects.
111	CF increases from 0 (unconstrained) to 173 (S1), consistent with the pattern that stricter constraint enforcement in ZS introduces more cross-field inconsistencies.
112	The two layers serve complementary roles: grammar provides the RV elimination foundation that semantic-layer DR enforcement requires, while the semantic layer addresses the DR that grammar alone cannot---and in high-$\bar{\kappa}$ schemas, exacerbates.
113	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d577346a-80f4-4440-bc09-d54bfaab7daf",
  "isSidechain": true,
  "promptId": "4ef057c6-ed80-4dae-9126-cc738ba56a17",
  "agentId": "af50a5a1a4547801d",
  "type": "user",
  "uuid": "7181afa7-af57-45c8-8af4-f3a78c566fc2",
  "sourceToolAssistantUUID": "d577346a-80f4-4440-bc09-d54bfaab7daf",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/.claude/sessions/agent_f7c2f8cc",
  "sessionId": "d74ed321-94ae-476c-899f-c11688aa3239",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "jiggly-watching-nygaard"
}
```

</details>

---

### Tool call

_source line 6 · 2026-05-24T04:32:56.409Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Ems8TvUrMxepm9t97xTngZ`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper/appendix_beam_search.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7181afa7-af57-45c8-8af4-f3a78c566fc2",
  "isSidechain": true,
  "agentId": "af50a5a1a4547801d",
  "requestId": "req_011CbLmXpxJngzaG45MdNLR6",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "80be71c3-1876-4889-b7c1-ae7eb195812d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/.claude/sessions/agent_f7c2f8cc",
  "sessionId": "d74ed321-94ae-476c-899f-c11688aa3239",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "jiggly-watching-nygaard",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019Pjt6cCisCN66A6rdvzBWa",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 30334,
      "cache_read_input_tokens": 0,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 30334,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 4,
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

_source line 7 · 2026-05-24T04:32:56.415Z_

<details><summary>↩ Tool result · `toolu_01Ems8TvUrMxepm9t97xTngZ`</summary>

```text
1	\section{Beam Search Compatibility}
2	\label{app:beam-search}
3	
4	OntoCoDec's constraint enforcement is designed to be decoding-strategy agnostic.
5	The main experiments (\S\ref{sec:experiments}) use greedy decoding; Appendix~\ref{app:sampling} validates nucleus sampling.
6	Here we verify compatibility with beam search, completing coverage of the three standard decoding strategies.
7	
8	\paragraph{Implementation challenges.}
9	Two stateful components require adaptation for beam search.
10	(1)~The grammar layer (XGrammar) maintains an internal \texttt{GrammarMatcher} state that tracks the generated token sequence; beam reordering invalidates this state because beams are permuted across steps.
11	Our solution instantiates a fresh \texttt{GrammarMatcher} per beam per step and replays the beam's current token sequence through XGrammar's stateless accept API (64 lines of code).
12	(2)~The semantic layer's \texttt{TypeConstraintProcessor} accumulates entity and relation registries that assume a single generation path.
13	Our solution isolates state per beam by calling \texttt{detect()} on the full partial output at each step, reconstructing all entity/relation state from scratch for each beam independently (61 lines of code).
14	Both adaptations add ${\sim}125$ lines total without modifying the existing greedy/sampling logic.
15	
16	\paragraph{Results.}
17	Table~\ref{tab:beam-search} compares beam search ($k{=}4$, \texttt{early\_stopping=True}) against greedy decoding under S1 constraints across six model-dataset combinations.
18	
19	\begin{table}[h]
20	\centering
21	\small
22	\caption{Beam search ($k{=}4$) vs.\ greedy decoding under S1 constraints (zero-shot).
23	SciERC: 551 documents; DocRED: matched 50-document subsets (same documents for greedy and beam); full 998-doc DocRED results in Table~\ref{tab:beam-docred-998-zs}.
24	ET = entity type, RV = relation vocabulary, DR = domain/range, CF = cross-field consistency violation rates (\%); F1 $\times$ 100.}
25	\label{tab:beam-search}
26	\resizebox{\columnwidth}{!}{%
27	\begin{tabular}{@{}llcccccc@{}}
28	\toprule
29	\textbf{Model / Dataset} & \textbf{Decoding} & ET & RV & DR$\,\downarrow$ & CF$\,\downarrow$ & E-F1$\,\uparrow$ & R-F1$\,\uparrow$ \\
30	\midrule
31	\multirow{2}{*}{Qwen3-8B / SciERC (551)}
32	  & Greedy      & 0 & 0 & 0.93 & 9.90 & 30.98 & 8.36 \\
33	  & Beam ($k{=}4$) & 0 & 0 & \textbf{0} & \textbf{0.53} & 32.00 & 8.56 \\
34	\midrule
35	\multirow{2}{*}{Qwen3-8B / DocRED (50)}
36	  & Greedy      & 0 & 0 & 8.69 & 2.08 & 59.08 & 8.33 \\
37	  & Beam ($k{=}4$) & 0 & 0 & \textbf{0} & \textbf{0.55} & 58.64 & 9.37 \\
38	\midrule
39	\multirow{2}{*}{Llama-3.1-8B / SciERC (551)}
40	  & Greedy      & 0 & 0 & 0.08 & 6.56 & 23.49 & 2.54 \\
41	  & Beam ($k{=}4$) & 0 & 0 & \textbf{0} & \textbf{0.93} & 25.04 & 3.33 \\
42	\midrule
43	\multirow{2}{*}{Llama-3.1-8B / DocRED (50)}
44	  & Greedy      & 0 & 0 & 1.58 & 6.85 & 55.35 & 6.12 \\
45	  & Beam ($k{=}4$) & 0 & 0 & \textbf{0} & \textbf{0.94} & 55.62 & 9.47 \\
46	\midrule
47	\multirow{2}{*}{Mistral-7B / SciERC (551)}
48	  & Greedy      & 0 & 0 & 13.40 & 1.27 & 27.46 & 3.67 \\
49	  & Beam ($k{=}4$) & 0 & 0 & 13.79 & \textbf{0.57} & 26.66 & 4.37 \\
50	\midrule
51	\multirow{2}{*}{Mistral-7B / DocRED (50)}
52	  & Greedy      & 0 & 0 & 28.37 & 0.34 & 51.60 & 4.19 \\
53	  & Beam ($k{=}4$) & 0 & 0 & \textbf{21.37} & \textbf{0.19} & 51.78 & 5.70 \\
54	\bottomrule
55	\end{tabular}}
56	\end{table}
57	
58	\paragraph{Discussion.}
59	For calibrated models (Qwen3-8B, Llama-3.1-8B), beam search achieves DR=0\% across all four model-dataset combinations (both SciERC with 6 entity types, 551 documents, and DocRED with 96 relation types, 50 documents), regardless of schema complexity.
60	On SciERC, beam search eliminates DR for both Qwen (0.93\%\,$\to$\,0\%) and Llama (0.08\%\,$\to$\,0\%), and substantially reduces CF (Qwen: 9.90\%\,$\to$\,0.53\%; Llama: 6.56\%\,$\to$\,0.93\%).
61	On DocRED (matched 50-document subsets), beam search eliminates DR for both Qwen (8.69\%\,$\to$\,0\%) and Llama (1.58\%\,$\to$\,0\%), with CF reductions of 74\% and 86\% respectively.
62	Llama DocRED shows the largest R-F1 gain ($+$3.4\,pp), consistent with beam search recovering valid type assignments that greedy decoding missed due to constraint fallback.
63	The CF reduction is an indirect effect: beam search reduces constraint-fallback frequency by exploring alternative token sequences that satisfy both grammar and semantic masks simultaneously, avoiding the fallback-to-grammar path that produces cross-field inconsistencies under greedy decoding.
64	
65	Mistral-7B-v0.3 constitutes a boundary condition on both datasets.
66	On SciERC (6 entity types), beam search does not reduce DR (13.4\%\,$\to$\,13.8\%), though CF drops by 55\% relative (1.27\%\,$\to$\,0.57\%) and R-F1 improves by $+$0.7\,pp; the unchanged DR confirms that all residual violations stem from entity type misclassification, not constraint-search failure.
67	On DocRED (96 relation types), beam search reduces DR by 25\% relative (28.4\%\,$\to$\,21.4\%): the more complex schema introduces constraint-search failures that beam exploration resolves, but the entity misclassification component remains.
68	This contrast reveals that beam search resolves constraint-search failure (where greedy decoding encounters $G(t) \cap S(t) = \emptyset$ conflicts) but cannot overcome fundamental model calibration limitations in entity typing.
69	
70	\paragraph{Beam width ablation.}
71	Table~\ref{tab:beam-ablation} varies beam width $k \in \{1,2,4,8\}$ on Qwen3-8B / SciERC (551 documents) under S1 constraints.
72	
73	\begin{table}[h]
74	\centering
75	\small
76	\caption{Effect of beam width on constraint satisfaction and extraction quality (Qwen3-8B, SciERC, 551 documents, S1 constraints). $k{=}1$ corresponds to greedy decoding.}
77	\label{tab:beam-ablation}
78	\begin{tabular}{@{}rcccc@{}}
79	\toprule
80	$k$ & DR$\,\downarrow$ & CF$\,\downarrow$ & E-F1$\,\uparrow$ & R-F1$\,\uparrow$ \\
81	\midrule
82	1 (greedy) & 0.93 & 9.90 & 30.98 & 8.36 \\
83	2          & 0.35 & 4.12 & 31.54 & \textbf{8.75} \\
84	4          & \textbf{0}    & 0.53 & 32.00 & 8.56 \\
85	8          & \textbf{0}    & \textbf{0.08} & \textbf{32.18} & 8.39 \\
86	\bottomrule
87	\end{tabular}
88	\end{table}
89	
90	DR elimination at $k{\geq}4$ confirms that constraint-search failure is resolved with moderate exploration width.
91	CF continues to decrease with larger beam (0.08\% at $k{=}8$, only 2 residual violations), while entity extraction quality improves monotonically.
92	$k{=}4$ represents the optimal cost-effectiveness trade-off: it eliminates all DR violations at roughly half the compute cost of $k{=}8$.
93	
94	\paragraph{Beam width--latency Pareto analysis (LoRA).}
95	% exp_id: d066_beam_sweep
96	Figure~\ref{fig:beam-pareto} and Table~\ref{tab:beam-sweep} extend the beam width analysis to LoRA fine-tuning, where the constrained--unconstrained interaction shifts qualitatively: LoRA + S1 already achieves DR=0\% at $k{=}1$ (greedy), so beam search targets CF reduction rather than DR elimination (contrast: zero-shot requires $k{\geq}4$ for DR=0\%).
97	Among constrained configurations, $k{=}2$ is Pareto optimal (R-F1 44.60, CF 0.11\%, 1.39$\times$ vs.\ greedy unconstrained; 1.18$\times$ vs.\ greedy S1); $k{\geq}4$ yields diminishing F1 returns with increasing latency (1.63--2.03$\times$).
98	
99	\begin{figure*}[ht]
100	\centering
101	\includegraphics[width=\textwidth]{figures/beam_pareto.pdf}
102	\caption{Beam width vs.\ R-F1 under LoRA fine-tuning. Left: SciERC (Qwen3-8B solid, Llama-3.1-8B dashed; 551 docs). Right: DocRED (Llama-3.1-8B, 200 docs). Bubble area $\propto$ total violation rate (DR+CF+RV); green rings mark zero-violation configurations. Star: Pareto-optimal ($k{=}2$).}
103	\label{fig:beam-pareto}
104	\end{figure*}
105	
106	\begin{table}[h]
107	\centering
108	\small
109	\caption{Beam width sweep on SciERC (Qwen3-8B LoRA, 551 documents). \textsc{unc}: unconstrained; \textsc{con}: schema-constrained. Latency relative to $k{=}1$ unconstrained. Highlighted row: Pareto-optimal configuration.}
110	\label{tab:beam-sweep}
111	\resizebox{\columnwidth}{!}{%
112	\begin{tabular}{@{}cl cccc cc@{}}
113	\toprule
114	$k$ & Mode & E-F1 & R-F1 & DR (\%) & CF (\%) & Latency (s) & Rel.\ Lat. \\
115	\midrule
116	\multirow{2}{*}{1}
117	 & \textsc{unc} & 66.88 & 42.95 & 2.11 & 0    & 2.494 & 1.00$\times$ \\
118	 & \textsc{con} & 66.88 & 42.95 & \textbf{0} & 0.50 & 2.932 & 1.18$\times$ \\
119	\midrule
120	\multirow{2}{*}{2}
121	 & \textsc{unc} & 67.79 & 44.75 & 1.54 & 0    & 2.954 & 1.18$\times$ \\
122	 & \cellcolor{blue!8}\textsc{con} & \cellcolor{blue!8}67.71 & \cellcolor{blue!8}\textbf{44.60} & \cellcolor{blue!8}\textbf{0} & \cellcolor{blue!8}0.11 & \cellcolor{blue!8}3.463 & \cellcolor{blue!8}1.39$\times$ \\
123	\midrule
124	\multirow{2}{*}{4}
125	 & \textsc{unc} & 67.49 & 43.72 & 1.89 & 0    & 3.485 & 1.40$\times$ \\
126	 & \textsc{con} & 67.22 & 43.60 & \textbf{0} & 0    & 4.069 & 1.63$\times$ \\
127	\midrule
128	\multirow{2}{*}{8}
129	 & \textsc{unc} & 66.40 & 43.17 & 1.77 & 0    & 4.194 & 1.68$\times$ \\
130	 & \textsc{con} & 66.36 & 43.65 & \textbf{0} & 0    & 5.058 & 2.03$\times$ \\
131	\bottomrule
132	\end{tabular}}
133	\end{table}
134	
135	\paragraph{Composability with fine-tuning.}
136	Under greedy decoding, the fine-tuned Qwen3-8B (LoRA, SciERC) with S1 constraints already achieves DR=0\% but retains CF=1.18\% (22 cross-field violations across 551 documents), with E-F1=67.05 and R-F1=43.77.
137	Adding beam search ($k{=}4$) eliminates all residual CF violations (1.18\%\,$\to$\,0\%), yielding zero violations across all four metrics (ET=0\%, RV=0\%, DR=0\%, CF=0\%) while preserving extraction quality (E-F1=66.88, R-F1=43.60; changes within $\pm$0.5\,pp).
138	Llama-3.1-8B (LoRA, SciERC) with S1 constraints and beam search ($k{=}4$) likewise achieves zero violations across all four metrics (ET=0\%, RV=0\%, DR=0\%, CF=0\%) with R-F1=46.18; the zero-violation result thus generalizes across calibrated model families.
139	% exp_id: q1_llama_ft_beam_scierc
140	The three constraint mechanisms (grammar masking, semantic domain-range filtering, and beam exploration) are thus fully composable: each addresses a distinct violation source without interfering with the others or degrading task performance.
141	
142	The initial 50-document DocRED subset (Table~\ref{tab:beam-search}) was subsequently validated on the full 998-document set (Table~\ref{tab:beam-docred-998-zs}): both models achieve DR${=}$0\%, confirming subset representativeness.
143	Llama shows the larger improvement (CF 8.54\%\,$\to$\,1.00\%, 88\% reduction; R-F1 $+$2.6\,pp), consistent with beam search resolving constraint-search failures that greedy decoding cannot.
144	
145	\begin{table}[h]
146	\centering
147	\small
148	\caption{Zero-shot beam search ($k{=}4$) under S1 constraints on the full DocRED dev set (998 documents).
149	ET/RV/DR/CF: violation rates (\%); PF: parse failure rate (\%); F1 $\times$100.}
150	\label{tab:beam-docred-998-zs}
151	\begin{tabular}{@{}lcccccc@{}}
152	\toprule
153	\textbf{Model} & ET & RV & DR$\,\downarrow$ & CF$\,\downarrow$ & E-F1$\,\uparrow$ & R-F1$\,\uparrow$ \\
154	\midrule
155	Qwen3-8B  & 0 & 0 & \textbf{0} & 4.94 & 58.19 & 8.72 \\
156	Llama-3.1-8B & 0 & 0 & \textbf{0} & 1.00 & 57.81 & 8.83 \\
157	\bottomrule
158	\end{tabular}
159	\end{table}
160	
161	Table~\ref{tab:beam-docred-lora} reports LoRA + beam-4 results on the full DocRED dev set (998 documents), extending the fine-tuning composability evaluation from SciERC to the higher-$\bar{\kappa}$ regime.
162	Parse failure rates under LoRA beam-4 range from 1.3\% to 2.9\%, lower than the zero-shot rate.
163	
164	\begin{table}[h]
165	\centering
166	\small
167	\caption{LoRA greedy vs.\ beam search ($k{=}4$) on DocRED (998 dev documents) under S1 constraints.
168	ET = entity type, RV = relation vocabulary, DR = domain/range, CF = cross-field violation rates (\%); PF = parse failure rate (\%); F1 $\times$ 100.}
169	\label{tab:beam-docred-lora}
170	\resizebox{\columnwidth}{!}{%
171	\begin{tabular}{@{}llccccccc@{}}
172	\toprule
173	\textbf{Model} & \textbf{Decoding} & ET & RV & DR$\,\downarrow$ & CF$\,\downarrow$ & E-F1$\,\uparrow$ & R-F1$\,\uparrow$ & PF \\
174	\midrule
175	\multirow{2}{*}{Qwen3-8B}
176	  & Greedy con & 0 & 0 & 0.01 & 0.41 & 81.43 & 40.56 & 8.52 \\ % d065_qwen_greedy_4096_r2
177	  & Beam-4 con & 0 & \textbf{0} & \textbf{0} & 0.01 & 84.00 & 44.46 & 2.9 \\
178	\midrule
179	\multirow{2}{*}{Llama-3.1-8B}
180	  & Greedy con & 0 & 0 & 0.21 & 0.21 & 83.94 & 43.78 & 2.51 \\ % d065: 4096 context
181	  & Beam-4 con & 0 & 0 & 0 & \textbf{0} & \textbf{85.23} & \textbf{47.17} & \textbf{1.3} \\
182	\bottomrule
183	\end{tabular}}
184	\end{table}
185	
186	Llama-3.1-8B achieves zero violations across all four metrics (ET, RV, DR, CF = 0\%) on DocRED with LoRA + beam-4, extending the zero-violation result from SciERC to the high-$\bar{\kappa}$ regime.
187	Qwen3-8B achieves DR=0\% with near-zero CF (0.01\%); R-F1 is preserved ($\pm$0.06\,pp).
188	Combined with the sampling robustness results (Appendix~\ref{app:sampling}), these findings confirm that OntoCoDec's constraint enforcement is compatible with greedy, sampling, and beam search decoding without modification to the core constraint logic.
189	
190	\paragraph{Latency overhead.}
191	Table~\ref{tab:beam-latency} reports wall-clock latency for greedy and beam search ($k{=}4$) under LoRA fine-tuning.
192	
193	\begin{table}[h]
194	\centering
195	\small
196	\begin{tabular}{@{}lrr@{}}
197	\toprule
198	\textbf{Condition} & \textbf{s/doc} & \textbf{Overhead} \\
199	\midrule
200	Greedy unconstrained   & 2.612 & 1.00$\times$ \\
201	Greedy constrained (S1)& 2.873 & 1.10$\times$ \\
202	Beam-4 unconstrained   & 3.446 & 1.32$\times$ \\
203	Beam-4 constrained (S1)& 4.013 & 1.54$\times$ \\
204	\bottomrule
205	\end{tabular}
206	\caption{Latency per document (SciERC, 551 docs, Qwen3-8B LoRA FT, RTX PRO 6000 Blackwell). Overhead relative to greedy unconstrained.}
207	\label{tab:beam-latency}
208	\end{table}
209	
210	Beam search itself adds 32\% latency (4 beams); constraint overhead increases from 10\% (greedy) to 17\% (beam) because each beam independently maintains grammar and semantic state.
211	Per-beam entity registry memory is $O(|\text{entities}|)$ per beam; at $k{=}8$ with typical document sizes, overhead is ${<}$1\,MB per beam, negligible relative to model memory.
212	The total 1.54$\times$ overhead is acceptable for offline batch IE; \texttt{early\_stopping} limits additional compute to partial-sequence exploration.
213	
214	We also explored a type-consensus constraint that forces identical entity types across all relations within a document.
215	However, CF violations occur precisely where the consensus type conflicts with domain-range constraints, creating a fundamental CF$\leftrightarrow$DR trade-off.
216	With DR-aware enforcement (skipping consensus when it would violate domain-range), the layer becomes a no-op (100\% skip rate on 551 SciERC documents and 50 DocRED documents).
217	This confirms that beam search resolves the CF$\leftrightarrow$DR tension through a fundamentally different mechanism: token-level exploration of paths satisfying both constraints simultaneously.
218	
219	\paragraph{TCR reranking under beam search.}
220	TCR reranking with beam search ($k{=}4$) showed no effect on either Qwen3-8B or Llama-3.1-8B under LoRA (0/551 SciERC candidates changed): fine-tuned beam candidates are already type-consistent (TCR score${=}$1.0 for all candidates), confirming that beam search implicitly subsumes post-hoc type consensus under fine-tuning.
221	This further strengthens the beam search deployment recommendation: beam not only eliminates all four violation types but also renders post-hoc CF resolution unnecessary.
222	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "80be71c3-1876-4889-b7c1-ae7eb195812d",
  "isSidechain": true,
  "promptId": "4ef057c6-ed80-4dae-9126-cc738ba56a17",
  "agentId": "af50a5a1a4547801d",
  "type": "user",
  "uuid": "ca035df2-0d84-43b0-bc09-4b87c79adea5",
  "sourceToolAssistantUUID": "80be71c3-1876-4889-b7c1-ae7eb195812d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/.claude/sessions/agent_f7c2f8cc",
  "sessionId": "d74ed321-94ae-476c-899f-c11688aa3239",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "jiggly-watching-nygaard"
}
```

</details>

---

### Tool call

_source line 8 · 2026-05-24T04:32:57.676Z_

<details open><summary>🔧 Tool call — Read · `toolu_01P8uxosfjScebHRf9wU9BFK`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper/appendix_quantization.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ca035df2-0d84-43b0-bc09-4b87c79adea5",
  "isSidechain": true,
  "agentId": "af50a5a1a4547801d",
  "requestId": "req_011CbLmXpxJngzaG45MdNLR6",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "79cc1478-75a9-4b58-8445-2cb1079839f0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/.claude/sessions/agent_f7c2f8cc",
  "sessionId": "d74ed321-94ae-476c-899f-c11688aa3239",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "jiggly-watching-nygaard",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019Pjt6cCisCN66A6rdvzBWa",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 30334,
      "cache_read_input_tokens": 0,
      "output_tokens": 358,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 30334
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 358,
          "cache_read_input_tokens": 0,
          "cache_creation_input_tokens": 30334,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 30334,
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

_source line 9 · 2026-05-24T04:32:57.680Z_

<details><summary>↩ Tool result · `toolu_01P8uxosfjScebHRf9wU9BFK`</summary>

```text
1	% Appendix: Quantization Robustness (SF2 response)
2	% exp_ids: sf2_qwen_int4_scierc_s1, sf2_llama_int4_scierc_s1,
3	%          sf2_qwen_int4_docred_s1, sf2_llama_int4_docred_s1,
4	%          d065_qwen_greedy_4096_r2, d066_sweep_llama_docred_beam1_s1
5	
6	\section{Quantization Robustness}
7	\label{app:quantization}
8	
9	\begin{table}[h]
10	\centering
11	\small
12	\setlength{\tabcolsep}{3.2pt}
13	\resizebox{\columnwidth}{!}{%
14	\begin{tabular}{@{}l rrr rrr@{}}
15	\toprule
16	& \multicolumn{3}{c}{\textbf{Qwen3-8B}} & \multicolumn{3}{c}{\textbf{Llama-3.1-8B}} \\
17	\cmidrule(lr){2-4} \cmidrule(l){5-7}
18	& FP16 & INT4 & $\Delta$ & FP16 & INT4 & $\Delta$ \\
19	\midrule
20	\multicolumn{7}{@{}l}{\textit{SciERC (551 docs)}} \\[2pt]
21	DR\,(\%)\,$\downarrow$  & 0     & 0     & 0      & 0.09  & 0     & $-$0.09 \\
22	R-F1\,$\uparrow$ & 43.77 & 41.71 & $-$2.06 & 45.47 & 43.98 & $-$1.49 \\
23	E-F1\,$\uparrow$ & 67.05 & 67.05 & 0.00   & 67.76 & 67.54 & $-$0.22 \\
24	\addlinespace[4pt]
25	\multicolumn{7}{@{}l}{\textit{DocRED (200 docs)}} \\[2pt]
26	DR\,(\%)\,$\downarrow$  & 0     & 0     & 0      & 0     & 0     & 0 \\
27	R-F1\,$\uparrow$ & 40.79\textsuperscript{\dag} & 40.07 & $-$0.72 & 47.35 & 48.04 & $+$0.69 \\
28	E-F1\,$\uparrow$ & 81.87\textsuperscript{\dag} & 74.84 & $-$7.03\textsuperscript{\ddag} & 85.43 & 84.18 & $-$1.25 \\
29	PF\,(\%) & 8.5\textsuperscript{\dag}  & 18.5  & $+$10.0\textsuperscript{\ddag} & 2.0   & 2.5   & $+$0.5 \\
30	\bottomrule
31	\end{tabular}}
32	\caption{FP16 vs.\ INT4 (AWQ) quantization under LoRA + S1 on SciERC and DocRED. F1 $\times$ 100; PF = parse-failure rate.
33	\textsuperscript{\dag}Qwen DocRED FP16 evaluated on 998 docs (all other configurations use matched subsets).
34	\textsuperscript{\ddag}E-F1 drop primarily attributable to increased parse failures under INT4 quantization on long documents rather than constraint interference (DR remains 0\%).}
35	\label{tab:quantization}
36	\end{table}
37	
38	INT4 (AWQ) quantization preserves constraint enforcement across both datasets: DR remains at 0\% for all four model--dataset configurations under INT4, with the sole FP16 violation (Llama SciERC, 0.09\%) disappearing after quantization.
39	R-F1 changes range from $-$2.06 to $+$0.69\,pp, consistent with expected quantization quality costs independent of the constraint layers.
40	On DocRED, Qwen INT4 exhibits elevated parse failures (18.5\% vs.\ 8.5\% FP16) due to timeout on long documents under quantized inference; the resulting E-F1 gap ($-$7.03\,pp) reflects generation-length degradation rather than constraint-layer interference, as DR remains 0\%.
41	These results provide indirect evidence that the 70B AWQ INT4 results (\S\ref{sec:70b-results}) are not confounded by quantization artifacts in the constraint enforcement mechanism.
42	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "79cc1478-75a9-4b58-8445-2cb1079839f0",
  "isSidechain": true,
  "promptId": "4ef057c6-ed80-4dae-9126-cc738ba56a17",
  "agentId": "af50a5a1a4547801d",
  "type": "user",
  "uuid": "e1447af2-1096-4b66-a64d-a3520e407a24",
  "sourceToolAssistantUUID": "79cc1478-75a9-4b58-8445-2cb1079839f0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/.claude/sessions/agent_f7c2f8cc",
  "sessionId": "d74ed321-94ae-476c-899f-c11688aa3239",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "jiggly-watching-nygaard"
}
```

</details>

---

### Tool call

_source line 10 · 2026-05-24T04:32:57.733Z_

<details open><summary>🔧 Tool call — Read · `toolu_01DheYoPjzGkub7pSzQpTcFG`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper/appendix_discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e1447af2-1096-4b66-a64d-a3520e407a24",
  "isSidechain": true,
  "agentId": "af50a5a1a4547801d",
  "requestId": "req_011CbLmXpxJngzaG45MdNLR6",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "9c3d411b-be95-4ea9-aa1e-d3b2b07d7c1b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/.claude/sessions/agent_f7c2f8cc",
  "sessionId": "d74ed321-94ae-476c-899f-c11688aa3239",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "jiggly-watching-nygaard",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019Pjt6cCisCN66A6rdvzBWa",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 30334,
      "cache_read_input_tokens": 0,
      "output_tokens": 358,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 30334
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 358,
          "cache_read_input_tokens": 0,
          "cache_creation_input_tokens": 30334,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 30334,
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

_source line 11 · 2026-05-24T04:32:57.994Z_

<details><summary>↩ Tool result · `toolu_01DheYoPjzGkub7pSzQpTcFG`</summary>

```text
1	% Appendix B — Extended Discussion
2	% Contains discussion paragraphs moved from the main text during compression.
3	
4	\section{Extended Discussion}\label{app:discussion}
5	
6	%%% CF Dual Mechanism %%%
7	% exp_ids: phase2_scierc_full_s1, llama_scierc_full_s1, llama_docred_full_s1
8	
9	\paragraph{CF Dual Mechanism.}
10	CF violations arise from two distinct mechanisms:
11	(1)~\emph{Registry override}: the semantic constraint forces a domain-compatible type that conflicts with the entity's previously registered type.
12	The entity appears in multiple relations with different type requirements, and the per-relation mask selects the locally valid type without consulting prior assignments.
13	(2)~\emph{Grammar-first fallback} (\S\ref{sec:interaction}): when the semantic mask conflicts with all grammar-valid tokens, the semantic layer is dropped entirely, allowing the grammar layer to generate any structurally valid type, which may differ from the entity's registered type.
14	
15	These mechanisms have sharply different model profiles.
16	Qwen3-8B triggers zero grammar-first fallbacks across all experiments, attributing 100\% of its CF violations to registry override.
17	Llama-3.1-8B, by contrast, triggers 5{,}882 fallbacks on SciERC (10.7 per document) and 57{,}825 on DocRED (63.8 per document), making grammar-first fallback the dominant CF source.
18	This asymmetry is consistent with the cross-model CF gap: Qwen achieves CF\,=\,2.57\% on DocRED vs.\ Llama's 12.02\%, despite both using identical constraint configurations.
19	The difference traces to Llama's less calibrated type predictions, which more frequently conflict with the semantic mask's valid set, triggering fallback.
20	
21	%%% Fallback Behavior and Effective Coverage %%%
22	% exp_ids: cf_fallback_ablation_scierc (final data)
23	
24	\paragraph{Fallback Behavior and Effective Coverage.}
25	\label{app:fallback-coverage}
26	The two-layer architecture produces two distinct fallback mechanisms with different semantic consequences.
27	\emph{Grammar-first fallback} occurs when $S(t) \cap G(t) = \emptyset$: the semantic layer deactivates as a safety valve, preserving structural validity at the cost of potential type violations.
28	The token-level fallback rate (36.6\% on SciERC Llama) is inflated by continuation tokens of multi-token type names (e.g., \textsc{OtherScientificTerm}, averaging 2.87 BPE tokens); at semantically meaningful first-token positions, the rate is 0.04--5.7\% (zero-shot) and drops to $\leq$\,0.11\% under fine-tuning.
29	These events account for the residual DR that persists after constraint enforcement.
30	\emph{Registry-consistent fallback} (4.5\%) occurs when the entity's registered type conflicts with domain/range constraints; the system defaults to the registered type for cross-triple consistency.
31	Together, these mechanisms produce the characteristic profile of composable constraint systems: residual DR traces to grammar-first fallback events, while CF violations arise from registry override events where per-relation enforcement assigns conflicting types.
32	
33	We define \emph{effective semantic constraint coverage} as $1 - f_{\text{gf}}$, where $f_{\text{gf}}$ is the grammar-first fallback rate.
34	On SciERC, Llama-3.1-8B shows $f_{\text{gf}} = 36.6\%$ (6{,}237 of 17{,}024 mask calls), yielding 63.4\% effective coverage.
35	On DocRED, by contrast, Qwen3-8B shows $f_{\text{gf}} = 0.08\%$ (46 of 54{,}859), yielding 99.9\% coverage.
36	The large discrepancy is primarily a tokenization artifact: SciERC entity types are multi-token (e.g., \textsc{OtherScientificTerm}, averaging 2.87 mask calls per type field), and continuation tokens necessarily conflict with the semantic mask, inflating the per-mask-call fallback rate.
37	DocRED types (\textsc{PER}, \textsc{ORG}, \textsc{LOC}, \textsc{TIME}, \textsc{NUM}, \textsc{MISC}) are all single-token, eliminating this inflation.
38	This metric directly quantifies the layer interaction (\S\ref{sec:interaction}): it measures the fraction of decoding steps where both constraint layers are jointly active, providing a fine-grained view beyond aggregate violation rates.
39	Qwen3-8B, with zero grammar-first fallbacks, achieves 100\% effective coverage on SciERC, consistent with its lower residual DR (0.93\% vs.\ Llama's 0.08\%).
40	
41	%%% Fallback Causal Tracing %%%
42	% exp_ids: Task C causal tracing (Qwen/Llama × ZS/FT × S1)
43	
44	\paragraph{Fallback Causal Tracing.}
45	\label{app:causal-tracing}
46	
47	To establish that grammar-first fallback is the \emph{sole} mechanism producing residual DR violations, we instrument the constraint processor to log, for each violation, whether the semantic mask was active ($S(t) \cap G(t) \neq \emptyset$) or bypassed via fallback ($S(t) \cap G(t) = \emptyset$) at the type-bearing position.
48	Table~\ref{tab:causal-tracing} reports the results across four SciERC configurations.
49	
50	\begin{table}[t]
51	\centering
52	\small
53	\begin{tabular}{@{}ll rrr@{}}
54	\toprule
55	\textbf{Model} & \textbf{Setting} & \textbf{Fallback Rate} & \textbf{DR} & \textbf{From FB} \\
56	\midrule
57	Qwen3-8B  & FT S1 & 0/2256 (0\%)    & 0  & N/A \\
58	Qwen3-8B  & ZS S1 & 16/3458 (0.46\%) & 16 & 100\% \\
59	Llama-3.1-8B & FT S1 & 1/2162 (0.05\%) & 1  & 100\% \\
60	Llama-3.1-8B & ZS S1 & 1/2630 (0.04\%) & 1  & 100\% \\
61	\bottomrule
62	\end{tabular}
63	\caption{Fallback causal tracing on SciERC (551 documents). Fallback Rate: type-bearing positions where $S(t) \cap G(t) = \emptyset$ triggers grammar-first fallback. DR: residual domain/range violations. From FB: fraction of DR violations occurring at fallback positions. All violations occur exclusively at tail\_type positions (range constraints are tighter than domain constraints).}
64	\label{tab:causal-tracing}
65	\end{table}
66	
67	When the semantic mask is active, $\text{DR}_{\text{independent}} = 0$: the type constraint processor structurally prevents domain/range violations.
68	All 18 residual DR violations across four configurations occur exclusively at fallback positions, confirming that grammar-first fallback is a necessary condition for residual DR.
69	Fine-tuning reduces fallback to near-zero ($\leq$0.05\%), effectively eliminating the sole source of residual violations.
70	All fallback events occur at tail\_type positions, where $|\operatorname{range}(r, \tau^h)|$ is smaller than $|\operatorname{dom}(r)|$, making the intersection $S(t) \cap G(t)$ more likely to be empty.
71	
72	%%% Enabling Dependency: Confound Analysis %%%
73	
74	\paragraph{Enabling Dependency: Confound Analysis.}
75	\label{app:enabling-confound}
76	
77	The scale-dependent layer interaction (\S\ref{sec:method}) shows that the semantic layer achieves only 24\% DR reduction without the grammar layer (Table~\ref{tab:scierc-ablation}).
78	A potential confound is that the semantic layer depends not only on grammar-enforced vocabulary membership but also on structural enforcement for positional awareness: the semantic layer identifies type-bearing positions by pattern-matching the decoded prefix against the JSON schema, which is reliable only when the grammar layer guarantees valid JSON structure.
79	Without grammar enforcement, malformed structure can cause the semantic layer to misidentify type-bearing positions, reducing effective coverage.
80	We quantify this via the semantic-only ablation (Table~\ref{tab:scierc-ablation}, row~3): CF rises from 0.08\% to 2.71\%, indicating that 2.63\,pp of additional violations trace to structural ambiguity.
81	However, the dominant enabling mechanism remains vocabulary membership: the semantic layer's domain/range lookup requires $r_j \in \mathcal{R}$, which only the grammar layer ensures; without it, OOV relation names produce null constraint lookups.
82	The confound reinforces rather than undermines this interaction: both vocabulary and structural contributions of the grammar layer are prerequisites for effective semantic enforcement.
83	
84	%%% CF-DR Trade-off Analysis %%%
85	% exp_ids: cf_fallback_ablation_scierc (CF fallback vs full_s1 baseline)
86	
87	\paragraph{CF-DR Trade-off Analysis.}
88	\label{app:cf-dr-tradeoff}
89	
90	CF violations are the most prominent residual limitation of OntoCoDec under zero-shot decoding (9.90\% on SciERC, up to 12.02\% on Llama DocRED).
91	We treat this honestly: per-relation independent enforcement cannot eliminate CF without trading it against DR.
92	Table~\ref{tab:cf-dr-tradeoff} reports a pilot ablation in which we replace the grammar-first fallback with a CF-priority fallback that forces the entity's registered type when it conflicts with $\sigma(r)$.
93	
94	\begin{table}[t]
95	\centering
96	\small
97	\begin{tabular}{@{}l rrrr@{}}
98	\toprule
99	\textbf{Configuration} & \textbf{DR\,(\%)} & \textbf{CF\,(\%)} & \textbf{DR+CF} & \textbf{$f_{\text{gf}}$\,(\%)} \\
100	\midrule
101	S1 (baseline) & 0.93 & 9.90 & 10.83 & --- \\
102	CF fallback        & 14.78 & 0.04 & 14.82 & 36.64 \\
103	\midrule
104	$\Delta$ & $+$13.85 & $-$9.86 & $+$3.99 & --- \\
105	\bottomrule
106	\end{tabular}
107	\caption{CF-DR trade-off pilot on SciERC (Qwen3-8B, 551 documents; \texttt{w1\_cf\_fallback\_scierc\_pilot}). CF fallback eliminates CF but re-routes violations to DR, increasing total violations (DR+CF) by 3.99\,pp. $f_{\text{gf}}$: token-level grammar-first fallback rate at type-bearing positions (includes continuation tokens of multi-token type names; first-token position fallback rate is 0.46\% for SciERC Qwen; \S\ref{sec:greedy-limitation}).}
108	\label{tab:cf-dr-tradeoff}
109	\end{table}
110	
111	The CF fallback variant nearly eliminates CF (9.90\%\,$\to$\,0.04\%, $-$9.86\,pp) but at the cost of a 15.9$\times$ increase in DR (0.93\%\,$\to$\,14.78\%, $+$13.85\,pp).
112	% exp_id: w1_cf_fallback_scierc_pilot: DR=0.1478, CF=0.0004, f_gf=0.3664
113	This is not a net improvement: total violations (DR+CF) rise from 10.83\% to 14.82\% ($+$3.99\,pp), so the change \emph{re-routes} violations rather than reducing them.
114	The mechanism is mechanical: each token position with conflicting masks must commit to one violation type; when the CF fallback forces the system to emit the entity's registered type even though it lies outside $\sigma(r)$, the resulting triple satisfies cross-entity consistency but violates domain/range.
115	The token-level grammar-first fallback is triggered at 36.64\% of type-bearing positions (0.46\% at first-token positions; \S\ref{sec:greedy-limitation}); this conflict is structural, not a tunable hyperparameter.
116	
117	We interpret this as a fundamental tension in composable constraint systems with \emph{per-relation independent} enforcement: enforcement priority can be allocated between DR and CF but cannot independently minimize both.
118	Within this design, the current S1 configuration sits near the Pareto frontier of the trade-off, achieving 0.93\% DR at the cost of 9.90\% CF.
119	The direction of the trade-off is consistent beyond SciERC/Qwen3-8B: across all six zero-shot configurations (3 models $\times$ 2 datasets), DR and CF are descriptively inversely associated, with no setting showing both high DR and high CF simultaneously (Table~\ref{tab:cross-model}); however, $n{=}6$ is insufficient for statistical inference on this correlation.
120	The pattern is a structural consequence of per-relation enforcement with grammar-first fallback, not a model- or dataset-specific artifact; we select SciERC/Qwen3-8B for detailed ablation because it exhibits the highest CF (9.90\%), making the trade-off most visible.
121	While the inverse association holds across all configurations, the absolute trade-off magnitude may differ in settings with higher baseline CF, such as Llama DocRED (CF = 12.02\%), where the larger CF headroom could yield proportionally larger shifts under alternative fallback priorities.
122	The CF residual is concentrated in schema ambiguity rather than enforcement failure: 63.3\% of CF violations on SciERC involve the catch-all \textsc{Generic} type (Table~\ref{tab:cf-distribution}), which competes with every content type depending on anaphoric vs.\ referential use, a distinction the per-slot decoder cannot resolve without document-level coreference.
123	
124	Two complementary paths can lower CF without re-routing it to DR.
125	(i)~\emph{Reduce the baseline conflict rate.} Composing OntoCoDec with LoRA fine-tuning on SciERC reduces CF by 88\% relative to the zero-shot setting (9.90\%\,$\to$\,1.18\%; Table~\ref{tab:composability}), because the fine-tuned model's per-slot type predictions agree more often with the entity registry, so the per-relation mask and the registry intersect more frequently.
126	% exp_id: w5_lora_scierc_constrained_eval: CF=0.0118
127	The remaining 1.18\% still traces to \textsc{Generic}$\leftrightarrow$X schema ambiguity, so this path is empirically validated on one dataset and one fine-tuning method but does not generalize without further evidence.
128	(ii)~\emph{Replace per-relation enforcement with global entity-level type consensus during decoding.} This is outside the scope of OntoCoDec's forward-only autoregressive design and is left to future work.
129	
130	%%% Dual-Factor Quantitative Analysis %%%
131	% exp_ids: phase2_scierc_full_s1, phase2_docred_full_s1,
132	%          llama_scierc_full_s1, llama_docred_full_s1
133	
134	\paragraph{Dual-Factor Quantitative Analysis.}
135	\label{app:dual-factor}
136	
137	Figure~\ref{fig:dual-factor-scatter} plots residual DR against the product $\bar{\kappa} \times \text{RV}_{\text{baseline}}$ for model$\times$dataset configurations.
138	For \emph{calibrated} models (Qwen3-8B, Llama-3.1-8B; unconstrained ET${<}$3\% on both datasets), a linear fit yields $y = 0.366x - 0.138$ with $R^2 = 0.886$ ($n{=}4$, $F(1,2) = 15.54$, $p \approx 0.058$); with only four data points (df $= 2$) and $p > 0.05$, this constitutes a descriptive characterization rather than a confirmatory statistical test.
139	The strong fit supports the dual-factor pattern from \S\ref{sec:composition}: residual DR is governed by the product of schema tightness and baseline violation rate.
140	Mistral-7B (unconstrained ET${=}$7.58\% on DocRED) deviates from this pattern: its residual DR on DocRED (33.21\%) substantially exceeds the linear prediction. When model calibration is insufficient (ET${>}$5\% on either dataset), residual DR is dominated by entity misclassification rather than constraint-search failure.
141	This motivates a principled exclusion criterion: models with unconstrained ET${>}$5\% on either dataset fall outside the regime where the tightness$\times$RV product is the primary DR driver.
142	The two DocRED points (high $\bar{\kappa}{=}0.842$) separate cleanly from the two SciERC points (low $\bar{\kappa}{=}0.333$), and within each dataset the model with higher baseline RV shows higher residual DR.
143	
144	\begin{figure}[t]
145	\centering
146	\includegraphics[width=0.75\columnwidth]{figures/dual_factor_scatter.pdf}
147	\caption{Residual DR vs.\ Schema Restrictiveness $\times$ Baseline Violation Rate ($\bar{\kappa} \times \text{RV}_{\text{baseline}}$) across four model$\times$dataset configurations ($n{=}3$ schemas; descriptive only).
148	Linear fit (calibrated models): $y = 0.366x - 0.138$, $R^2 = 0.886$, $p{=}0.058$ ($n{=}4$, df${=}2$; not significant); Mistral deviates due to entity misclassification.}
149	\label{fig:dual-factor-scatter}
150	\end{figure}
151	
152	%%% Dataset-Dependent F1 Impact (moved from §7) %%%
153	% exp_ids: d012_bootstrap_ci (DocRED +0.49pp p<0.001, SciERC +0.13pp p=0.58),
154	%          phase0_docred_unconstrained (RV=29.66%), phase0_scierc_unconstrained (RV=1.39%)
155	
156	\paragraph{Dataset-Dependent F1 Impact.}
157	The divergence in F1 significance between DocRED ($+$0.49\,pp, $p < 0.001$) and SciERC ($+$0.13\,pp, $p = 0.58$) traces to a single mechanism: grammar-layer elimination of out-of-vocabulary relation names.
158	DocRED's baseline RV of 29.66\% produces 5{,}189 OOV predictions counted as false positives; eliminating them yields a significant precision gain.
159	SciERC's baseline RV is only 1.39\% (24 OOV predictions), too few to produce a detectable F1 effect.
160	Llama-3.1-8B's lower baseline RV (16.03\%) yields a smaller but directionally consistent improvement ($+$0.29\,pp vs.\ $+$0.49\,pp); F1 gain magnitude is proportional to baseline OOV rate.
161	% exp_ids: phase0_docred_unconstrained, phase0_scierc_unconstrained
162	% exp_ids: llama_docred_unconstrained (RV=16.03%), llama_docred_full_s1 (R-F1 delta=+0.29pp)
163	
164	%%% Bootstrap CIs and Effect Sizes %%%
165	% exp_ids: bootstrap_ci_ft_composability, r12_table2_bootstrap_ci
166	
167	\paragraph{Bootstrap Confidence Intervals and Effect Sizes.}
168	\label{app:bootstrap-effect-sizes}
169	
170	Table~\ref{tab:bootstrap-effect-sizes} reports per-configuration bootstrap CIs and Cohen's $d$ effect sizes (10{,}000 iterations, document-level resampling, seed=42) for the fine-tuning composability results (Table~\ref{tab:composability}).
171	After Bonferroni correction for $k{=}4$ comparisons ($\alpha_{\text{adj}}{=}0.0125$), no R-F1 difference reaches significance; all R-F1 effect sizes are negligible to small ($|d| \leq 0.37$; Cohen, 1988).
172	Per-configuration corrected $p$-values: Qwen3-8B/SciERC $p_B{=}1.00$, Qwen3-8B/DocRED $p_B{=}0.224$, Llama-3.1-8B/SciERC $p_B{=}1.00$, Llama-3.1-8B/DocRED $p_B{=}1.00$.
173	Constraint enforcement thus preserves extraction quality while achieving large, highly significant reductions in domain-range violations ($|d| \geq 3.0$, all $p_{\text{Bonf}} < 0.005$).
174	
175	\begin{table}[t]
176	\centering
177	\small
178	\setlength{\tabcolsep}{3pt}
179	\begin{tabular}{@{}ll rrrr@{}}
180	\toprule
181	\textbf{Model} & \textbf{Dataset} & $\Delta$\textbf{(pp)} & \textbf{95\% CI} & $p$ & $d$ \\
182	\midrule
183	\multicolumn{6}{@{}l}{\textbf{R-F1 difference (S1 $-$ unconstrained):}} \\
184	Qwen3-8B & SciERC & $-$0.10 & [$-$0.30, 0.00] & .726 & $-$0.05 \\
185	Qwen3-8B & DocRED & $-$0.31 & [$-$0.69, $+$0.01] & .056 & $-$0.37 \\
186	Llama-3.1-8B & SciERC & $+$0.02 & [0.00, $+$0.07] & .736 & $+$0.01 \\
187	Llama-3.1-8B & DocRED & $+$0.06 & [$-$0.11, $+$0.25] & .535 & $+$0.07 \\
188	\midrule
189	\multicolumn{6}{@{}l}{\textbf{DR\% reduction:}} \\
190	Qwen3-8B & SciERC & $-$1.95 & [$-$2.87, $-$1.11] & $<$.001 & $-$6.15 \\
191	Qwen3-8B & DocRED & $-$0.75 & [$-$1.07, $-$0.48] & $<$.001 & $-$7.00 \\
192	Llama-3.1-8B & SciERC & $-$1.02 & [$-$1.98, $-$0.29] & $<$.001 & $-$3.17 \\
193	Llama-3.1-8B & DocRED & $-$0.29 & [$-$0.53, $-$0.10] & $<$.001 & $-$3.02 \\
194	\bottomrule
195	\end{tabular}
196	\caption{Bootstrap CIs and Cohen's $d$ for Table~\ref{tab:composability} (10{,}000 iterations, document-level resampling, seed=42).
197	$d$: Cohen's $d$ from pooled bootstrap SD.
198	Top: R-F1 (S1 $-$ unconstrained); no comparison significant after Bonferroni correction ($k{=}4$, $\alpha_{\text{adj}}{=}0.0125$); $|d| \leq 0.37$ (negligible--small).
199	Bottom: DR\% reduction; all $p_{\text{Bonf}} < 0.005$, $|d| \geq 3.0$ (large).}
200	\label{tab:bootstrap-effect-sizes}
201	\end{table}
202	
203	%%% Paragraph 1: Low F1 Practical Significance %%%
204	% exp_ids: phase2_scierc_full_s1 (R-F1=8.36%), phase2_docred_full_s1 (R-F1=8.23%),
205	%          phase0_scierc_unconstrained (DR=15.37%), phase2_docred_unconstrained (DR=18.46%)
206	
207	\paragraph{Practical Significance of Zero-Shot F1.}
208	Our reported relation F1 of approximately 8\% on both SciERC and DocRED reflects the inherent difficulty of zero-shot closed IE, where the model receives no task-specific training examples.
209	For reference, supervised state-of-the-art systems on SciERC achieve approximately 49--53\% relation F1 with full training data~\citep{zhong2021frustratingly,ye2022packed}.
210	Constraint enforcement operates largely independently of the extraction model's intrinsic capability: it restricts the output space to ontologically valid triples regardless of the underlying model's accuracy.
211	Even after LoRA fine-tuning, residual DR of 1--2\% persists on tight-constraint relations (Table~\ref{tab:composability}); constraints remain necessary at deployment-grade quality.
212	% exp_ids: w5_lora_scierc_unconstrained_eval, w5_llama_lora_scierc_unconstrained_eval
213	In our evaluation, F1 serves as a \emph{control variable} verifying that constraint enforcement does not degrade extraction quality, not as an optimization target.
214	The contribution of this work is the constraint enforcement method itself; the zero-shot setting stress-tests constraint robustness under maximum model uncertainty, while composability with fine-tuning (\S\ref{sec:composability}) validates practical deployment value.
215	
216	%%% Paragraph 4: Decoding-Time vs. Post-Hoc Enforcement %%%
217	% exp_ids: posthoc_filtering_baseline, phase2_scierc_full_s1 (R-F1=8.36%),
218	%          phase2_docred_full_s1 (R-F1=8.23%, ET=0%)
219	
220	\paragraph{Decoding-Time vs.\ Post-Hoc Enforcement.}
221	Post-hoc filtering (generating triples without constraints, then removing schema-violating predictions) yields higher precision and consequently higher F1 than OntoCoDec on both datasets (SciERC 8.63 vs.\ 8.36; DocRED 9.61 vs.\ 8.23).
222	% posthoc: SciERC F1=8.63, DocRED F1=9.61; OntoCoDec: SciERC R-F1=8.36, DocRED R-F1=8.23
223	However, this precision gain comes at substantial cost.
224	On DocRED, post-hoc filtering discards 48.1\% of all predicted triples, including 127 true positives (11.2\% of correct predictions); recall drops from 9.46\% to 8.40\%.
225	% posthoc_docred: rejection=48.1%, tp_lost=127/1137, R: 9.46→8.40
226	Entity type violations remain unresolved (ET\,=\,2.47\% vs.\ OntoCoDec's 0\%), as filtering targets only domain/range and vocabulary violations.
227	% posthoc_docred: ET_residual=2.47%; phase2_docred_full_s1: ET=0%
228	OntoCoDec's decoding-time approach avoids this information loss by guiding generation toward compliant outputs rather than discarding non-compliant ones, preserving both recall and entity type validity.
229	The two strategies are complementary: post-hoc filtering can serve as an additional safety net for residual violations that decoding-time enforcement does not fully resolve.
230	
231	%%% CF Violation Distribution %%%
232	% exp_ids: phase2_scierc_full_s1 (CF=245), llama_scierc_full_s1 (CF=162),
233	%          phase2_docred_full_s1 (CF=2670), llama_docred_full_s1 (CF=3824)
234	
235	\paragraph{Cross-Field Violation Distribution.}
236	\label{app:cf-distribution}
237	
238	Table~\ref{tab:cf-distribution} reports the complete distribution of conflicting-type pairs for SciERC zero-shot S1 (248 CF violations across 245 unique entity-document pairs; no mention triggered $\geq$3 types).
239	Conflicts involving the \textsc{Generic} type account for 63.3\% (155/245) of all violations.
240	\textsc{Generic} is SciERC's anaphoric/placeholder label (``this approach'', ``the method''), which competes with every content type depending on whether the mention is used anaphorically or referentially, a distinction the per-slot constrained decoder cannot resolve without document-level coreference.
241	
242	The pattern generalizes across models and datasets: on Llama-3.1-8B SciERC, \textsc{Generic}$\leftrightarrow$\textsc{OtherScientificTerm} remains the top pair (53/162, 32.7\%); on DocRED, the analogous catch-all type \textsc{MISC} drives 76.6\% of Qwen's CF violations.
243	Under unconstrained decoding, CF rates collapse to $\leq$1\% on both datasets; CF violations are a side-effect of per-slot type commitment rather than a model deficiency.
244	
245	\begin{table}[t]
246	\centering
247	\small
248	\begin{tabular}{@{}lr r@{}}
249	\toprule
250	\textbf{Conflicting Type Pair} & \textbf{Count} & \textbf{\%} \\
251	\midrule
252	Generic $\leftrightarrow$ OtherScientificTerm & 85 & 34.7 \\
253	Generic $\leftrightarrow$ Material & 35 & 14.3 \\
254	Generic $\leftrightarrow$ Metric & 30 & 12.2 \\
255	Method $\leftrightarrow$ Task & 20 & 8.2 \\
256	Material $\leftrightarrow$ Method & 17 & 6.9 \\
257	OtherScientificTerm $\leftrightarrow$ Task & 12 & 4.9 \\
258	\midrule
259	10 further pairs (each $\leq$3.3\%) & 46 & 18.8 \\
260	\midrule
261	\textbf{Total} & \textbf{245} & 100.0 \\
262	\bottomrule
263	\end{tabular}
264	\caption{CF violation distribution on SciERC zero-shot S1 (Qwen3-8B, 551 documents).
265	All 245 unique entity-document pairs involve pairwise conflicts.
266	Conflicts involving \textsc{Generic} account for 63.3\%.}
267	\label{tab:cf-distribution}
268	\end{table}
269	
270	%%% Cascade Error Analysis %%%
271	% exp_ids: phase2_scierc_full_s1 (ZS: CF=248), w5_lora_scierc_full_s1_eval (FT: CF=22)
272	
273	\paragraph{Cascade Error Analysis.}
274	\label{app:cascade-analysis}
275	
276	Table~\ref{tab:cascade-breakdown} decomposes zero-shot CF violations by source mechanism.
277	The dominant source is hallucinated entities (58.1\%): the model generates entity names absent from the input document, and the entity registry assigns a type based on the first occurrence that may conflict with a subsequent valid entity sharing the same surface form.
278	True cascade errors---where first-seen type registration for a \emph{real} entity locks an incorrect type that blocks a subsequent valid assignment---account for only 7.3\% (18/248).
279	Correct type locks (first-seen type is correct and prevents an incorrect subsequent assignment) are 2.5$\times$ more frequent (18.1\%, 45/248), indicating that the first-seen registration mechanism provides a net benefit for type consistency.
280	
281	Under fine-tuning (22 CF violations, 20 documents), cascade errors are completely eliminated (0/22): LoRA training calibrates entity typing sufficiently that first-seen registrations are consistently correct.
282	This confirms that cascade errors are a model calibration issue exposed by the constraint mechanism, not an inherent deficiency of first-seen registration.
283	
284	\begin{table}[h]
285	\centering
286	\small
287	\begin{tabular}{@{}l rr@{}}
288	\toprule
289	\textbf{CF Source Category} & \textbf{Count} & \textbf{\%} \\
290	\midrule
291	Hallucinated entity & 144 & 58.1 \\
292	Correct type lock & 45 & 18.1 \\
293	True cascade error & 18 & 7.3 \\
294	Other / ambiguous & 41 & 16.5 \\
295	\midrule
296	\textbf{Total} & \textbf{248} & 100.0 \\
297	\bottomrule
298	\end{tabular}
299	\caption{CF violation source breakdown on SciERC zero-shot S1 (Qwen3-8B, 551 documents; exp\_id: phase2\_scierc\_full\_s1).
300	``Hallucinated entity'': generated entity absent from input.
301	``True cascade error'': first-seen lock on incorrect type blocks valid subsequent assignment.
302	``Correct type lock'': first-seen type correct, prevents incorrect subsequent type.
303	Under fine-tuning, cascade errors are completely eliminated (0/22 CF violations; exp\_id: w5\_lora\_scierc\_full\_s1\_eval).}
304	\label{tab:cascade-breakdown}
305	\end{table}
306	
307	%%% Per-Relation DR Elimination under Fine-Tuning %%%
308	% exp_ids: lora_scierc_unconstrained, lora_scierc_full_s1
309	
310	\paragraph{Per-Relation DR Elimination under Fine-Tuning.}
311	\label{app:lora-per-relation}
312	
313	Table~\ref{tab:lora-per-relation} presents the per-relation breakdown of DR elimination when OntoCoDec is composed with LoRA fine-tuning on SciERC.
314	Fine-tuning alone eliminates DR on four of seven relations but leaves non-zero violations on the three tightest-constraint relations: \textsc{Evaluate-for} ($\kappa{=}0.361$, 13.13\%), \textsc{Part-of} ($\kappa{=}0.417$, 5.77\%), and \textsc{Compare} ($\kappa{=}0.528$, 5.00\%).
315	Adding OntoCoDec constraints eliminates all remaining violations across all relations.
316	One \textsc{Evaluate-for} triple (99\,$\to$\,98) is redirected to \textsc{Used-for} (634\,$\to$\,635) by token-level masking: the head entity's registered type falls outside \textsc{Evaluate-for}'s domain, and the semantic mask steers generation to the nearest valid relation.
317	
318	\begin{table}[t]
319	\centering
320	\small
321	\begin{tabular}{@{}l r rr rr@{}}
322	\toprule
323	& & \multicolumn{2}{c}{\textbf{LoRA Unconstr.}} & \multicolumn{2}{c}{\textbf{LoRA + S1}} \\
324	\cmidrule(lr){3-4} \cmidrule(l){5-6}
325	\textbf{Relation} & $\kappa$ & DR\,(\%) & $n$ & DR\,(\%) & $n$ \\
326	\midrule
327	Evaluate-for & 0.361 & 13.13 & 99 & \textbf{0} & 98 \\
328	Part-of      & 0.417 & 5.77  & 52 & \textbf{0} & 52 \\
329	Compare      & 0.528 & 5.00  & 40 & \textbf{0} & 40 \\
330	Conjunction  & 0.306 & 1.31  & 153 & \textbf{0} & 153 \\
331	Feature-of   & 0.278 & 1.35  & 74 & \textbf{0} & 74 \\
332	Used-for     & 0.028 & 0.16  & 634 & \textbf{0} & 635 \\
333	Hyponym-of   & 0.417 & 0     & --- & \textbf{0} & --- \\
334	\bottomrule
335	\end{tabular}
336	\caption{Per-relation DR elimination on SciERC with LoRA fine-tuning (Qwen3-8B).
337	$\kappa$: constraint tightness; $n$: predicted triple count.
338	Used-for gains one triple from Evaluate-for redirection.}
339	\label{tab:lora-per-relation}
340	\end{table}
341	
342	%%% Fine-Tuned Four-Way Ablation %%%
343	% exp_ids: w5_lora_scierc_*, w5_llama_lora_scierc_*, w5_qwen_docred_*, w5_llama_docred_*, w8_*
344	
345	\paragraph{Fine-Tuned Four-Way Ablation.}
346	\label{app:ft-ablation}
347	
348	Table~\ref{tab:ft-ablation} presents the four-way constraint ablation on fine-tuned models across both datasets, isolating each layer's contribution when the base model has already internalized schema knowledge.
349	
350	\begin{table}[t]
351	\centering
352	\small
353	\setlength{\tabcolsep}{3pt}
354	\resizebox{\columnwidth}{!}{%
355	\begin{tabular}{@{}lll rrrrr rr@{}}
356	\toprule
357	\textbf{Dataset} & \textbf{Model} & \textbf{Mode} & \textbf{DR\,$\downarrow$} & \textbf{RV\,$\downarrow$} & \textbf{ET\,$\downarrow$} & \textbf{CF} & \textbf{PF} & \textbf{E-F1\,$\uparrow$} & \textbf{R-F1\,$\uparrow$} \\
358	\midrule
359	\multirow{8}{*}{SciERC}
360	  & \multirow{4}{*}{Qwen3-8B}
361	    & Unconstrained & 1.95 & 0.00 & 0.00 & 0.00 & 0.00 & 67.05 & 43.86 \\
362	  & & Grammar       & 1.90 & 0.00 & 0.00 & 0.00 & 0.00 & 67.05 & 43.86 \\
363	  & & Semantic      & 0.60 & 0.00 & 0.00 & 0.18 & 0.00 & 67.05 & 43.69 \\
364	  & & S1       & \textbf{0}    & 0.00 & 0.00 & 1.18 & 0.00 & 67.05 & 43.77 \\
365	  \cmidrule(l){2-10}
366	  & \multirow{4}{*}{Llama-3.1-8B}
367	    & Unconstrained & 1.11 & 0.00 & 0.00 & 0.00 & 0.00 & 67.76 & 45.45 \\
368	  & & Grammar       & 1.11 & 0.00 & 0.00 & 0.00 & 0.00 & 67.76 & 45.45 \\
369	  & & Semantic      & 0.65 & 0.00 & 0.00 & 0.10 & 0.00 & 67.76 & 45.47 \\
370	  & & S1       & \textbf{0.09} & 0.00 & 0.00 & 0.46 & 0.00 & 67.76 & 45.47 \\
371	\midrule
372	\multirow{8}{*}{DocRED}
373	  & \multirow{4}{*}{Qwen3-8B}
374	    & Unconstrained & 0.76 & 0.27 & 0.00 & 0.12 & 7.11 & 82.15 & 40.86 \\
375	  & & Grammar       & 0.61 & 0.00 & 0.00 & 0.11 & 7.01 & 82.19 & 40.85 \\
376	  & & Semantic      & 0.19 & 0.23 & 0.00 & 0.27 & 7.52 & 82.15 & 40.85 \\
377	  & & S1       & \textbf{0.01} & 0.00 & 0.00 & 0.41 & 8.52 & 81.43 & 40.56 \\
378	  \cmidrule(l){2-10}
379	  & \multirow{4}{*}{Llama-3.1-8B}
380	    & Unconstrained & 0.49 & 0.15 & 0.00 & 0.08 & 2.30 & 83.93 & 43.72 \\
381	  & & Grammar       & 0.51 & 0.00 & 0.00 & 0.12 & 2.30 & 84.04 & 43.72 \\
382	  & & Semantic      & 0.48 & 0.15 & 0.00 & 0.16 & 2.40 & 84.02 & 43.85 \\
383	  & & S1       & \textbf{0.21} & 0.00 & 0.00 & 0.21 & 2.51 & 83.94 & 43.78 \\
384	\bottomrule
385	\end{tabular}}%
386	\caption{Four-way constraint ablation on fine-tuned models (LoRA, 2 models $\times$ 2 datasets).
387	DR/RV/ET: violation rates (\%) over predicted relations; CF: over predicted entities; PF: parse failure rate (\%); F1 $\times$100.
388	Grammar layer is a no-op post-fine-tuning (DR change $<$0.2\,pp in all 4 settings; RV and ET already 0\% without constraints).
389	Semantic layer is the sole effective DR defense (41--69\% on SciERC, 2--75\% on DocRED); the near-zero Llama DocRED reduction reflects a near-floor baseline (DR${=}$0.49\%).
390	F1 cost is negligible: max $\Delta$R-F1 = $-$0.30\,pp (Qwen DocRED, full vs.\ unconstrained).}
391	\label{tab:ft-ablation}
392	\end{table}
393	
394	The grammar layer is effectively a no-op for fine-tuned models across all four settings: RV and ET are already 0\% without constraints, and grammar-only DR change is $<$0.2\,pp (4/4 settings).
395	The semantic layer is the sole effective DR defense under fine-tuning, independently reducing DR by 41--69\% on SciERC (Qwen $-$69\%, Llama $-$41\%) and 2--75\% on DocRED (Qwen $-$75\%, Llama $-$2\%); the near-zero Llama DocRED reduction reflects a near-floor baseline (DR${=}$0.49\%, 80 violations in 16{,}074 triples), where the semantic layer has minimal room to improve.
396	Adding both layers achieves near-complete elimination (DR\,$\leq$\,0.21\% in all 4 settings): even after fine-tuning, the semantic layer's pair-based enforcement captures violations that training alone cannot eliminate, specifically on tight-constraint relations where the valid type-pair space is small.
397	F1 cost is negligible: the maximum R-F1 decrease across S1 vs.\ unconstrained is $-$0.30\,pp (Qwen DocRED).
398	
399	%%% DocRED Zero-Shot Ablation (moved from main text) %%%
400	% exp_ids: phase2_docred_unconstrained, phase2_docred_grammar_only,
401	%          phase2_docred_semantic_only, phase2_docred_full_s1
402	
403	\paragraph{DocRED Zero-Shot Ablation.}
404	\label{app:docred-zs-ablation}
405	
406	Table~\ref{tab:docred-ablation} presents the four-way constraint ablation on DocRED under zero-shot decoding, parallel to the SciERC ablation in Table~\ref{tab:scierc-ablation}.
407	
408	\begin{table}[t]
409	\centering
410	\small
411	\setlength{\tabcolsep}{3.6pt}
412	\resizebox{\columnwidth}{!}{%
413	\begin{tabular}{@{}l rrrrrr rr@{}}
414	\toprule
415	& \multicolumn{6}{c}{\textbf{Violation Rates (\%)}}
416	& \multicolumn{2}{c}{\textbf{F1}} \\
417	\cmidrule(lr){2-7} \cmidrule(l){8-9}
418	\textbf{Mode}
419	  & DR\,$\downarrow$ & $\Delta$DR
420	  & RV\,$\downarrow$ & ET\,$\downarrow$ & CF & Tot.\,$\downarrow$
421	  & Rel.\,$\uparrow$ & Ent.\,$\uparrow$ \\
422	\midrule
423	Unconstrained
424	  & 18.46 & ---
425	  & 29.66 & 2.48
426	  & 0.10  & 18.56
427	  & 7.74  & 58.15 \\
428	Grammar
429	  & 26.17 & $\uparrow$42\%
430	  & \textbf{0.03} & \textbf{0}
431	  & 0.07  & 26.24
432	  & \textbf{8.31}  & \textbf{59.38} \\
433	Semantic
434	  & 13.84 & $\downarrow$25\%
435	  & 29.87 & 4.22
436	  & 1.05  & 14.89
437	  & 7.70  & 57.81 \\
438	S1
439	  & \textbf{10.21} & $\downarrow$\textbf{45\%}
440	  & \textbf{0.03} & \textbf{0}
441	  & 2.57  & \textbf{12.78}
442	  & 8.23  & 59.37 \\
443	\bottomrule
444	\end{tabular}}%
445	\caption{Four-way ablation on DocRED (998 documents, Qwen3-8B, zero-shot).
446	$\Delta$DR: relative change vs.\ unconstrained.
447	Tot.\ = DR + CF (total type-violation burden).
448	Best per column in \textbf{bold} (CF excluded; Tot.\ included).
449	F1 $\times$100. Bootstrap significance: R-F1 $+$0.49\,pp ($p < 0.001$).
450	Grammar-only $\uparrow$DR: vocabulary enforcement makes OOV outputs evaluable, exposing latent violations (see \S\ref{sec:docred-results}).}
451	\label{tab:docred-ablation}
452	\end{table}
453	
454	%%% Residual DR Error Analysis (Fine-Tuned) %%%
455	% exp_ids: w5_qwen_docred_*, w5_llama_docred_*, w5_lora_scierc_*, w5_llama_lora_scierc_*
456	
457	\paragraph{Residual DR Error Analysis.}
458	\label{app:residual-dr-analysis}
459	
460	Across all fine-tuned settings (2 models $\times$ 2 datasets $\times$ S1), only 36 domain/range violations remain.
461	Manual inspection reveals four root causes:
462	
463	\begin{enumerate}[nosep,leftmargin=*]
464	\item \emph{Entity type errors} (39\%): the LLM assigns an incorrect entity type (e.g., labeling a geographic entity as \textsc{LOC} when the gold standard requires \textsc{MISC}), causing the semantic mask to permit a domain/range-incompatible relation.
465	\item \emph{Schema coverage gaps} (33\%): the frequency-based constraint table, constructed from training-set co-occurrence statistics, does not cover long-tail type pairs that are ontologically valid but rare. These violations are irreducible by decoding-time constraints alone.
466	\item \emph{Incorrect relation selection} (17\%): the model selects a semantically inappropriate relation whose domain/range constraints are incompatible with the correctly typed entities.
467	\item \emph{Direction reversal} (11\%): the model assigns the correct relation but inverts head/tail roles, placing entities in positions that violate the relation's asymmetric domain/range specification.
468	\end{enumerate}
469	
470	Two dataset-specific patterns emerge.
471	Outside Llama DocRED, all residual violations (3 of 36, spanning Llama SciERC and Qwen DocRED) trace exclusively to schema coverage gaps: the model's entity typing is accurate, and the constraint system has reached its theoretical ceiling given the frequency-based constraint table.
472	On DocRED, Llama-3.1-8B contributes 33 of 36 residual violations (92\%), with entity type errors as the dominant cause (14/33, 42\%).
473	This asymmetry reflects Llama's weaker fine-tuned entity typing on DocRED's larger ontology (96 relations, 6 entity types) compared to Qwen, which achieves near-zero residual.
474	The implication is twofold: (i)~the irreducible floor from schema gaps is small ($\sim$3 violations across 4 settings), so the constraint system operates near its theoretical optimum; (ii)~residual violations from entity typing errors are addressable through stronger base models or improved entity typing modules, without modifying the constraint architecture.
475	
476	%%% Post-Hoc Filtering Comparison (Extended) %%%
477	% exp_ids: posthoc_*_zs, posthoc_*_ft
478	
479	\paragraph{Post-Hoc Filtering: Extended Comparison.}
480	\label{app:posthoc-extended}
481	
482	Table~\ref{tab:posthoc-extended} presents the full comparison across all six zero-shot and four fine-tuned configurations.
483	
484	\begin{table}[t]
485	\centering
486	\small
487	\setlength{\tabcolsep}{3pt}
488	\resizebox{\columnwidth}{!}{%
489	\begin{tabular}{@{}lll rrr l@{}}
490	\toprule
491	\textbf{Setting} & \textbf{Model} & \textbf{Dataset} & \textbf{Reject\%} & \textbf{R-F1$_{\text{ph}}$} & \textbf{R-F1$_{\text{cd}}$} & \textbf{Winner} \\
492	\midrule
493	\multirow{6}{*}{ZS}
494	  & Qwen    & SciERC & 16.8 & 8.63  & 8.36  & ph \\
495	  & Llama   & SciERC & 13.9 & 2.71  & 2.54  & ph \\
496	  & Mistral & SciERC & 20.3 & 3.94  & 3.67  & ph \\
497	  & Qwen    & DocRED & 48.1 & 9.61  & 8.23  & ph \\
498	  & Llama   & DocRED & 42.2 & 7.44  & 6.27  & ph \\
499	  & Mistral & DocRED & \textbf{73.7} & 3.85  & \textbf{5.52} & cd \\
500	\midrule
501	\multirow{4}{*}{FT}
502	  & Qwen    & SciERC & 1.95 & 43.94 & 43.77 & ph \\
503	  & Llama   & SciERC & 1.11 & 45.23 & 45.47 & cd \\
504	  & Qwen    & DocRED & 1.03 & 41.11 & 40.79 & ph \\
505	  & Llama   & DocRED & 0.64 & 43.92 & 43.78 & cd \\
506	\bottomrule
507	\end{tabular}}%
508	\caption{Post-hoc filtering (ph) vs.\ constrained decoding (cd).
509	In zero-shot settings, post-hoc F1 is higher in 5/6 groups (precision-dominated), but constrained decoding preserves higher recall in all 6/6 groups.
510	At reject rate $>$70\% (Mistral DocRED), post-hoc F1 collapses below constrained.
511	Under fine-tuning, rejection rates drop to 0.6--2.0\% and the two strategies are equivalent ($\Delta \leq 0.55$\,pp; each wins two groups).
512	F1 $\times$100.}
513	\label{tab:posthoc-extended}
514	\end{table}
515	
516	The crossover point occurs when post-hoc rejection exceeds $\sim$70\%: Mistral DocRED rejects 73.7\% of predicted triples, discarding enough true positives that constrained decoding's recall advantage dominates ($+$1.67\,pp).
517	OntoCoDec's advantage thus scales with violation severity: precisely when constraints are most needed, post-hoc filtering is most destructive.
518	Under fine-tuning, both strategies converge because few violations remain to filter or constrain ($\Delta \leq 0.55$\,pp across all four FT groups, with each strategy winning two).
519	
520	%%% Zero-Shot Runtime Profiling %%%
521	
522	\paragraph{Zero-Shot Runtime Profiling.}
523	\label{app:runtime}
524	
525	On SciERC (Qwen3-8B, zero-shot greedy, NVIDIA RTX PRO 6000 Blackwell Server Edition), unconstrained inference averages 4.163\,s/doc and S1 constrained decoding averages 4.710\,s/doc ($+$13.1\% overhead).
526	On DocRED (same configuration), relative overhead is lower due to amortization: the fixed per-token constraint cost is spread over longer generation sequences.
527	XGrammar automaton compilation takes 0.044\,s; the full constraint pipeline (schema parsing, JSON Schema generation, grammar compilation) takes 0.33\,s on SciERC (Table~\ref{tab:scalability}), amortized to zero over the evaluation set.
528	
529	% exp_id: p8c_ft_scierc_latency — Reviewer Report #23 verified
530	\paragraph{Fine-Tuned Latency Profiling.}
531	\label{app:ft-latency}
532	Under LoRA fine-tuning (same hardware and dataset), unconstrained inference averages 2.612\,s/doc and S1 constrained decoding averages 2.873\,s/doc ($+$10.0\% overhead, $n{=}551$).
533	Fine-tuned models generate shorter, more structured outputs than zero-shot models (2.612\,s vs.\ 4.163\,s/doc unconstrained); absolute generation time drops by 37\%.
534	The relative overhead ($+$10.0\%) is slightly lower than zero-shot ($+$13.1\%), consistent with shorter sequences requiring fewer constraint checks per document.
535	
536	%%% Fuzzy Relation Matching %%%
537	
538	\paragraph{Relation Matching Protocol.}
539	\label{app:fuzzy-matching}
540	Relation F1 evaluation uses fuzzy normalization to handle model-specific formatting variants (e.g., underscores vs.\ spaces, abbreviations).
541	A predicted relation $r_p$ matches gold relation $r_g$ if: (1)~exact string match after case-insensitive normalization, or (2)~token overlap $>$80\% \emph{and} edit distance $\leq 2$.
542	This protocol affects primarily Mistral, which produces underscore-separated variants (e.g., ``head\_of\_government'' for ``head of government'').
543	On Mistral DocRED, fuzzy matching contributes 98 additional TPs ($+$0.84\,pp R-F1; strict R-F1\,=\,3.50\% vs.\ fuzzy 4.34\%).
544	For Qwen and Llama under grammar constraints, the grammar layer enforces exact relation names, making fuzzy matching irrelevant (0 additional matches).
545	All F1 figures in the main text use fuzzy normalization consistently across all models and conditions.
546	
547	%%% Per-Relation Violation Landscape %%%
548	
549	\paragraph{Per-Relation Violation Landscape.}
550	\label{app:per-relation-landscape}
551	
552	Table~\ref{tab:prompt_comparison} compares violation rates under unconstrained and schema-informed prompting.
553	Figure~\ref{fig:per_relation_dr} shows the per-relation DR distribution on SciERC.
554	
555	\begin{table}[t]
556	\centering
557	\small
558	\caption{Violation rates (\%) under unconstrained and schema-informed prompting (Qwen3-8B, zero-shot).}
559	\label{tab:prompt_comparison}
560	\resizebox{\columnwidth}{!}{%
561	\begin{tabular}{ll cccc}
562	\toprule
563	Dataset & Prompt & DR$\downarrow$ & RV$\downarrow$ & ET$\downarrow$ & CF$\downarrow$ \\
564	\midrule
565	\multirow{2}{*}{SciERC} & Unconstrained & 15.4 & 1.4 & 0.4 & 0.1 \\
566	 & Schema-informed & 5.8 & 0.3 & \textbf{0.0} & --- \\
567	\midrule
568	\multirow{2}{*}{DocRED} & Unconstrained & 18.5 & 29.7 & 2.5 & 0.1 \\
569	 & Schema-informed & 12.8 & 18.4 & 0.2 & 0.2 \\
570	\bottomrule
571	\end{tabular}}
572	\end{table}
573	
574	\begin{figure}[t]
575	\centering
576	\includegraphics[width=\columnwidth]{figures/fig2_per_relation_dr.pdf}
577	\caption{Per-relation DR violation rates on SciERC (Qwen3-8B, unconstrained). Rates correlate with constraint tightness $\kappa(r)$. Llama-3.1-8B shows similar per-relation patterns (Appendix~\ref{app:llama-per-relation}).}
578	\label{fig:per_relation_dr}
579	\end{figure}
580	
581	%%% WikiEvents Extended %%%
582	
583	\paragraph{WikiEvents Dataset Details.}
584	\label{app:wikievents}
585	WikiEvents~\cite{li2021document} is a document-level event argument extraction benchmark grounded in the DARPA KAIROS ontology.
586	It defines 56 event types, 80 argument roles, and 27 entity types, with 245 (event\_type, role)$\to$allowed\_entity\_types constraints.
587	The grammar layer targets EV (event vocabulary), RoV (role vocabulary), and ET; the semantic layer enforces AC (argument constraint) via role-conditioned masking, analogous to RE domain/range enforcement.
588	
589	\paragraph{Constraint Tightness in WikiEvents.}
590	\label{app:wikievents-kappa}
591	% Data source: artifacts/w1c_wikievents_kappa_results.md
592	WikiEvents role-level tightness (with $|\mathcal{E}|{=}27$) has mean $\bar{\kappa}{=}0.82$ and median 0.89; 84\% of roles have $\kappa \geq 0.80$ (4 or fewer valid entity types out of 27).
593	The tightness-violation pattern extends to event extraction: roles with $\kappa \geq 0.90$ exhibit the highest AC rate (50\%), compared to 21\% for medium-tightness ($0.80 \leq \kappa < 0.90$) and 30\% for loose ($\kappa < 0.80$) roles; this is consistent with the RE observation that constraint tightness correlates with violation frequency.
594	However, the correlation is modulated by entity type prototypicality: semantically intuitive roles (e.g., Transportation.Vehicle$\to$VEH) show 0\% AC despite $\kappa{=}0.963$, while roles that require rare KAIROS-specific types (e.g., Crime$\to$CRM, Sentence$\to$SEN) show near-100\% AC because LLMs default to common types (PER, ORG).
595	The loose group's elevated rate (30\%) is driven by high-frequency roles such as Attack.Target (126 args, 34\% AC, $\kappa{=}0.59$), where systematic model errors outweigh the permissive constraint space.
596	
597	%%% Lucky Violation Analysis %%%
598	% exp_ids: task_e_lucky_violation_analysis
599	
600	\paragraph{Lucky Violation Analysis.}
601	\label{app:lucky-violations}
602	Table~\ref{tab:lucky-violations} quantifies the recall cost of DR elimination.
603	A ``lucky violation'' is a constraint-removed triple that happens to match a gold label---an ontologically invalid prediction that is nonetheless correct.
604	Across four fine-tuned configurations, lucky violations average 0.24\% of gold triples (range 0.01--0.51\%), confirming that nearly all removed DR violations are false positives.
605	On Llama SciERC, all five lucky violations are recovered as legal type paths under constrained decoding (zero churn): the model finds an ontology-compliant route to the same prediction.
606	
607	\begin{table}[h]
608	\centering
609	\small
610	\resizebox{\columnwidth}{!}{%
611	\begin{tabular}{@{}llrrrr@{}}
612	\toprule
613	\textbf{Model} & \textbf{Dataset} & \textbf{DR (\%)} & \textbf{Lucky} & \textbf{$\Delta$Recall} & \textbf{Churn} \\
614	& & \textbf{unc$\to$con} & \textbf{(\% gold)} & \textbf{(pp)} & \textbf{(\%)} \\
615	\midrule
616	Qwen3-8B  & SciERC & 1.95$\to$0    & 4 (0.41\%) & $-$0.10 & 0.22 \\
617	Llama-8B  & SciERC & 1.11$\to$0.09 & 5 (0.51\%) & $\pm$0.00 & 0 \\
618	Qwen3-8B  & DocRED & 1.03$\to$0.01 & 1 (0.01\%) & $-$0.84 & 2.05 \\
619	Llama-8B  & DocRED & 0.64$\to$0.21 & 1 (0.01\%) & $-$0.10 & 0.86 \\
620	\midrule
621	\multicolumn{2}{@{}l}{\textit{Average}} & & \textit{0.24\%} & $-$0.26 & 0.78 \\
622	\bottomrule
623	\end{tabular}}
624	\caption{Lucky violation analysis across four LoRA fine-tuned configurations.
625	Lucky: count (and \% of gold triples) of constraint-removed violations matching gold labels.
626	$\Delta$Recall: recall change from unconstrained to constrained.
627	Churn: fraction of gold-matching triples whose predictions change (including recovery via legal type paths).}
628	\label{tab:lucky-violations}
629	\end{table}
630	
631	%%% Trie-Only Baseline %%%
632	% exp_ids: trie_qwen_ft_scierc, trie_qwen_zs_scierc, trie_llama_ft_scierc, trie_llama_zs_scierc
633	
634	\paragraph{Trie-Only Baseline (GCD-Equivalent).}
635	\label{app:trie-baseline}
636	Table~\ref{tab:trie-baseline} isolates the effect of vocabulary membership constraints without JSON structural enforcement.
637	The trie constrains entity type and relation tokens to schema-valid values (achieving ET${=}$0\%, RV${=}$0\% across all configurations), functionally equivalent to GCD's~\cite{geng2023gcd} constrained decoding.
638	However, without grammar-level JSON enforcement, models systematically omit entity type fields (83\% of triples) or produce malformed JSON (0--51\% parse failure), causing DR to rise to 15--96\%---far worse than unconstrained baselines.
639	The effect is most dramatic for Llama-8B LoRA: 50.8\% parse failure causes R-F1 to collapse from 45.47 (OntoCoDec S1) to 19.95, demonstrating that the grammar layer is not merely helpful but a structural prerequisite---vocabulary constraints require JSON scaffolding to reach the positions where they apply.
640	
641	\begin{table}[h]
642	\centering
643	\small
644	\resizebox{\columnwidth}{!}{%
645	\begin{tabular}{@{}ll rrrr rr@{}}
646	\toprule
647	\textbf{Model} & \textbf{Setting}
648	  & \textbf{ET\,$\downarrow$} & \textbf{RV\,$\downarrow$} & \textbf{DR\,$\downarrow$} & \textbf{CF}
649	  & \textbf{R-F1\,$\uparrow$} & \textbf{PF\,(\%)} \\
650	\midrule
651	\multirow{2}{*}{Qwen3-8B}
652	  & LoRA  & 0 & 0 & 95.5  & 0.09 & 41.16 & 9.1 \\
653	  & ZS    & 0 & 0 & 29.3  & 0    & 8.64  & 0 \\
654	\multirow{2}{*}{Llama-8B}
655	  & LoRA  & 0 & 0 & 15.2$^\dagger$  & 0    & 19.95 & 50.8 \\
656	  & ZS    & 0 & 0 & 84.4  & 0.36 & 2.90  & 0 \\
657	\midrule
658	\multicolumn{8}{@{}l}{\textit{Comparison with OntoCoDec S1:}} \\
659	\midrule
660	& & \multicolumn{2}{c}{\textbf{S1 DR\,(\%)}} & \textbf{Trie DR\,(\%)} & \multicolumn{2}{c}{\textbf{DR Gap (pp)}} & \\
661	\cmidrule(lr){3-4} \cmidrule(lr){5-5} \cmidrule(lr){6-7}
662	Qwen3-8B  & LoRA  & \multicolumn{2}{c}{0}    & 95.5  & \multicolumn{2}{c}{95.5}  & \\
663	Qwen3-8B  & ZS    & \multicolumn{2}{c}{0.93} & 29.3  & \multicolumn{2}{c}{28.4}  & \\
664	Llama-8B  & LoRA  & \multicolumn{2}{c}{0.09} & 15.2  & \multicolumn{2}{c}{15.1}  & \\
665	Llama-8B  & ZS    & \multicolumn{2}{c}{0.08} & 84.4  & \multicolumn{2}{c}{84.3}  & \\
666	\bottomrule
667	\end{tabular}}
668	\caption{Trie-only baseline (GCD-equivalent, vocabulary membership without JSON grammar) on SciERC.
669	Top: full trie-only metrics (ET/RV/DR/CF: violation rates \%; R-F1 $\times$100; PF: parse failure rate).
670	Trie achieves ET${=}$0\%, RV${=}$0\% but DR rises to 15--96\% because models omit type fields without structural enforcement.
671	Bottom: DR gap between OntoCoDec S1 and trie-only, quantifying the grammar layer's contribution.
672	$^\dagger$50.8\% parse failure rate.}
673	\label{tab:trie-baseline}
674	\end{table}
675	
676	%%% GCD/BoostCD Equivalence Comparison %%%
677	
678	\paragraph{Comparison with Grammar-Based Constrained Decoding.}
679	\label{app:gcd-comparison}
680	
681	Table~\ref{tab:gcd-comparison} summarizes the relationship between OntoCoDec's constraint layers and existing grammar-based constrained decoding methods.
682	
683	\begin{table}[h]
684	\centering
685	\small
686	\resizebox{\columnwidth}{!}{%
687	\begin{tabular}{@{}l l l l l l@{}}
688	\toprule
689	\textbf{Method} & \textbf{Constraint Type} & \textbf{Level} & \textbf{DR Red.} & \textbf{CF} & \textbf{State} \\
690	\midrule
691	GCD~\cite{geng2023gcd} & CFG (JSON schema) & Grammar & ${\sim}$3\% & N/A & Stateless \\
692	BoostCD~\cite{boostcd2025} & CFG + beam rerank & Grammar & ${\sim}$3\%$^\dagger$ & N/A & Stateless \\
693	Trie-Only (Tab.~\ref{tab:trie-baseline}) & Prefix trie & Vocab & 0\%$^\ddagger$ & N/A & Stateless \\
694	\midrule
695	vLLM \texttt{guided\_json}~\cite{kwon2023vllm} & JSON Schema & Grammar & ${\sim}$3\%$^\S$ & N/A & Stateless \\
696	\midrule
697	OntoCoDec Grammar & CFG (XGrammar) & Grammar & ${\sim}$3\% & N/A & Stateless \\
698	OntoCoDec S1 & CFG + type constr. & Gram.+Sem. & 94--100\% (FT) & ${\leq}$1.4\% (FT) & Entity reg. \\
699	\bottomrule
700	\end{tabular}}
701	\caption{Comparison with grammar-based constrained decoding methods.
702	$^\dagger$Equivalent mechanism; BoostCD adds beam-level reranking but the CFG enforcement is identical.
703	$^\ddagger$Vocabulary-only constraints without JSON structure cause DR to \emph{increase} (15--96\%; Table~\ref{tab:trie-baseline}).
704	$^\S$Experimentally verified: DR${=}$15.26\% vs.\ grammar-only 14.84\% ($\Delta{<}$0.5\,pp; Table~\ref{tab:vllm-verification}).
705	Grammar-only results are analytically equivalent to GCD/BoostCD (same CFG enforcement; \S\ref{sec:related_work}).}
706	\label{tab:gcd-comparison}
707	\end{table}
708	
709	Our grammar layer implements the same CFG-based token masking as GCD and BoostCD---the mechanisms are formally identical (JSON schema $\to$ pushdown automaton $\to$ per-step allowed token set).
710	Table~\ref{tab:scierc-ablation} row~2 therefore constitutes a direct comparison: grammar-only enforcement achieves RV/ET$\to$0\% but only ${\sim}$3\% DR reduction, identical to what GCD-family methods would achieve on IE tasks.
711	
712	% exp_id: vllm_guided_json_scierc_zs
713	\paragraph{External verification via vLLM.}
714	To confirm this equivalence experimentally, we evaluated vLLM's \texttt{guided\_json} mode~\cite{kwon2023vllm}---an independent CFG enforcement implementation---on SciERC under identical conditions (Qwen3-8B, zero-shot, 551 documents).
715	
716	\begin{table}[h]
717	\centering
718	\small
719	\begin{tabular}{@{}l rrrr r@{}}
720	\toprule
721	\textbf{Method} & \textbf{DR\,$\downarrow$} & \textbf{RV\,$\downarrow$} & \textbf{ET\,$\downarrow$} & \textbf{CF} & \textbf{R-F1\,$\uparrow$} \\
722	\midrule
723	Grammar-Only (XGrammar) & 14.84 & 0 & 0 & 9.90 & 8.23 \\
724	vLLM \texttt{guided\_json} & 15.26 & 0 & 0 & --- & 8.75 \\
725	\midrule
726	$\Delta$ & $+$0.42 & 0 & 0 & --- & $+$0.52 \\
727	\bottomrule
728	\end{tabular}
729	\caption{GCD-equivalence verification: OntoCoDec grammar-only vs.\ vLLM \texttt{guided\_json} on SciERC (Qwen3-8B, zero-shot, 551 documents). All differences $<$0.5\,pp, confirming that CFG-based approaches---regardless of implementation---leave ${\sim}$15\% DR violations unaddressed.}
730	\label{tab:vllm-verification}
731	\end{table}
732	
733	All metrics differ by $<$0.5\,pp (Table~\ref{tab:vllm-verification}), confirming that any CFG-based constrained decoding tool---whether GCD, BoostCD, or vLLM---enforces the same constraint class and leaves the same ${\sim}$15\% DR gap.
734	The critical gap these methods cannot address is cross-field type consistency (Level~2), which requires the stateful semantic layer that maintains an entity registry across relation slots and enforces per-relation domain/range constraints at each type-bearing position.
735	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "9c3d411b-be95-4ea9-aa1e-d3b2b07d7c1b",
  "isSidechain": true,
  "promptId": "4ef057c6-ed80-4dae-9126-cc738ba56a17",
  "agentId": "af50a5a1a4547801d",
  "type": "user",
  "uuid": "dc0586cc-6254-4a1b-948d-c512eb1e00be",
  "sourceToolAssistantUUID": "9c3d411b-be95-4ea9-aa1e-d3b2b07d7c1b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/.claude/sessions/agent_f7c2f8cc",
  "sessionId": "d74ed321-94ae-476c-899f-c11688aa3239",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "jiggly-watching-nygaard"
}
```

</details>

---

### Assistant

_source line 12 · 2026-05-24T04:34:55.586Z_

Now I have all four files. Let me systematically verify every number against the registry data.

---

## FILE 1: `appendix_70b_ablation.tex`

### Table: 70B LoRA SciERC ablation (lines 21-26)

| Line | Paper Value | Exp ID | Registry Value | Status |
|------|------------|--------|---------------|--------|
| 21 | Unconstrained: DR=1.50, RV=0, CF=0, R-F1=44.73, E-F1=64.86 | eval_70b_lora_scierc_unconstrained | DR=1.5%, CF=0, R_F1=44.73, E_F1=64.86 | ✅ All match |
| 22 | Grammar: DR=1.50, CF=0, R-F1=44.63, E-F1=64.82 | eval_70b_lora_scierc_grammar_only | DR=1.5%, R_F1=44.63, E_F1=64.82 | ✅ All match |
| 23 | Semantic: DR=0.60, CF=9, R-F1=44.73, E-F1=64.86 | eval_70b_lora_scierc_semantic_only | DR=0.6%, CF=9, R_F1=44.73, E_F1=64.86 | ✅ All match |
| 24 | S1: DR=0, CF=15, R-F1=44.53, E-F1=64.76 | eval_70b_lora_scierc_s1_constrained | DR=0%, CF=15, R_F1=44.53, E_F1=64.76 | ✅ All match |
| 25 | S2: DR=0, CF=18, R-F1=36.28, E-F1=62.35 | eval_70b_lora_scierc_full_s2 | DR=0%, CF=18, R_F1=36.28, E_F1=62.35 | ✅ All match |
| 26 | Beam4 S1: DR=0, CF=1, R-F1=44.81, E-F1=64.89 | eval_70b_lora_scierc_beam4_s1 | DR=0%, CF=1, R_F1=44.81, E_F1=64.89 | ✅ All match |

### Prose references (lines 34-38)

- [line 34] "1.50%→1.50% on SciERC" → ✅ matches unconstrained→grammar DR
- [line 34] "DR actually increases +3.58 pp" → Grammar DocRED ZS: 13.45→17.03 = +3.58 ✅
- [line 35] "1.50%→0.60%, 60% reduction" → Unconstrained→Semantic: 1.50→0.60 = 60% ✅
- [line 35] "Δ=0 pp" R-F1 → 44.73→44.73 ✅
- [line 36] "S2...−8.45 pp" → S1 R-F1=44.53, S2 R-F1=36.28, diff=−8.25 pp → ❌ **Paper says −8.45, actual is −8.25** (44.53−36.28=8.25, not 8.45). However, measuring from unconstrained: 44.73−36.28=8.45. The text says "causes severe R-F1 degradation (−8.45 pp)" which appears to be measuring from unconstrained, not S1. Context-dependent—if measuring from unconstrained baseline it's ✅, if from S1 it's ❌. The text doesn't specify the baseline explicitly, but the delta calculation of 44.73−36.28=8.45 works ✅ from unconstrained.
- [line 37] "DR=0%, CF=1, R-F1=44.81" → ✅

### Table: 70B LoRA DocRED ablation (lines 58-63)

| Line | Paper Value | Exp ID | Registry Value | Status |
|------|------------|--------|---------------|--------|
| 58 | Unconstrained: DR=0.22, RV=0.57, CF=2 | eval_70b_lora_docred_200_unconstrained | DR=0.22%, RV=0.57%, CF=0.06% | ❌ **CF mismatch: paper says "2" (count), registry says "0.06%" (rate).** If 0.06% is a rate and there are ~3300 triples, that would be ~2 violations. Plausible as count=2 ✅ if CF is count in this table |
| 58 | R-F1=43.80, E-F1=80.34 | | R_F1=43.8, E_F1=80.34 | ✅ |
| 59 | Grammar: DR=0.38, CF=0.06%† | eval_70b_lora_docred_200_grammar_only | DR=0.38%, CF=0.06% | ✅ |
| 59 | R-F1=43.96, E-F1=80.13 | | R_F1=43.96, E_F1=80.13 | ✅ |
| 60 | Semantic: DR=0, RV=0.51, CF=0.21%† | eval_70b_lora_docred_200_semantic_only | DR=0%, RV=0.51%, CF=0.21% | ✅ |
| 60 | R-F1=43.61, E-F1=80.06 | | R_F1=43.61, E_F1=80.06 | ✅ |
| 61 | S1: DR=0, CF=0.18%† | eval_70b_lora_docred_200_s1_constrained | DR=0%, CF=0.18% | ✅ |
| 61 | R-F1=43.95, E-F1=79.38 | | R_F1=43.95, E_F1=79.38 | ✅ |
| 62 | S2: DR=0, CF=0.34%†, R-F1=36.45, E-F1=84.96 | eval_70b_lora_docred_200_full_s2 | DR=0%, CF=0.34%, R_F1=36.45, E_F1=84.96 | ✅ |
| 63 | Beam4 S1: DR=0, CF=0, R-F1=48.14, E-F1=85.57 | eval_70b_lora_docred_200_beam4_s1 | DR=0%, CF=0%, R_F1=48.14, E_F1=85.57 | ✅ |

### Caption (line 69)

- "PF: greedy S1 12.5%" → eval_70b_lora_docred_200_s1_constrained: parse_fail=12.5% ✅
- "beam4 S1 0.5%" → eval_70b_lora_docred_200_beam4_s1: parse_fail=0.5% ✅

### Prose (lines 73-78)

- [line 73] "grammar eliminates RV (0.57%→0%)" → ✅
- [line 73] "DR increases slightly (+0.16 pp)" → 0.22→0.38 = +0.16 ✅
- [line 73] "semantic-only independently eliminates DR (0.22%→0%)" → ✅
- [line 73] "retains RV (0.51%)" → ✅
- [line 75] "−7.50 pp vs. S1" → S1 R-F1=43.95, S2 R-F1=36.45, diff=−7.50 ✅
- [line 75] "mirroring SciERC (−8.45 pp)" → per analysis above, 44.73−36.28=8.45 ✅
- [line 75] "baseline DR is already near-zero (0.22%)" → ✅
- [line 76] "CF increases from 0.18% (S1) to 0.34% (S2)" → ✅
- [line 77] "+4.19 pp R-F1 gain from beam search (43.95→48.14)" → 48.14−43.95=4.19 ✅
- [line 77] "greedy S1 fails to parse 12.5% of documents (25/200)" → 25/200=12.5% ✅
- [line 77] "beam reduces this to 0.5% (1/200)" → ✅
- [line 78] "+0.28 pp" → Beam4 SciERC R-F1=44.81, S1 R-F1=44.53, diff=+0.28 ✅

### Table: 70B DocRED zero-shot ablation (lines 97-101)

| Line | Paper Value | Exp ID | Registry Value | Status |
|------|------------|--------|---------------|--------|
| 97 | Unconstrained: DR=13.45, RV=7.88, CF=0, R-F1=13.25, E-F1=70.14 | eval_70b_zs_docred_200_unconstrained | DR=13.45%, RV=7.88%, CF=0, R_F1=13.25, E_F1=70.14 | ✅ |
| 98 | Grammar: DR=17.03, CF=0, R-F1=13.23, E-F1=70.12 | eval_70b_zs_docred_200_grammar_only | DR=17.03%, R_F1=13.23 | ✅ (E-F1=70.12 not in registry, cannot verify) |
| 99 | Semantic: DR=1.66, RV=8.24, ET=0.12, CF=132, R-F1=13.05, E-F1=70.10 | eval_70b_zs_docred_200_semantic_only | DR=1.66%, RV=8.24%, R_F1=13.05 | ✅ (ET=0.12 and CF=132 and E-F1=70.10 not in registry) |
| 100 | S1: DR=0, CF=173, R-F1=13.25, E-F1=70.05 | eval_70b_zs_docred_200_full_s1 | DR=0%, R_F1=13.25, E_F1=70.05 | ✅ (CF=173 not in registry but CF=5.34% registry → 5.34% of triples; cannot compute count without total triple count) |

### Prose (lines 108-112)

- [line 108] "DR increases by +3.58 pp (13.45%→17.03%)" → ✅
- [line 109] "87.7% DR reduction (13.45%→1.66%)" → (13.45−1.66)/13.45=87.7% ✅
- [line 110] "13.45%→0% with zero R-F1 cost (13.25=13.25)" → ✅
- [line 111] "CF increases from 0 (unconstrained) to 173 (S1)" → CF=0 unconstrained ✅, CF=173 S1 (registry shows CF=5.34% rate; cannot verify count)

### r16 experiments referenced elsewhere

The paper's Table on lines 97-101 uses `eval_70b_zs_docred_200_*` experiments (200-doc subset). The registry also has `r16_70b_docred_zs_s1` with different values (DR=0%, CF=0.04%, R_F1=13.05, 998 docs). These are different experiments (different subsets) so no mismatch.

---

## FILE 2: `appendix_beam_search.tex`

### Table: Beam sweep (lines 117-130)

| Line | Paper Value | Exp ID | Registry Value | Status |
|------|------------|--------|---------------|--------|
| 117 | k1 unc: R-F1=42.95, DR=2.11, CF=0, Latency=2.494 | d066_beam_sweep k1_unc | DR=2.11, CF=0, R_F1=42.95, avg_time=2.494 | ✅ |
| 118 | k1 con: R-F1=42.95, DR=0, CF=0.50, Latency=2.932 | d066_beam_sweep k1_con | DR=0, CF=0.5, R_F1=42.95, avg_time=2.932 | ✅ |
| 121 | k2 unc: R-F1=44.75, DR=1.54, CF=0, Latency=2.954 | d066_beam_sweep k2_unc | DR=1.54, CF=0, R_F1=44.75, avg_time=2.954 | ✅ |
| 122 | k2 con: R-F1=44.60, DR=0, CF=0.11, Latency=3.463 | d066_beam_sweep k2_con | DR=0, CF=0.11, R_F1=44.60, avg_time=3.463 | ✅ |
| 125 | k4 unc: R-F1=43.72, DR=1.89, CF=0, Latency=3.485 | d066_beam_sweep k4_unc | DR=1.89, CF=0, R_F1=43.72, avg_time=3.485 | ✅ |
| 126 | k4 con: R-F1=43.60, DR=0, CF=0, Latency=4.069 | d066_beam_sweep k4_con | DR=0, CF=0, R_F1=43.60, avg_time=4.069 | ✅ |
| 129 | k8 unc: R-F1=43.17, DR=1.77, CF=0, Latency=4.194 | d066_beam_sweep k8_unc | DR=1.77, CF=0, R_F1=43.17, avg_time=4.194 | ✅ |
| 130 | k8 con: R-F1=43.65, DR=0, CF=0, Latency=5.058 | d066_beam_sweep k8_con | DR=0, CF=0, R_F1=43.65, avg_time=5.058 | ✅ |

### Relative latencies (computed)

- [line 117] k1 unc: 1.00× → base ✅
- [line 118] k1 con: 1.18× → 2.932/2.494=1.1757 ≈ 1.18× ✅
- [line 121] k2 unc: 1.18× → 2.954/2.494=1.1844 ≈ 1.18× ✅
- [line 122] k2 con: 1.39× → 3.463/2.494=1.3885 ≈ 1.39× ✅
- [line 125] k4 unc: 1.40× → 3.485/2.494=1.3973 ≈ 1.40× ✅
- [line 126] k4 con: 1.63× → 4.069/2.494=1.6316 ≈ 1.63× ✅
- [line 129] k8 unc: 1.68× → 4.194/2.494=1.6816 ≈ 1.68× ✅
- [line 130] k8 con: 2.03× → 5.058/2.494=2.0281 ≈ 2.03× ✅

### Prose (line 97)

- "R-F1 44.60, CF 0.11%, 1.39× vs. greedy unconstrained; 1.18× vs. greedy S1" → k2 con: R-F1=44.60 ✅, CF=0.11% ✅, 3.463/2.494=1.39× ✅, 3.463/2.932=1.18× ✅
- "1.63–2.03×" → k4 con=1.63×, k8 con=2.03× ✅

### Latency table (lines 200-203)

| Line | Paper Value | Exp ID | Registry Value | Status |
|------|------------|--------|---------------|--------|
| 200 | Greedy unc: 2.612 s/doc | d062_beam_latency | greedy_unc=2.612s | ✅ |
| 201 | Greedy con: 2.873 s/doc | d062_beam_latency | greedy_constrained=2.873s | ✅ |
| 202 | Beam-4 unc: 3.446 s/doc | d062_beam_latency | beam4_unc=3.446s | ✅ |
| 203 | Beam-4 con: 4.013 s/doc | d062_beam_latency | beam4_constrained=4.013s | ✅ |

### Overhead calculations (line 210)

- "32% latency (4 beams)" → (3.446−2.612)/2.612=31.9% ≈ 32% ✅
- "10% (greedy)" → (2.873−2.612)/2.612=9.99% ≈ 10% ✅
- "17% (beam)" → This should be the constraint overhead for beam: (4.013−3.446)/3.446=16.5% ≈ 17% ✅
- "1.54×" → 4.013/2.612=1.536 ≈ 1.54× ✅

### Overhead in table (lines 200-203)

- Greedy unc: 1.00× ✅
- Greedy con: 1.10× → 2.873/2.612=1.0999 ≈ 1.10× ✅
- Beam-4 unc: 1.32× → 3.446/2.612=1.319 ≈ 1.32× ✅
- Beam-4 con: 1.54× → 4.013/2.612=1.536 ≈ 1.54× ✅

But wait—the registry also has `ratio=1.397` for d062_beam_latency. The paper doesn't report this ratio directly but the computed 4.013/2.873=1.397 matches ✅.

---

## FILE 3: `appendix_quantization.tex`

### INT4 values (lines 21-29)

| Line | Paper Value | Exp ID | Registry Value | Status |
|------|------------|--------|---------------|--------|
| 22 | Qwen SciERC INT4: R-F1=41.71 | sf2_qwen_int4_scierc_s1 | R_F1=41.71 | ✅ |
| 23 | Qwen SciERC INT4: E-F1=67.05 | sf2_qwen_int4_scierc_s1 | E_F1=67.05 | ✅ |
| 21 | Qwen SciERC INT4: DR=0 | sf2_qwen_int4_scierc_s1 | DR=0% | ✅ |
| 22 | Qwen SciERC FP16: R-F1=43.77 | (not in provided registry) | Cannot verify from provided data | ⚠️ |
| 23 | Qwen SciERC FP16: E-F1=67.05 | (not in provided registry) | Cannot verify from provided data | ⚠️ |
| 22 | Llama SciERC INT4: R-F1=43.98 | sf2_llama_int4_scierc_s1 | R_F1=43.98 | ✅ |
| 23 | Llama SciERC INT4: E-F1=67.54 | sf2_llama_int4_scierc_s1 | E_F1=67.54 | ✅ |
| 21 | Llama SciERC INT4: DR=0 | sf2_llama_int4_scierc_s1 | DR=0% | ✅ |
| 22 | Llama SciERC INT4 Δ=−1.49 | | 45.47−43.98=1.49 ✅ (FP16=45.47 assumed from table) |
| 22 | Qwen SciERC INT4 Δ=−2.06 | | 43.77−41.71=2.06 ✅ |
| 27 | Qwen DocRED INT4: R-F1=40.07 | sf2_qwen_int4_docred_s1 | R_F1=40.07 | ✅ |
| 28 | Qwen DocRED INT4: E-F1=74.84 | sf2_qwen_int4_docred_s1 | E_F1=74.84 | ✅ |
| 26 | Qwen DocRED INT4: DR=0 | sf2_qwen_int4_docred_s1 | DR=0% | ✅ |
| 27 | Llama DocRED INT4: R-F1=48.04 | sf2_llama_int4_docred_s1 | R_F1=48.04 | ✅ |
| 28 | Llama DocRED INT4: E-F1=84.18 | sf2_llama_int4_docred_s1 | E_F1=84.18 | ✅ |
| 26 | Llama DocRED INT4: DR=0 | sf2_llama_int4_docred_s1 | DR=0% | ✅ |

### CF values

- [line 21] Qwen SciERC INT4 CF not shown in table but registry: sf2_qwen_int4_scierc_s1 CF=1.1% → not explicitly in table (no CF column for SciERC section) ✅ (not a discrepancy, CF column not shown)
- sf2_qwen_int4_docred_s1: CF=0.1% → not shown in table ✅
- sf2_llama_int4_scierc_s1: CF=0.94% → not shown ✅
- sf2_llama_int4_docred_s1: CF=0.22% → not shown ✅

### Prose (lines 38-41)

- [line 39] "R-F1 changes range from −2.06 to +0.69 pp" → Qwen SciERC: −2.06, Llama SciERC: −1.49, Qwen DocRED: −0.72, Llama DocRED: +0.69 → range is −2.06 to +0.69 ✅
- [line 40] "18.5% vs. 8.5% FP16" → PF values from table line 29 ✅
- [line 40] "E-F1 gap (−7.03 pp)" → 81.87−74.84=7.03 ✅

---

## FILE 4: `appendix_discussion.tex`

This file contains many numbers from experiments not in the provided registry data (phase2_*, llama_*, cf_fallback_*, etc.). I'll focus on numbers that can be checked against the provided registry.

### 70B references

- [line 75] "baseline DR of 0.22%" → eval_70b_lora_docred_200_unconstrained: DR=0.22% ✅ (referenced in context of 70B S2)

### Beam sweep references

The beam sweep data is referenced indirectly. No direct numeric citations from the provided registry experiments in this file that I haven't already covered.

### Key numbers from appendix_discussion that reference provided registry data:

- [line 90] "CF violations...9.90% on SciERC" → From beam sweep data k1 con CF, but this is zero-shot SciERC data not from the provided 70B experiments. This refers to phase2_scierc_full_s1 which is not in the provided registry. Cannot verify against provided data. ⚠️

- [line 532] "unconstrained inference averages 2.612 s/doc and S1 constrained decoding averages 2.873 s/doc (+10.0% overhead)" → d062_beam_latency: greedy_unc=2.612s, greedy_constrained=2.873s. Overhead: (2.873−2.612)/2.612=9.99%≈10.0% ✅

---

## SUMMARY OF DISCREPANCIES

### Confirmed errors: **0 hard errors found**

### Ambiguous / borderline:

1. **[appendix_70b_ablation.tex:36]** "−8.45 pp" R-F1 degradation for S2. This is 44.73−36.28=8.45 (from unconstrained baseline). If measured from S1 it would be 44.53−36.28=8.25. The text says "S2 eliminates DR but causes severe R-F1 degradation (−8.45 pp)" which is ambiguous about baseline. Measuring from unconstrained is defensible but could mislead since S1 is the more natural comparison point in an ablation. **Not a factual error but potentially misleading.** ⚠️

2. **[appendix_70b_ablation.tex:58]** CF=2 for unconstrained DocRED LoRA. Registry says CF=0.06%. If 0.06% is over ~3300 triples, 0.06%×3300≈2 violations. The table caption says "CF: violation count except †reported as percentage." The unconstrained row has no †, so reporting as count=2 is consistent. ✅

3. **[appendix_70b_ablation.tex:98-99]** Grammar row E-F1=70.12 and Semantic E-F1=70.10 — these specific E-F1 values are not in the provided registry data for grammar_only and semantic_only DocRED ZS experiments. Cannot verify. ⚠️

### Unverifiable numbers (not in provided registry):

Many numbers in `appendix_discussion.tex` and `appendix_beam_search.tex` (Tables 5-8 with Qwen/Llama/Mistral 8B zero-shot data, causal tracing, CF distributions, etc.) reference experiments not included in the provided registry data (phase2_*, llama_*, cf_fallback_*, d065_*, etc.). These cannot be verified from the data provided.

---

## FINAL VERDICT

All numbers that can be verified against the provided registry data are **correct**. No hard discrepancies found. The one borderline case (−8.45 pp S2 degradation) is technically correct when measured from the unconstrained baseline, though the ablation context makes S1 a more natural reference point. The grammar-only and semantic-only E-F1 values for 70B DocRED ZS (70.12 and 70.10) are not in the provided registry and cannot be verified.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "dc0586cc-6254-4a1b-948d-c512eb1e00be",
  "isSidechain": true,
  "agentId": "af50a5a1a4547801d",
  "requestId": "req_011CbLmYPUei3NGGsSpdYVFk",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "f9dd80df-22dd-40ec-9e16-54db716a0abf",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/.claude/sessions/agent_f7c2f8cc",
  "sessionId": "d74ed321-94ae-476c-899f-c11688aa3239",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "jiggly-watching-nygaard",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VbRFNsnFKaPx9fvDgUJmHV",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 32792,
      "cache_read_input_tokens": 30334,
      "output_tokens": 7181,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 32792
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 7181,
          "cache_read_input_tokens": 30334,
          "cache_creation_input_tokens": 32792,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 32792,
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
