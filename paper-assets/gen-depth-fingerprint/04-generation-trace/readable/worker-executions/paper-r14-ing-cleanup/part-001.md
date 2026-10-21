# paper r14 ing cleanup — Part 1 of 2

**Depth Profiling: Classifying Recursive Generation Depth in Base-Model LLM Text** · Worker execution logs

[Transcript overview](../paper-r14-ing-cleanup.md) · [Part 2 →](part-002.md) · [Structured JSON](../../../sessions/0f/0f31a7b01ca47cd785f7.json)

## Before a recorded user message

## Before a recorded user message

193 recorded events


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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint",
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
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
    "mcp__agent-ml-research__read_project_file",
    "mcp__agent-ml-research__save_project_file"
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
  "uuid": "7241ef06-ba0c-4988-8a74-aa7faaee3f5d",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/memory/"
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
    "resetsAt": 1779053400,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "f767a310-010a-4855-a912-cfaae2a9149c",
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070"
}
```

---


### Assistant

_source line 4_

<details><summary>Logged reasoning block</summary>

```text
The user wants me to clean up AI writing traces in their paper, specifically -ing participle phrases. Let me start by searching for these patterns in the .tex files.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "c7a3a81c-f1f5-493e-8867-3cbe0fae296b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BmurVg9Z2BpZGoPkiUBxAY",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13680,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13680
      },
      "output_tokens": 30,
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

搜索所有 .tex 文件中的 -ing 模式。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "f9b01aee-3302-4c5e-8bd0-3195cb80e09a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BmurVg9Z2BpZGoPkiUBxAY",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13680,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13680
      },
      "output_tokens": 30,
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

<details open><summary>🔧 Tool call — Grep · `toolu_019uHrP5eZbhpLCXNTutNKoJ`</summary>

```json
{
  "pattern": "ing,",
  "glob": "*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "8ba11c67-8253-4afa-9c22-d1097c3b2a3a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BmurVg9Z2BpZGoPkiUBxAY",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13680,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13680
      },
      "output_tokens": 30,
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

_source line 7 · 2026-05-17T19:51:44.457Z_

<details><summary>↩ Tool result · `toolu_019uHrP5eZbhpLCXNTutNKoJ`</summary>

```text
artifacts/_project/paper/related_work.tex:23:Iterative self-refinement \cite{self_refine} represents another form of recursive LLM processing, but targets output improvement through feedback loops rather than open-ended continuation; the distributional drift we study arises specifically from unconstrained recursive generation.
artifacts/_project/paper/related_work.tex:45:Scalable data curation relies on quality signals \cite{dsir,qurating,ccnet}; generation depth is a complementary provenance signal characterizing \emph{how many steps removed} text is from a human source.
artifacts/_project/paper/appendix_feature_distributions.tex:10:\caption{Per-feature depth trends. Black line: pooled mean ($\pm$1 std shading) across all generators. Colored traces: individual generators. Features are labeled by DDR category (drifting, intermediate, stationary). Spearman $\rho$ and linear $R^2$ are annotated per panel.}
artifacts/_project/paper/appendix_human_edit.tex:85:To test robustness under semantically coherent editing, we use Qwen3-0.6B-Base to randomly regenerate 1--3 sentences per passage (avg 1.69 sentences, ${\sim}$50\% edit distance) and re-evaluate the 8-gen LOGO pipeline.
artifacts/_project/paper/abstract.tex:7:The depth signal degrades substantially under instruction tuning, restricting current applicability to base models.
artifacts/_project/paper/appendix_domain.tex:30:In the cross-domain setting, 3-class F1 (0.62--0.65) falls below binary F1 (0.74--0.75), reversing the pattern observed in the main experiment (3-class 0.762 $>$ binary 0.694).
artifacts/_project/paper/appendix_finer_depth.tex:21:\caption{5-class LOGO evaluation. Each row holds out one generator for testing, training on the remaining five.}
artifacts/_project/paper/results.tex:17:Under class balancing, macro F1 reaches 0.831 (per-class breakdown in Appendix~\ref{app:cross-model-detail}).
artifacts/_project/paper/results.tex:24:Length-matched subsampling yields binary F1\,=\,0.724 (vs.\ 0.770 unmatched); a random-subsample control confirms the drop reflects deconfounding, not sample-size reduction (Appendix~\ref{app:length}).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "45df8be4-799a-4ce1-9a34-543a164474d9",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "artifacts/_project/paper/related_work.tex:23:Iterative self-refinement \\cite{self_refine} represents another form of recursive LLM processing, but targets output improvement through feedback loops rather than open-ended continuation; the distributional drift we study arises specifically from unconstrained recursive generation.\nartifacts/_project/paper/related_work.tex:45:Scalable data curation relies on quality signals \\cite{dsir,qurating,ccnet}; generation depth is a complementary provenance signal characterizing \\emph{how many steps removed} text is from a human source.\nartifacts/_project/paper/appendix_feature_distributions.tex:10:\\caption{Per-feature depth trends. Black line: pooled mean ($\\pm$1 std shading) across all generators. Colored traces: individual generators. Features are labeled by DDR category (drifting, intermediate, stationary). Spearman $\\rho$ and linear $R^2$ are annotated per panel.}\nartifacts/_project/paper/appendix_human_edit.tex:85:To test robustness under semantically coherent editing, we use Qwen3-0.6B-Base to randomly regenerate 1--3 sentences per passage (avg 1.69 sentences, ${\\sim}$50\\% edit distance) and re-evaluate the 8-gen LOGO pipeline.\nartifacts/_project/paper/abstract.tex:7:The depth signal degrades substantially under instruction tuning, restricting current applicability to base models.\nartifacts/_project/paper/appendix_domain.tex:30:In the cross-domain setting, 3-class F1 (0.62--0.65) falls below binary F1 (0.74--0.75), reversing the pattern observed in the main experiment (3-class 0.762 $>$ binary 0.694).\nartifacts/_project/paper/appendix_finer_depth.tex:21:\\caption{5-class LOGO evaluation. Each row holds out one generator for testing, training on the remaining five.}\nartifacts/_project/paper/results.tex:17:Under class balancing, macro F1 reaches 0.831 (per-class breakdown in Appendix~\\ref{app:cross-model-detail}).\nartifacts/_project/paper/results.tex:24:Length-matched subsampling yields binary F1\\,=\\,0.724 (vs.\\ 0.770 unmatched); a random-subsample control confirms the drop reflects deconfounding, not sample-size reduction (Appendix~\\ref{app:length}).",
    "numLines": 9
  }
}
```

</details>

---


### Tool call

_source line 8_

<details open><summary>🔧 Tool call — Grep · `toolu_01LZbMgMcuoYfXT48dvKVY6z`</summary>

```json
{
  "pattern": "ing\\.",
  "glob": "*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "6e9c5617-37f0-4292-a950-05bc6d74e328",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BmurVg9Z2BpZGoPkiUBxAY",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13680,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13680
      },
      "output_tokens": 30,
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

_source line 9 · 2026-05-17T19:51:45.421Z_

<details><summary>↩ Tool result · `toolu_01LZbMgMcuoYfXT48dvKVY6z`</summary>

```text
artifacts/_project/paper/related_work.tex:20:These studies focus on \emph{training-loop} degradation; our setting studies \emph{inference chains}, where a fixed model generates text conditioned on its own prior output without retraining.
artifacts/_project/paper/related_work.tex:27:\citet{markovian_chains} demonstrate that semantic-preservation constraints induce attractor dynamics bounding distinguishable depth to approximately three classes; their analysis focuses on characterizing convergence behavior through model-based perplexity tracking.
artifacts/_project/paper/related_work.tex:30:That both works independently converge on approximately three distinguishable classes reflects different mechanisms reaching the same practical ceiling.
artifacts/_project/paper/related_work.tex:39:Our surface features (TTR and hapax ratio) are classical stylometric measures \cite{stamatatos_survey,koppel_authorship} that we apply to inference chains, showing monotonic diversity decline across depths without model retraining.
artifacts/_project/paper/appendix_feature_distributions.tex:23:\caption{UMAP 2D projection of the 7-feature space ($N$\,=\,7{,}500 stratified sample). (a) Colored by raw generation depth (0--4): a gradient structure emerges, with deeper depths converging. (b) Colored by 3-class label: gen-0 separates clearly; gen-1 and gen-2+ overlap, consistent with the high false-negative rate at the gen-1/gen-2+ boundary.}
artifacts/_project/paper/appendix_downstream.tex:29:\paragraph{Equivalence testing.}
artifacts/_project/paper/appendix_downstream.tex:37:Knowing the generation depth of a document does not, by itself, make it more or less useful for training; at fixed sample count, depth-aware curation is statistically equivalent to uninformed random subsampling.
artifacts/_project/paper/appendix_human_edit.tex:80:Avg-LogProb is the most fragile overall ($-$34.7\,pp at 10\%), while FastDetectGPT drops sharply at 5\% ($-$13.4\,pp) before partially recovering.
artifacts/_project/paper/method.tex:88:\paragraph{Metrics and statistical testing.}
artifacts/_project/paper/appendix_error_analysis.tex:18:\caption{Binary classification error rates by generator (8-gen LOGO). Sorted by error rate descending.}
artifacts/_project/paper/appendix_classifier.tex:64:The scale effect (larger models $\rightarrow$ lower F1) is consistent with higher-capacity models generating text statistically closer to human writing.
artifacts/_project/paper/appendix_domain.tex:27:This finding suggests that reference model selection is a key factor for cross-domain deployment of depth fingerprinting.
artifacts/_project/paper/results.tex:9:We therefore adopt leak-free binary F1 (gen-1 vs.\ gen-2+)\,=\,0.694, CI [0.688, 0.700], as the primary metric throughout; it excludes gen-0 entirely and is unaffected by seed sharing.
artifacts/_project/paper/results.tex:66:The six-fold magnitude gap between drifting ($|\rho| > 0.60$) and shape features ($|\rho| < 0.10$) serves as the operative criterion for the DDR split, with entropy std occupying an intermediate position ($|\rho| = 0.17$); shifting these descriptive thresholds by $\pm 0.10$ does not alter feature grouping.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "421a3d90-4e5e-4c26-bfae-2edb9f6b2632",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "artifacts/_project/paper/related_work.tex:20:These studies focus on \\emph{training-loop} degradation; our setting studies \\emph{inference chains}, where a fixed model generates text conditioned on its own prior output without retraining.\nartifacts/_project/paper/related_work.tex:27:\\citet{markovian_chains} demonstrate that semantic-preservation constraints induce attractor dynamics bounding distinguishable depth to approximately three classes; their analysis focuses on characterizing convergence behavior through model-based perplexity tracking.\nartifacts/_project/paper/related_work.tex:30:That both works independently converge on approximately three distinguishable classes reflects different mechanisms reaching the same practical ceiling.\nartifacts/_project/paper/related_work.tex:39:Our surface features (TTR and hapax ratio) are classical stylometric measures \\cite{stamatatos_survey,koppel_authorship} that we apply to inference chains, showing monotonic diversity decline across depths without model retraining.\nartifacts/_project/paper/appendix_feature_distributions.tex:23:\\caption{UMAP 2D projection of the 7-feature space ($N$\\,=\\,7{,}500 stratified sample). (a) Colored by raw generation depth (0--4): a gradient structure emerges, with deeper depths converging. (b) Colored by 3-class label: gen-0 separates clearly; gen-1 and gen-2+ overlap, consistent with the high false-negative rate at the gen-1/gen-2+ boundary.}\nartifacts/_project/paper/appendix_downstream.tex:29:\\paragraph{Equivalence testing.}\nartifacts/_project/paper/appendix_downstream.tex:37:Knowing the generation depth of a document does not, by itself, make it more or less useful for training; at fixed sample count, depth-aware curation is statistically equivalent to uninformed random subsampling.\nartifacts/_project/paper/appendix_human_edit.tex:80:Avg-LogProb is the most fragile overall ($-$34.7\\,pp at 10\\%), while FastDetectGPT drops sharply at 5\\% ($-$13.4\\,pp) before partially recovering.\nartifacts/_project/paper/method.tex:88:\\paragraph{Metrics and statistical testing.}\nartifacts/_project/paper/appendix_error_analysis.tex:18:\\caption{Binary classification error rates by generator (8-gen LOGO). Sorted by error rate descending.}\nartifacts/_project/paper/appendix_classifier.tex:64:The scale effect (larger models $\\rightarrow$ lower F1) is consistent with higher-capacity models generating text statistically closer to human writing.\nartifacts/_project/paper/appendix_domain.tex:27:This finding suggests that reference model selection is a key factor for cross-domain deployment of depth fingerprinting.\nartifacts/_project/paper/results.tex:9:We therefore adopt leak-free binary F1 (gen-1 vs.\\ gen-2+)\\,=\\,0.694, CI [0.688, 0.700], as the primary metric throughout; it excludes gen-0 entirely and is unaffected by seed sharing.\nartifacts/_project/paper/results.tex:66:The six-fold magnitude gap between drifting ($|\\rho| > 0.60$) and shape features ($|\\rho| < 0.10$) serves as the operative criterion for the DDR split, with entropy std occupying an intermediate position ($|\\rho| = 0.17$); shifting these descriptive thresholds by $\\pm 0.10$ does not alter feature grouping.",
    "numLines": 14
  }
}
```

</details>

---


### Tool call

_source line 10_

<details open><summary>🔧 Tool call — Grep · `toolu_01Fg545ZsXN4jNa3nNfCbakk`</summary>

```json
{
  "pattern": "ing[\\s}~\\\\]",
  "glob": "*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper",
  "output_mode": "content",
  "-n": true,
  "head_limit": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "9b183794-e521-4a94-8b09-96b574610632",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BmurVg9Z2BpZGoPkiUBxAY",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13680,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13680
      },
      "output_tokens": 30,
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

_source line 11 · 2026-05-17T19:51:46.940Z_

<details><summary>↩ Tool result · `toolu_01Fg545ZsXN4jNa3nNfCbakk`</summary>

```text
&lt;persisted-output>
Output too large (48.3KB). Full output saved to: /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/4bdb13b7-b460-45f7-96ee-c950b3a16070/tool-results/toolu_01Fg545ZsXN4jNa3nNfCbakk.txt

Preview (first 2KB):
artifacts/_project/paper/appendix_cross_model_detail.tex:15:\caption{Cross-model chain per-class performance (class-balanced 5-fold CV, $N$\,=\,2{,}964, 5 generators: Pythia-2.8B/1B, OLMo-2-1B, Qwen3-0.6B/1.7B). Macro F1\,=\,0.831 under class balancing; under natural class distribution, macro F1\,=\,0.809 (as reported in \S\ref{sec:results-classification}). Cross-model chains avoid the gen-0 seed sharing issue present in single-generator LOGO.}
artifacts/_project/paper/related_work.tex:7:Methods for distinguishing human-written from machine-generated text have evolved from statistical tests \cite{gltr,grover,release_strategies} to zero-shot reference-model approaches \cite{detectgpt,fast_detectgpt,binoculars,dna_gpt} and learned classifiers \cite{ghostbuster,feat_aug_transformer,reliable_detection,ld_score}.
artifacts/_project/paper/related_work.tex:8:Recent work pursues diverse signals including intrinsic dimensionality \cite{intrinsic_dimension}, surprisal diversity \cite{diveye}, and distributional gap measures \cite{generator_barrier}; see \citet{wu_survey_2025} and \citet{jawahar_survey} for surveys.
artifacts/_project/paper/related_work.tex:12:Adversarial training approaches (e.g., RADAR \cite{radar}) improve robustness to paraphrasing but remain binary detectors without depth awareness.
artifacts/_project/paper/related_work.tex:13:Our contribution is not a new detection method but the task formulation (generation depth classification, framed within the broader ordinal classification literature \cite{gutierrez_ordinal_survey,coral_ordinal}) and the finding that combining drifting and stationary features yields consistent cross-generator performance.
...
&lt;/persisted-output>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "4e9008a4-6832-4ecf-b8d7-d4673baa9474",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "artifacts/_project/paper/appendix_cross_model_detail.tex:15:\\caption{Cross-model chain per-class performance (class-balanced 5-fold CV, $N$\\,=\\,2{,}964, 5 generators: Pythia-2.8B/1B, OLMo-2-1B, Qwen3-0.6B/1.7B). Macro F1\\,=\\,0.831 under class balancing; under natural class distribution, macro F1\\,=\\,0.809 (as reported in \\S\\ref{sec:results-classification}). Cross-model chains avoid the gen-0 seed sharing issue present in single-generator LOGO.}\nartifacts/_project/paper/related_work.tex:7:Methods for distinguishing human-written from machine-generated text have evolved from statistical tests \\cite{gltr,grover,release_strategies} to zero-shot reference-model approaches \\cite{detectgpt,fast_detectgpt,binoculars,dna_gpt} and learned classifiers \\cite{ghostbuster,feat_aug_transformer,reliable_detection,ld_score}.\nartifacts/_project/paper/related_work.tex:8:Recent work pursues diverse signals including intrinsic dimensionality \\cite{intrinsic_dimension}, surprisal diversity \\cite{diveye}, and distributional gap measures \\cite{generator_barrier}; see \\citet{wu_survey_2025} and \\citet{jawahar_survey} for surveys.\nartifacts/_project/paper/related_work.tex:12:Adversarial training approaches (e.g., RADAR \\cite{radar}) improve robustness to paraphrasing but remain binary detectors without depth awareness.\nartifacts/_project/paper/related_work.tex:13:Our contribution is not a new detection method but the task formulation (generation depth classification, framed within the broader ordinal classification literature \\cite{gutierrez_ordinal_survey,coral_ordinal}) and the finding that combining drifting and stationary features yields consistent cross-generator performance.\nartifacts/_project/paper/related_work.tex:19:Self-consuming generative models progressively lose distributional coverage \\cite{self_consuming_mad}, and model collapse is inevitable without fresh human data \\cite{curse_of_recursion}, though careful data mixing can mitigate this \\cite{model_collapse_avoidable,strong_model_collapse}.\nartifacts/_project/paper/related_work.tex:20:These studies focus on \\emph{training-loop} degradation; our setting studies \\emph{inference chains}, where a fixed model generates text conditioned on its own prior output without retraining.\nartifacts/_project/paper/related_work.tex:21:The distinction extends beyond setting: model collapse erodes distributional tail coverage irreversibly as training progresses \\cite{curse_of_recursion,strong_model_collapse}, whereas the drift we observe is reversible under fixed parameters and approximately preserves distributional shape (\\S\\ref{sec:results-differential}).\nartifacts/_project/paper/related_work.tex:22:The drifting/stationary feature decomposition central to our analysis has no analogue in model collapse studies, which track aggregate divergence without separating location from shape components.\nartifacts/_project/paper/related_work.tex:26:\\citet{broken_telephone} analyze paraphrasing and translation chains, showing progressive information loss.\nartifacts/_project/paper/related_work.tex:27:\\citet{markovian_chains} demonstrate that semantic-preservation constraints induce attractor dynamics bounding distinguishable depth to approximately three classes; their analysis focuses on characterizing convergence behavior through model-based perplexity tracking.\nartifacts/_project/paper/related_work.tex:28:We differ in three respects: (i) we study \\emph{non-paraphrastic continuation} chains, where the absence of semantic anchoring permits richer depth signal; (ii) we use handcrafted features rather than model-internal representations, enabling the DDR decomposition into drifting vs.\\ stationary components; and (iii) we focus on \\emph{estimating} depth from text rather than characterizing the convergence dynamics of the generation process.\nartifacts/_project/paper/related_work.tex:30:That both works independently converge on approximately three distinguishable classes reflects different mechanisms reaching the same practical ceiling.\nartifacts/_project/paper/related_work.tex:32:We observe the same bound empirically through feature-space compression: inter-class KS statistics drop sharply after depth 2 (gen-1$\\rightarrow$gen-2: KS\\,=\\,0.28 vs.\\ gen-2$\\rightarrow$gen-3: KS\\,=\\,0.09 for entropy mean), collapsing discriminative margins.\nartifacts/_project/paper/related_work.tex:33:The approaches are complementary: their theoretical framework explains \\emph{why} convergence occurs (attractor dynamics in semantic space), while our DDR decomposition reveals \\emph{what} converges (location properties) versus what remains stable (distributional shape), providing an empirical signature that can be exploited for detection without access to model internals.\nartifacts/_project/paper/related_work.tex:38:Declining lexical diversity in LLM-generated text is documented in both training \\cite{curious_decline} and deployment \\cite{writing_diversity} settings.\nartifacts/_project/paper/related_work.tex:39:Our surface features (TTR and hapax ratio) are classical stylometric measures \\cite{stamatatos_survey,koppel_authorship} that we apply to inference chains, showing monotonic diversity decline across depths without model retraining.\nartifacts/_project/paper/related_work.tex:40:We push beyond generator identity \\cite{uchendu_attribution} to the \\emph{depth} dimension, and show that diversity declines monotonically even under top-$p$ sampling \\cite{nucleus_sampling}.\nartifacts/_project/paper/related_work.tex:45:Scalable data curation relies on quality signals \\cite{dsir,qurating,ccnet}; generation depth is a complementary provenance signal characterizing \\emph{how many steps removed} text is from a human source.\nartifacts/_project/paper/related_work.tex:46:Proactive watermarking \\cite{watermark_llm,synthid_text,aaronson_watermark} embeds identifiable patterns, but watermark strength decays across multi-step chains \\cite{chainwash}, motivating passive post-hoc methods like ours.\nartifacts/_project/paper/appendix_dataset_stats.tex:4:Table~\\ref{tab:dataset-stats} reports per-generator sample counts after filtering (removing generation failures, exact duplicates, and passages shorter than 50 whitespace tokens).\nartifacts/_project/paper/appendix_dataset_stats.tex:25:\\caption[Per-generator sample counts]{Per-generator sample counts after filtering (8 generators, 5 families). Each generator starts from ${\\sim}$1{,}000 shared Wikipedia seeds and produces chains of depth 4 (5 texts per chain). Attrition varies by generator due to differing generation failure rates.\\protect\\footnotemark}\nartifacts/_project/paper/appendix_dataset_stats.tex:31:The violin plots confirm the DDR pattern: drifting features (entropy mean, TTR, hapax ratio) show progressive narrowing and location shift, while shape features (entropy max, tail decay) maintain approximately constant distributions across depths.\nartifacts/_project/paper/appendix_dataset_stats.tex:36:\\caption{Feature distributions by generation depth (violin plots, $N$\\,=\\,37{,}058). Drifting features (entropy mean, TTR, hapax ratio: $|\\rho| > 0.60$) show clear location shifts and narrowing with increasing depth. Shape features (entropy max, tail decay: $|\\rho| < 0.10$) remain approximately stationary. Quartile lines indicate median and interquartile range.}\nartifacts/_project/paper/appendix_prompt_type.tex:1:We evaluate depth fingerprinting under three prompt types using Pythia-2.8B: \\emph{continuation} (``Continue the following text''), \\emph{elaboration} (``Elaborate on the following text''), and \\emph{inspired rewriting} (``Write a new passage inspired by the following text''). Each uses 995 seeds $\\times$ 5 depths.\nartifacts/_project/paper/appendix_prompt_type.tex:4:5-fold CV macro-F1: continuation 0.78, rewriting 0.74, elaboration 0.73. All three prompt types exhibit the same differential depth response pattern: drifting features (hapax ratio, TTR, entropy mean) show consistent monotonic trends, while stationary features (entropy std, tail decay) change by less than 5\\%.\nartifacts/_project/paper/appendix_prompt_type.tex:7:Leave-one-prompt-type-out evaluation yields average F1\\,=\\,0.753, confirming that depth signal transfers across prompt types. Feature decay rates differ: continuation shows the strongest drift (16.9\\% per depth step), followed by rewriting (6.1\\%) and elaboration (1.4\\%), consistent with continuation chains applying less semantic constraint on the output.\nartifacts/_project/paper/appendix_qlora.tex:1:To assess whether depth signal extends beyond handcrafted features, we fine-tune a pretrained language model end-to-end as a depth classifier using QLoRA \\cite{qlora}.\nartifacts/_project/paper/appendix_qlora.tex:4:We fine-tune Qwen3-0.6B-Base with LoRA rank 16, learning rate $2 \\times 10^{-4}$, and 3 epochs, framing depth estimation as 5-class sequence classification (gen-0 through gen-4).\\footnote{Evaluated on the original 6-generator subset; XGBoost 3-class F1\\,=\\,0.789. We expect 8-generator training to further improve given additional diversity; the comparison direction is preserved.}\nartifacts/_project/paper/appendix_qlora.tex:30:A second run with LoRA rank 32 and seed 123 yields 5-class F1\\,=\\,0.587 ($\\pm$0.005) and 3-class F1\\,=\\,0.905 ($\\pm$0.004), confirming stability across hyperparameter and seed variation ($\\Delta < 1$\\,pp on both metrics).\nartifacts/_project/paper/appendix_qlora.tex:34:End-to-end fine-tuning exploits token-level patterns (e.g., positional regularities, n-gram repetitions) that aggregate features cannot represent.\nartifacts/_project/paper/appendix_feature_distributions.tex:4:The consistent downward trajectories for drifting features across all generators confirm that DDR is a universal property of recursive generation.\nartifacts/_project/paper/appendix_feature_distributions.tex:14:\\subsection*{UMAP Embedding}\nartifacts/_project/paper/appendix_feature_distributions.tex:18:Panel (b) shows the 3-class view: gen-0 forms a separable cluster, while gen-1 and gen-2+ overlap substantially, explaining the classification difficulty at this boundary.\nartifacts/_project/paper/appendix_cross_temp.tex:2:We evaluate four train$\\rightarrow$test temperature conditions using Qwen3-1.7B data regenerated at $t{=}1.0$ (remaining five generators retain $t{=}0.7$).\nartifacts/_project/paper/appendix_cross_temp.tex:7:[Omitted long matching line]\nartifacts/_project/paper/appendix_cross_temp.tex:16:\\item \\textbf{Asymmetric transfer}: Training at $t{=}1.0$ and testing at $t{=}0.7$ (F1\\,=\\,0.791) transfers well, but the reverse (0.7$\\rightarrow$1.0, F1\\,=\\,0.723) degrades. This asymmetry reflects the information structure: features learned from high-variance (high-temperature) data generalize to low-variance settings, but not vice versa.\nartifacts/_project/paper/appendix_cross_temp.tex:18:\\item \\textbf{Generator-specific vulnerability}: Qwen3-1.7B, the only generator with temperature-mismatched test data, drops to F1\\,=\\,0.418 under cross-temperature conditions while all other generators maintain F1 $>$ 0.76. This confirms that depth features are calibrated to the specific decoding regime.\nartifacts/_project/paper/appendix_cross_temp.tex:20:\\item \\textbf{Binary robustness}: Binary classification (gen-0/1 vs.\\ gen-2+) is more robust to temperature mismatch (0.900--0.958 across all conditions) than 3-class, suggesting the coarser gen-0 vs.\\ machine boundary is less sensitive to decoding parameters than fine-grained depth discrimination.\nartifacts/_project/paper/main.tex:15:\\title{Depth Fingerprinting: Detecting Recursive Generation Depth\\\\in LLM Text Chains}\nartifacts/_project/paper/main.tex:39:Main paper results (\\S\\ref{sec:results}) use the full eight-generator set (adding Llama-3.2-3B and Mistral-7B-v0.3).\nartifacts/_project/paper/appendix_confusion_matrix.tex:17:\\caption{Aggregated 3-class confusion matrix from 6-generator LOGO evaluation ($N=27{,}529$). Each cell shows count and row-normalized percentage. Gen-0 is near-perfectly identified. Gen-1 errors are asymmetric: misclassification as gen-2+ (18.8\\%) is 3$\\times$ more frequent than as gen-0 (6.2\\%), indicating that gen-1 text already carries detectable recursive distortion.}\nartifacts/_project/paper/appendix_downstream.tex:18:\\caption{Downstream fine-tuning perplexity (OLMo-2-0425-1B, mean $\\pm$ std across 3 seeds). At equal sample count, random subsampling (2.367) outperforms depth-aware curation (depth 0--1: 2.387, binary-filtered: 2.389).}\nartifacts/_project/paper/appendix_downstream.tex:23:Training on all 12{,}299 samples yields the lowest perplexity (2.335).\nartifacts/_project/paper/appendix_downstream.tex:24:At equal sample count ($n$\\,=\\,3{,}951), random subsampling (2.367) \\emph{outperforms} both depth-stratified selection (depth 0--1: 2.387) and binary detection filtering (2.389).\nartifacts/_project/paper/appendix_downstream.tex:25:Cross-seed variance is below 0.002 across all variants, confirming the robustness of this null result.\nartifacts/_project/paper/appendix_downstream.tex:27:Restricting training to human-only text (depth 0, $n$\\,=\\,797) produces a sharp perplexity increase to 2.681, driven primarily by the 5$\\times$ reduction in data volume rather than depth composition per se.\nartifacts/_project/paper/appendix_downstream.tex:30:We apply a two one-sided $t$-test (TOST) with a $\\pm$2\\% relative margin (equivalence bounds $\\pm$0.047 on the ppl scale) to formally assess whether the depth-aware and random subsampling conditions produce practically indistinguishable perplexity.\nartifacts/_project/paper/appendix_downstream.tex:32:TOST confirms equivalence ($p = 1.1 \\times 10^{-4}$), indicating the two curation strategies yield practically indistinguishable downstream quality within the $\\pm$2\\% margin.\nartifacts/_project/paper/appendix_downstream.tex:35:Comparing the full dataset ($n$\\,=\\,12{,}299, ppl\\,=\\,2.335) against the depth-filtered subset ($n$\\,=\\,3{,}951, ppl\\,=\\,2.387): TOST \\emph{rejects} equivalence (minimum equivalence margin\\,=\\,0.053, exceeding the $\\pm$2\\% bound), confirming that data quantity drives perplexity reduction beyond what depth-aware selection can recover.\nartifacts/_project/paper/appendix_downstream.tex:37:Knowing the generation depth of a document does not, by itself, make it more or less useful for training; at fixed sample count, depth-aware curation is statistically equivalent to uninformed random subsampling.\nartifacts/_project/paper/appendix_downstream.tex:41:To assess the robustness of the equivalence conclusion to margin choice, we repeat the TOST procedure across multiple equivalence margins \\cite{lakens_equivalence}, following the recommendation to report sensitivity across plausible bounds rather than relying on a single threshold (Table~\\ref{tab:tost-margins}).\nartifacts/_project/paper/appendix_downstream.tex:62:\\caption{TOST equivalence testing across multiple margins. ``Equiv?'' indicates whether equivalence is established at $\\alpha = 0.05$.}\nartifacts/_project/paper/appendix_downstream.tex:70:These appear large but are unreliable: with only $n$\\,=\\,3 seeds per condition, the pooled standard deviation is extremely small ($<$0.001), artificially inflating $d$.\nartifacts/_project/paper/appendix_downstream.tex:71:The inflated effect sizes reflect low seed-level variance (confirming reproducibility) rather than practically meaningful perplexity differences.\nartifacts/_project/paper/table1.tex:22:Each row holds out one generator for testing and trains on the remaining seven.}\nartifacts/_project/paper/appendix_human_edit.tex:1:We assess robustness to post-generation text modification by randomly replacing words at varying rates and re-evaluating the 8-generator LOGO pipeline (Table~\\ref{tab:human-edit}).\nartifacts/_project/paper/appendix_human_edit.tex:2:Random word replacement represents a worst-case perturbation: real human editing preserves semantic coherence, so practical degradation is expected to be substantially lower than these estimates.\nartifacts/_project/paper/appendix_human_edit.tex:22:Binary depth discrimination (gen-1 vs.\\ gen-2+) degrades sublinearly: the first 5\\% replacement causes the largest drop ($-$4.6\\,pp), with diminishing marginal impact thereafter ($-$3.6\\,pp for 5\\%$\\to$10\\%, $-$2.3\\,pp for 10\\%$\\to$20\\%).\nartifacts/_project/paper/appendix_human_edit.tex:23:At 10\\% replacement, binary F1 remains 0.614, well above the 0.50 random baseline, indicating that depth signal survives moderate perturbation.\nartifacts/_project/paper/appendix_human_edit.tex:25:Three-class classification is more sensitive (0.737$\\to$0.367 at 20\\%), because distinguishing gen-0 from gen-1 relies heavily on lexical diversity features (TTR, hapax ratio) that are directly disrupted by word replacement.\nartifacts/_project/paper/appendix_human_edit.tex:31:At 20\\% replacement, the 7-feature ensemble surpasses entropy-only on binary F1 (0.591 vs.\\ 0.569), despite starting from a lower baseline.\nartifacts/_project/paper/appendix_human_edit.tex:32:Random word replacement drastically alters per-token context, making entropy features (computed over the full token sequence) extremely sensitive to noise.\nartifacts/_project/paper/appendix_human_edit.tex:39:\\caption{Feature subset degradation under random word replacement (8-gen LOGO). Entropy-only: 5 reference-model features; 7-feature: full ensemble including lexical features.}\nartifacts/_project/paper/appendix_human_edit.tex:82:The 7-feature ensemble offers the highest starting performance among single-reference methods, with sublinear degradation ($-$10.4\\,pp at 20\\%).\nartifacts/_project/paper/appendix_human_edit.tex:87:The binary degradation ($-$4.5\\,pp) is nearly identical to that caused by 5\\% random word replacement ($-$4.6\\,pp), despite the LLM rephrase altering ${\\sim}$50\\% of characters.\nartifacts/_project/paper/appendix_human_edit.tex:88:This asymmetry arises because LLM-generated replacements preserve the underlying statistical fingerprint of the generation process (entropy dynamics, depth-accumulated distributional drift), whereas random word substitution directly destroys local statistical signals.\nartifacts/_project/paper/appendix_human_edit.tex:89:Depth fingerprinting thus captures deep generative structure that survives semantic-preserving edits.\nartifacts/_project/paper/appendix_human_edit.tex:92:Performance is stable across seed text complexity: stratifying seeds by vocabulary richness (TTR terciles) yields maximum F1 variation of 1.1\\,pp across groups.\nartifacts/_project/paper/conclusion.tex:6:The signal degrades substantially under instruction tuning and may further compress at larger scales (our largest generator is 8B), defining the current scope boundaries.\nartifacts/_project/paper/appendix_lofo.tex:26:Entropy\\_max causes the largest degradation when removed ($-$1.5\\,pp), despite ranking only fourth in permutation importance (split frequency 0.063). This indicates that entropy\\_max provides unique signal (capturing the most surprising token under the reference model) that is not redundant with other features.\nartifacts/_project/paper/appendix_lofo.tex:28:Six of seven features contribute positively to the ensemble, confirming that the 7-feature design is not over-specified.\nartifacts/_project/paper/discussion.tex:4:The near-stationarity of shape features is consistent with the softmax architecture and fixed sampling parameters constraining distributional shape while allowing location to drift.\nartifacts/_project/paper/discussion.tex:5:Sampling ablation supports this as a tendency rather than a guarantee ($t \\in [0.5, 0.7]$: ${\\leq}0.3$\\,pp degradation; $t = 1.0$: $-6$\\,pp; Appendix~\\ref{app:sampling-sensitivity}), and prompt-type dependence further modulates the effect (elaboration F1\\,=\\,0.730 vs.\\ continuation 0.781; Appendix~\\ref{app:prompt-type}).\nartifacts/_project/paper/discussion.tex:9:At the document level within base models, gen-1 per-class F1\\,=\\,0.63 is insufficient for automated filtering but sufficient for corpus-level flagging; the gen-1\\,/\\,gen-2+ boundary concentrates 86\\% of binary errors as false negatives, with larger generators exacerbating this (Mistral-7B error rate 45\\% vs.\\ Pythia-1B 18\\%; Appendix~\\ref{app:error-analysis}).\nartifacts/_project/paper/discussion.tex:12:Three classes represent the practical resolution ceiling: 5-class F1 drops to ${\\approx}$0.50 (Appendix~\\ref{app:finer-depth}), and ordinal-specific methods (CORAL, Frank-Hall) yield no improvement over standard XGBoost (Appendix~\\ref{app:classifier}), suggesting that the gen-1/gen-2+ boundary rather than ordinal structure is the bottleneck.\nartifacts/_project/paper/discussion.tex:13:DDR is distinct from model collapse \\cite{curse_of_recursion,strong_model_collapse}: inference-chain drift occurs with fixed parameters, is fully reversible, and approximately preserves distributional shape, suggesting compression within existing capacity rather than erosion of it.\nartifacts/_project/paper/method.tex:7:[Omitted long matching line]\nartifacts/_project/paper/method.tex:14:Given a text $x$, the goal is to predict its \\emph{generation depth} $d \\in \\{0, 1, 2{+}\\}$, where $d{=}0$ denotes human-written text, $d{=}1$ denotes first-generation LLM output conditioned on human text, and $d{=}2{+}$ denotes text produced by recursively conditioning an LLM on its own prior output at least twice.\nartifacts/_project/paper/method.tex:17:We frame depth estimation as an ordinal classification task over three classes rather than binary real-vs-synthetic detection, enabling finer-grained provenance characterization.\nartifacts/_project/paper/method.tex:23:We construct generation chains using eight generators spanning five model families: \\textbf{Pythia} (2.8B, 1B) \\cite{pythia}, \\textbf{OLMo} (OLMo-2-1B) \\cite{olmo}, \\textbf{Qwen} (Qwen3-1.7B, Qwen3-0.6B, Qwen3-8B-Base) \\cite{qwen3}, \\textbf{Llama} (Llama-3.2-3B) \\cite{llama3}, and \\textbf{Mistral} (Mistral-7B-v0.3) \\cite{mistral7b}.\nartifacts/_project/paper/method.tex:24:This selection covers parameter scales from 0.6B to 8B and diverse pretraining corpora, enabling evaluation of cross-generator and cross-scale generalization.\nartifacts/_project/paper/method.tex:28:We use shared seeds across generators to ensure that cross-generator comparisons control for input content, isolating the effect of the generation model from source text variation.\nartifacts/_project/paper/method.tex:29:In LOGO evaluation, gen-0 samples from the held-out generator's chains also appear (with the same text) in the training generators' chains, creating a potential train--test overlap for the gen-0 class.\nartifacts/_project/paper/method.tex:30:We address this with a supplementary binary evaluation excluding gen-0 entirely (\\S\\ref{sec:results-baselines}).\nartifacts/_project/paper/method.tex:31:Each seed is iteratively fed through the generator to produce a chain of depth 4 (i.e., gen-0 through gen-4), using the prompt ``\\texttt{Continue the following text: \\{text\\}}''.\nartifacts/_project/paper/method.tex:32:All generation uses temperature $\\tau{=}0.7$, nucleus sampling with $p{=}0.9$, and maximum length of 256 new tokens.\nartifacts/_project/paper/method.tex:33:The theoretical yield is $8 \\times {\\sim}1{,}000 \\times 5 = 39{,}815$ texts; after removing 2{,}746 chain breaks (empty or degenerate outputs at intermediate depths that prevented deeper generation) and 11 passages too short for feature extraction, 37{,}058 texts remain (Appendix~\\ref{app:dataset-stats}).\nartifacts/_project/paper/method.tex:42:This two-pronged design is validated through leave-one-feature-out analysis (Appendix~\\ref{app:lofo}) and cross-group ablation (\\S\\ref{sec:results-differential}), confirming that both feature groups contribute to depth discrimination.\nartifacts/_project/paper/method.tex:48:We use ``entropy'' as shorthand for token-level NLL throughout, following convention in prior detection work; these are point-wise NLL values, not Shannon entropy of the full distribution.\nartifacts/_project/paper/method.tex:50:From the resulting NLL sequence, we extract five statistics:\nartifacts/_project/paper/method.tex:52:    \\item \\textbf{entropy\\_mean}: mean token-level NLL, capturing the average predictability of the text under the reference model;\nartifacts/_project/paper/method.tex:53:    \\item \\textbf{entropy\\_std}: standard deviation of token-level NLL, measuring the spread of per-token surprise;\nartifacts/_project/paper/method.tex:54:    \\item \\textbf{entropy\\_max}: maximum token-level NLL, capturing the most surprising token;\nartifacts/_project/paper/method.tex:55:    \\item \\textbf{entropy\\_min}: minimum token-level NLL, capturing the most predictable token. As generation depth increases, the floor of token-level surprise drops, reflecting the model's increasing confidence on its own outputs.\nartifacts/_project/paper/method.tex:56:    Retained because removing it does not improve performance (LOFO $\\Delta$F1\\,=\\,+0.01\\,pp, within bootstrap noise) and it completes the four-number NLL summary (mean, std, max, min), ensuring the classifier has access to the full marginal distribution shape;\nartifacts/_project/paper/method.tex:58:    For each text, we compute the mean log-probability of each vocabulary token across all positions under the reference model, sort tokens in descending order of mean log-probability, and fit a linear regression to ranks 100--1000.\nartifacts/_project/paper/method.tex:59:    The slope captures how steeply the reference model's probability mass decays beyond high-probability tokens, characterizing the shape of the distribution tail.\nartifacts/_project/paper/method.tex:64:Two features capture lexical diversity without requiring a reference model:\nartifacts/_project/paper/method.tex:67:    \\item \\textbf{hapax\\_ratio}: proportion of words appearing exactly once (\\emph{hapax legomena}).\nartifacts/_project/paper/method.tex:71:The grouping reflects an empirical pattern we term \\emph{differential depth response}: central-tendency and diversity features (entropy\\_mean, TTR, hapax\\_ratio) show substantial monotonic drift with generation depth ($|\\rho| = 0.60$--$0.63$); entropy\\_min and entropy\\_std show moderate drift ($|\\rho| = 0.17$--$0.41$); and shape features (entropy\\_max, tail\\_decay) remain near-stationary ($|\\rho| < 0.10$).\nartifacts/_project/paper/method.tex:72:This differential behavior, consistent with recursive generation shifting the location of the NLL distribution while approximately preserving distributional shape, motivates combining both feature types.\nartifacts/_project/paper/method.tex:84:We use XGBoost \\cite{xgboost} throughout ($n\\_\\text{estimators}{=}200$, $\\max\\_\\text{depth}{=}6$, learning rate $0.1$), with identical hyperparameters across all methods in Table~\\ref{tab:baselines}.\nartifacts/_project/paper/method.tex:86:Alternative classifiers and ordinal-specific methods (CORAL \\cite{coral_ordinal}, Frank-Hall \\cite{frank_hall_ordinal}) yield comparable performance (Appendix~\\ref{app:classifier}), confirming that discriminative power resides in the features.\nartifacts/_project/paper/method.tex:96:Each baseline score is used as a univariate feature in the same XGBoost framework under LOGO cross-validation, ensuring a controlled comparison.\nartifacts/_project/paper/method.tex:99:Since TTR and hapax\\_ratio are mechanically length-dependent, we verify depth signal is not a length artifact via length-matched subsampling that equalizes length distributions across depth classes (\\S\\ref{sec:results-classification}; Appendix~\\ref{app:length}).\nartifacts/_project/paper/limitations.tex:5:This is a deliberate design choice: base models isolate the generation mechanism from instruction-tuning effects, enabling controlled study of recursive distributional drift.\nartifacts/_project/paper/limitations.tex:7:Preliminary instruct experiments confirm that depth signal degrades substantially under instruction tuning: OLMo-2-1B-Instruct drops to LOGO F1\\,=\\,0.338 (vs.\\ 0.763 base) and Qwen3-0.6B with chat template to 0.667 (vs.\\ 0.816 base); these comparisons use earlier LOGO subsets (5--6 generators) predating the full 8-generator expansion in Table~\\ref{tab:logo-results}.\nartifacts/_project/paper/limitations.tex:8:Length-matched analysis yields near-zero correlations ($|\\rho| < 0.02$) and binary classification near chance (F1\\,$\\approx$\\,0.5) for Qwen models, leaving interpretation ambiguous.\nartifacts/_project/paper/limitations.tex:9:Extending depth fingerprinting to instruct models requires addressing these confounds (length regulation, format constraints, safety-driven distribution shaping) that instruction tuning introduces.\nartifacts/_project/paper/limitations.tex:15:Differential depth response strength is prompt-type dependent: continuation chains show strongest drift (within-type F1\\,=\\,0.781) compared to elaboration (0.730), rewriting (0.737), and paraphrastic chains (binary F1\\,=\\,0.671 vs.\\ 0.749 for continuation).\nartifacts/_project/paper/limitations.tex:19:Our primary evaluation uses single-generator chains; cross-model chains (\\S\\ref{sec:results-classification}) confirm depth signal under generator heterogeneity (3-class F1\\,=\\,0.809, binary F1\\,=\\,0.764), though the eight generators represent a controlled laboratory setting rather than the full diversity of real-world contamination.\nartifacts/_project/paper/limitations.tex:20:Simulated human editing (\\S\\ref{sec:discussion}) suggests graceful degradation, but the gap between simulated token replacement and real-world post-processing remains untested.\nartifacts/_project/paper/limitations.tex:24:Cross-domain evaluation (Appendix~\\ref{app:domain}) shows that depth signal persists across News, Academic, and Code domains (binary F1 $>$ 0.73 under LOGO at $t{=}1.0$), though a domain $\\times$ temperature interaction exists: certain domain/generator combinations at lower temperature approach chance level (e.g., Academic domain binary F1\\,=\\,0.628 at $t{=}0.7$), suggesting that reference model calibration is critical for cross-domain deployment.\nartifacts/_project/paper/limitations.tex:28:Our default analysis uses fixed decoding parameters (temperature 0.7, nucleus $p{=}0.9$). A sampling ablation (Appendix~\\ref{app:sampling-sensitivity}) shows robustness to moderate variation ($t \\in [0.5, 0.7]$, ${\\leq}0.3$\\,pp) but substantial degradation at $t{=}1.0$ ($-6$\\,pp), indicating that depth fingerprinting assumes standard decoding regimes.\nartifacts/_project/paper/limitations.tex:30:We use 3-class granularity (gen-0\\,/\\,gen-1\\,/\\,gen-2+). A 5-class evaluation (Appendix~\\ref{app:finer-depth}) yields LOGO F1\\,$\\approx$\\,0.50, with depths 2--4 mutually indistinguishable, validating the 3-class design as the practical resolution limit.\nartifacts/_project/paper/appendix_length.tex:10:Spearman rank correlation between word count and generation depth is weak across all eight generators ($|\\rho| < 0.14$), indicating that depth does not systematically shorten or lengthen text in our corpus.\nartifacts/_project/paper/appendix_length.tex:16:This motivates the length-matched evaluation below: if length mediates some depth--feature association, controlling for length will reduce classification performance.\nartifacts/_project/paper/appendix_length.tex:21:To distinguish this from a sample-size effect, we run a random-subsample control at equal $N$ without length matching: F1\\,=\\,0.767, confirming that the 0.046 drop reflects genuine length deconfounding rather than reduced data.\nartifacts/_project/paper/appendix_length.tex:26:Surface features (TTR, hapax\\_ratio) partially co-vary with length, but their depth-discriminative contribution persists after length control, consistent with generation-induced vocabulary compression operating independently of text truncation.\nartifacts/_project/paper/appendix_error_analysis.tex:10:The monotonic decrease confirms that deeper generations accumulate progressively stronger fingerprints, making the gen-1$\\to$gen-2 transition the hardest to detect.\nartifacts/_project/paper/appendix_error_analysis.tex:13:Table~\\ref{tab:error-by-gen} shows error rates vary substantially across generators, correlating with model scale: larger models (Mistral-7B, Qwen3-8B) produce text closer to gen-1 characteristics, making depth discrimination harder.\nartifacts/_project/paper/appendix_error_analysis.tex:37:Mann-Whitney U tests comparing correctly vs.\\ incorrectly classified samples reveal that drifting features show significant distributional differences between correct and incorrect predictions: entropy\\_mean ($p < 10^{-300}$), TTR ($p < 10^{-300}$), and hapax\\_ratio ($p < 10^{-300}$).\nartifacts/_project/paper/appendix_error_analysis.tex:38:In contrast, shape features show no discriminating power: entropy\\_max ($p = 0.584$) and tail\\_decay ($p = 0.653$).\nartifacts/_project/paper/appendix_error_analysis.tex:39:Misclassified gen-2+ samples have systematically higher TTR (0.464 vs.\\ 0.302 for correct) and entropy\\_mean (2.26 vs.\\ 1.57), indicating they retain gen-1-like lexical diversity and have not undergone the distributional convergence characteristic of deeper generations.\nartifacts/_project/paper/ethics.tex:15:All experiments were conducted on 4$\\times$ NVIDIA RTX 5090 GPUs (32\\,GB each), totaling approximately 62 GPU-hours.\nartifacts/_project/paper/abstract.tex:1:% Abstract — Depth Fingerprinting of Recursive LLM Generation Chains\nartifacts/_project/paper/abstract.tex:3:LLM-generated text increasingly re-enters the web and seeds subsequent generation, producing recursive chains whose outputs progressively diverge from human-written text.\nartifacts/_project/paper/abstract.tex:4:We ask whether this drift is structured enough to classify how many generation steps a text has undergone, framing this as \\emph{generation depth classification} (gen-0\\,/\\,gen-1\\,/\\,gen-2+ rather than binary real-vs-synthetic).\nartifacts/_project/paper/abstract.tex:5:Studying eight base (pretrained) models from five families (0.6B--8B parameters), we identify a \\emph{differential depth response} (DDR): central-tendency features (mean entropy, lexical diversity) drift monotonically with generation depth, while shape features (entropy max, vocabulary tail slope) remain near-stationary, consistent with a location shift in the token-level NLL distribution that approximately preserves distributional shape.\nartifacts/_project/paper/abstract.tex:6:A 7-feature ensemble achieves leak-free binary F1\\,=\\,0.694 under eight-generator leave-one-generator-out (LOGO) evaluation and 0.764 on cross-model chains (five-generator subset), using a single 410M-parameter reference model.\nartifacts/_project/paper/abstract.tex:7:The depth signal degrades substantially under instruction tuning, restricting current applicability to base models.\nartifacts/_project/paper/appendix_classifier.tex:2:we repeat the 6-generator LOGO evaluation using Logistic Regression and Random Forest\nartifacts/_project/paper/appendix_classifier.tex:5:kept identical. For Logistic Regression we apply standard scaling to the features.\nartifacts/_project/paper/appendix_classifier.tex:27:The per-generator ranking is also consistent across classifiers\nartifacts/_project/paper/appendix_classifier.tex:29:confirming that discriminative power originates in the entropy and lexical features,\nartifacts/_project/paper/appendix_classifier.tex:31:Ordinal-specific methods (CORAL \\cite{coral_ordinal}, Frank-Hall \\cite{frank_hall_ordinal}) achieve comparable F1 with overlapping CIs, confirming that 3-class granularity provides insufficient resolution for ranking-aware losses to improve over standard multiclass classification.\nartifacts/_project/paper/appendix_classifier.tex:33:\\subsection*{Sampling Sensitivity Analysis}\nartifacts/_project/paper/appendix_classifier.tex:36:To assess robustness to decoding hyperparameters, we regenerate Qwen3-1.7B continuation chains under three sampling configurations (the remaining five generators retain their default-configuration data) and re-evaluate the 6-generator LOGO pipeline (Table~\\ref{tab:sampling-ablation}).\nartifacts/_project/paper/appendix_classifier.tex:40:\\caption{Depth classification under varying sampling parameters. All other settings match the default pipeline. (6-generator LOGO; 3-class and binary.)}\nartifacts/_project/paper/appendix_classifier.tex:55:The depth signal is robust to moderate sampling variation: low and default configurations differ by at most 0.3\\,pp in both 3-class and binary F1, and entropy--depth Spearman correlations remain strongly negative ($\\rho \\leq -0.60$).\nartifacts/_project/paper/appendix_classifier.tex:57:This is consistent with the hypothesis that depth features are shaped by the sampling mechanism (\\S\\ref{sec:discussion}): elevated temperature injects sufficient randomness to flatten the distributional drift that accumulates across generation steps, effectively masking the depth signal.\nartifacts/_project/paper/appendix_classifier.tex:58:The practical implication is that depth fingerprinting applies reliably under standard decoding regimes but should not be expected to generalize to high-entropy sampling settings.\nartifacts/_project/paper/appendix_classifier.tex:64:The scale effect (larger models $\\rightarrow$ lower F1) is consistent with higher-capacity models generating text statistically closer to human writing.\nartifacts/_project/paper/appendix_classifier.tex:69:\\caption{Per-generator LOGO performance. (a) 8-generator binary and 3-class F1, sorted by binary F1. Dashed lines: pool average. (b) 6-generator LOGO detail heatmap showing the performance spread across model families.}\nartifacts/_project/paper/appendix_domain.tex:1:We evaluate whether depth signal generalizes beyond Wikipedia by constructing generation chains from three additional domains: News articles, Academic abstracts, and Code documentation.\nartifacts/_project/paper/appendix_domain.tex:2:For each domain, we sample 200 seed texts and generate chains of depth 3 using three generators (Pythia-1B, Qwen3-1.7B, Mistral-7B).\nartifacts/_project/paper/appendix_domain.tex:21:All three non-Wikipedia domains achieve binary F1 $>$ 0.73 under leave-one-generator-out evaluation, demonstrating that depth signal is not an artifact of Wikipedia text properties.\nartifacts/_project/paper/appendix_domain.tex:27:This finding suggests that reference model selection is a key factor for cross-domain deployment of depth fingerprinting.\nartifacts/_project/paper/appendix_domain.tex:30:In the cross-domain setting, 3-class F1 (0.62--0.65) falls below binary F1 (0.74--0.75), reversing the pattern observed in the main experiment (3-class 0.762 $>$ binary 0.694).\nartifacts/_project/paper/appendix_domain.tex:31:This inversion reflects degraded gen-0 vs.\\ gen-1 separation: the Pythia-410M reference model is calibrated to Wikipedia text, so its baseline entropy estimates are less discriminative for out-of-domain human text, compressing the feature distance between gen-0 and gen-1.\nartifacts/_project/paper/appendix_domain.tex:32:The binary task (gen-1 vs.\\ gen-2+) is unaffected because both classes are generated under identical domain and decoding conditions; recursive drift is a relative change that does not depend on absolute calibration.\nartifacts/_project/paper/introduction.tex:4:LLM-generated text increasingly re-enters the web and seeds subsequent generation \\cite{dolma,fineweb}, with estimates suggesting that 7--17\\% of recent scientific papers and peer reviews contain substantial LLM-modified content \\cite{mapping_llm_science,monitoring_ai_review}.\nartifacts/_project/paper/introduction.tex:6:[Omitted long matching line]\nartifacts/_project/paper/introduction.tex:8:We formulate \\emph{generation depth classification}, classifying text by generation depth (gen-0\\,/\\,gen-1\\,/\\,gen-2+) rather than a binary label, and refer to the overall framework as \\emph{depth fingerprinting}.\nartifacts/_project/paper/introduction.tex:9:No existing method addresses this task in non-paraphrastic continuation chains.\nartifacts/_project/paper/introduction.tex:11:The key finding is a \\emph{differential depth response} (DDR): when we measure how eight base-model generators from five families (Pythia, OLMo, Qwen, Llama, Mistral; 0.6B--8B parameters) transform text across recursive depths, central-tendency and diversity features (reference-model mean entropy, type-token ratio, hapax ratio) drift monotonically, while shape features (entropy max, tail decay) remain near-stationary.\nartifacts/_project/paper/introduction.tex:12:This pattern is consistent with recursive generation inducing a location shift in the token-level NLL distribution while approximately preserving its shape: the softmax architecture and fixed sampling parameters constrain distributional shape under standard decoding regimes, while each successive generation compresses the location toward the model's preferred output distribution.\nartifacts/_project/paper/introduction.tex:13:We restrict to base (pretrained) models as a deliberate design choice, since instruction-tuning introduces confounds (length regulation, format constraints, safety-driven shaping) that obscure this intrinsic mechanism; preliminary experiments confirm substantially degraded depth signal under instruction tuning (\\S\\ref{sec:discussion}).\nartifacts/_project/paper/introduction.tex:15:The combination of drifting and stationary features yields a 7-feature ensemble that, under eight-generator leave-one-generator-out (LOGO) evaluation, achieves leak-free binary F1\\,=\\,0.694 and 0.764 on cross-model chains (five-generator subset), using a single 410M-parameter reference model.\nartifacts/_project/paper/introduction.tex:17:The signal is prompt-type dependent: continuation chains show stronger drift than elaboration or rewriting (\\S\\ref{sec:discussion}).\nartifacts/_project/paper/introduction.tex:21:    \\item We formulate generation depth classification, moving beyond binary real-vs-synthetic detection to classify text as gen-0\\,/\\,gen-1\\,/\\,gen-2+, and construct an evaluation suite of 37K texts from eight base-model generators spanning five families (0.6B--8B parameters).\nartifacts/_project/paper/introduction.tex:22:    \\item We characterize a \\emph{differential depth response} (DDR): central-tendency features show monotonic drift under recursive generation ($|\\rho| > 0.60$) while distributional shape remains approximately stationary ($|\\rho| < 0.10$). A 7-feature ensemble exploiting this structure achieves leak-free binary F1\\,=\\,0.694 under eight-generator LOGO evaluation with a single 410M reference model.\nartifacts/_project/paper/appendix_finer_depth.tex:1:We evaluate finer-grained 5-class depth classification (gen-0 through gen-4) using the same 7-feature ensemble and LOGO protocol described in \\S\\ref{sec:method}.\nartifacts/_project/paper/appendix_finer_depth.tex:21:\\caption{5-class LOGO evaluation. Each row holds out one generator for testing, training on the remaining five.}\nartifacts/_project/paper/appendix_finer_depth.tex:41:Moving from 3-class (gen-0 / gen-1 / gen-2+) to 5-class classification reduces LOGO macro F1 from 0.762 to approximately 0.49.\nartifacts/_project/paper/appendix_finer_depth.tex:46:Shape features that are near-stationary in the 3-class setting become substantially more important under 5-class evaluation: permutation importance of entropy\\_std increases by 93\\% and tail\\_decay by 400\\% relative to 3-class, yet these gains are insufficient to resolve adjacent depths.\nartifacts/_project/paper/appendix_finer_depth.tex:47:These results support the 3-class grouping adopted in the main paper: collapsing gen-2+ preserves the most informative boundary (human vs.\\ first-generation vs.\\ deeper recursion) while avoiding the noise introduced by near-identical adjacent depths.\nartifacts/_project/paper/appendix_finer_depth.tex:50:To verify that 5-class degradation reflects feature-level limitations rather than classifier choice, we evaluate four alternatives under the same protocol: HistGradientBoosting (macro F1\\,=\\,0.501, 95\\% bootstrap CI [0.496, 0.506]), random forest (0.476), logistic regression (0.447), and Frank-Hall ordinal reduction (0.451).\nartifacts/_project/paper/appendix_finer_depth.tex:51:All classifiers perform comparably to the default XGBoost ensemble (0.501), ruling out classifier capacity as the bottleneck.\nartifacts/_project/paper/appendix_finer_depth.tex:52:The gen-2/gen-3 boundary is the primary failure mode across all methods: these two classes are effectively inseparable with the current feature set, establishing 3-class granularity as the practical ceiling for surface and entropy features.\nartifacts/_project/paper/appendix_finer_depth.tex:53:At the 3-class level, ordinal-specific methods (CORAL ordinal regression, Frank-Hall reduction) similarly fail to improve over multiclass XGBoost (\\S\\ref{sec:results}), confirming that the bottleneck is feature separability across all granularities, not the modeling of label ordinality.\nartifacts/_project/paper/results.tex:10:Per-generator binary F1 ranges from 0.633 (Mistral-7B) to 0.724 (Pythia-2.8B); the primary difficulty is distinguishing gen-1 from gen-2+ (Appendix~\\ref{app:confusion}).\nartifacts/_project/paper/results.tex:15:Cross-model chains (randomly selected generator per step) yield 3-class F1\\,=\\,0.809 and binary F1\\,=\\,0.764 under 5-fold CV,\\footnote{Cross-model chains use the original five-generator subset (Pythia, OLMo, Qwen); Llama and Mistral were added later for single-generator evaluation.} confirming that depth signal persists when text passes through heterogeneous generators.\nartifacts/_project/paper/results.tex:16:The higher cross-model performance relative to single-generator LOGO (3-class: 0.809 vs.\\ 0.762) suggests that generator heterogeneity amplifies distributional shifts between depths, making each recursive step more distinct.\nartifacts/_project/paper/results.tex:19:Leave-one-family-out (LOFO) evaluation yields average binary F1\\,=\\,0.686, confirming transfer across architectural families.\nartifacts/_project/paper/results.tex:20:A scale effect emerges: Pythia generators achieve the highest binary F1 (0.718--0.724), while larger models show degradation (Mistral-7B: 0.633), consistent with higher-capacity models compressing the feature margins DDR exploits.\nartifacts/_project/paper/results.tex:24:Length-matched subsampling yields binary F1\\,=\\,0.724 (vs.\\ 0.770 unmatched); a random-subsample control confirms the drop reflects deconfounding, not sample-size reduction (Appendix~\\ref{app:length}).\nartifacts/_project/paper/results.tex:47:\\caption{8-generator LOGO macro-F1 for the 7-feature ensemble (bootstrap 95\\% CIs, $n$\\,=\\,1000). Binary F1 (gen-1 vs.\\ gen-2+) is the primary metric. Note: 3-class F1 may carry upward bias from gen-0 seed sharing across generators; binary F1 is leak-free. Cross-model chains (Table~\\ref{tab:cross-ref}) use sample-level CV without this issue.}\nartifacts/_project/paper/results.tex:54:Features exhibit \\emph{differential depth response} (DDR): central-tendency and diversity measures drift monotonically with depth, while shape measures remain near-stationary, consistent with recursive generation inducing a location shift in the NLL distribution while approximately preserving its functional form (shape-feature CV shift $<$3\\% vs.\\ $>$15\\% for drifting features).\nartifacts/_project/paper/results.tex:64:drifting features show substantial monotonic trends (hapax ratio $\\rho = -0.63$, TTR $\\rho = -0.61$, entropy mean $\\rho = -0.60$),\nartifacts/_project/paper/results.tex:66:The six-fold magnitude gap between drifting ($|\\rho| > 0.60$) and shape features ($|\\rho| < 0.10$) serves as the operative criterion for the DDR split, with entropy std occupying an intermediate position ($|\\rho| = 0.17$); shifting these descriptive thresholds by $\\pm 0.10$ does not alter feature grouping.\nartifacts/_project/paper/results.tex:70:Levene tests reject equal variance for all features ($p < 10^{-10}$), but effect sizes differ markedly: shape-feature CV shift $<$3\\% vs.\\ $>$15\\% for drifting features, supporting ``approximately preserves'' as a practical characterization rather than a strict invariance claim.\nartifacts/_project/paper/results.tex:78:Alternative references (OLMo-2-1B, Qwen3-0.6B) achieve comparable LOGO F1 (spread 0.013; Table~\\ref{tab:cross-ref} in Appendix~\\ref{app:cross-ref}), with consistently negative entropy drift, confirming DDR is a property of recursive generation.\nartifacts/_project/paper/results.tex:82:At $t{=}1.0$, performance degrades by ${\\sim}6$\\,pp as the primary depth signal collapses: entropy mean's Spearman correlation with depth drops from $\\rho = -0.60$ to $\\rho = -0.002$, indicating that high-temperature sampling injects sufficient token-level randomness to mask the systematic location shift that DDR exploits.\nartifacts/_project/paper/results.tex:88:We repurpose four detection scores as ordinal depth predictors using the same XGBoost framework and LOGO splits (Table~\\ref{tab:baselines}, Figure~\\ref{fig:baseline-ci}).\nartifacts/_project/paper/results.tex:113:[Omitted long matching line]\nartifacts/_project/paper/results.tex:121:Preliminary downstream evaluation (fine-tuning OLMo-2-0425-1B on depth-stratified data; Appendix~\\ref{app:downstream}) finds that depth composition does not determine training utility at fixed sample count, though the evidence is limited (three seeds, single perplexity metric).",
    "numLines": 188
  }
}
```

</details>

---


### Assistant

_source line 12_

<details><summary>Logged reasoning block</summary>

```text
Let me read the full output of the third grep and also specifically search for the problematic -ing patterns (participle phrases used at the end of sentences/clauses).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "10139a59-0e20-4b40-9e4a-7a3de8df083b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QLTcq2iLiLa84wJTzFkiqa",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2684,
      "cache_read_input_tokens": 25521,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2684
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

_source line 13_

Let me do more targeted searches for the problematic -ing participle phrase patterns.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "3565ce1c-a6e8-4d3a-9a87-2be79a691476",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QLTcq2iLiLa84wJTzFkiqa",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2684,
      "cache_read_input_tokens": 25521,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2684
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

_source line 14_

<details open><summary>🔧 Tool call — Grep · `toolu_01711es5fbsGAECzNtRmMSoW`</summary>

```json
{
  "pattern": ", [a-z]+ing [a-z]",
  "glob": "*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper",
  "output_mode": "content",
  "-n": true,
  "head_limit": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "17bd87be-d0fb-4028-9cd0-198bb03d2577",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QLTcq2iLiLa84wJTzFkiqa",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2684,
      "cache_read_input_tokens": 25521,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2684
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

_source line 15 · 2026-05-17T19:51:52.726Z_

<details><summary>↩ Tool result · `toolu_01711es5fbsGAECzNtRmMSoW`</summary>

```text
artifacts/_project/paper/related_work.tex:26:\citet{broken_telephone} analyze paraphrasing and translation chains, showing progressive information loss.
artifacts/_project/paper/related_work.tex:28:We differ in three respects: (i) we study \emph{non-paraphrastic continuation} chains, where the absence of semantic anchoring permits richer depth signal; (ii) we use handcrafted features rather than model-internal representations, enabling the DDR decomposition into drifting vs.\ stationary components; and (iii) we focus on \emph{estimating} depth from text rather than characterizing the convergence dynamics of the generation process.
artifacts/_project/paper/related_work.tex:32:We observe the same bound empirically through feature-space compression: inter-class KS statistics drop sharply after depth 2 (gen-1$\rightarrow$gen-2: KS\,=\,0.28 vs.\ gen-2$\rightarrow$gen-3: KS\,=\,0.09 for entropy mean), collapsing discriminative margins.
artifacts/_project/paper/related_work.tex:33:The approaches are complementary: their theoretical framework explains \emph{why} convergence occurs (attractor dynamics in semantic space), while our DDR decomposition reveals \emph{what} converges (location properties) versus what remains stable (distributional shape), providing an empirical signature that can be exploited for detection without access to model internals.
artifacts/_project/paper/related_work.tex:39:Our surface features (TTR and hapax ratio) are classical stylometric measures \cite{stamatatos_survey,koppel_authorship} that we apply to inference chains, showing monotonic diversity decline across depths without model retraining.
artifacts/_project/paper/related_work.tex:46:Proactive watermarking \cite{watermark_llm,synthid_text,aaronson_watermark} embeds identifiable patterns, but watermark strength decays across multi-step chains \cite{chainwash}, motivating passive post-hoc methods like ours.
artifacts/_project/paper/appendix_prompt_type.tex:7:Leave-one-prompt-type-out evaluation yields average F1\,=\,0.753, confirming that depth signal transfers across prompt types. Feature decay rates differ: continuation shows the strongest drift (16.9\% per depth step), followed by rewriting (6.1\%) and elaboration (1.4\%), consistent with continuation chains applying less semantic constraint on the output.
artifacts/_project/paper/appendix_qlora.tex:4:We fine-tune Qwen3-0.6B-Base with LoRA rank 16, learning rate $2 \times 10^{-4}$, and 3 epochs, framing depth estimation as 5-class sequence classification (gen-0 through gen-4).\footnote{Evaluated on the original 6-generator subset; XGBoost 3-class F1\,=\,0.789. We expect 8-generator training to further improve given additional diversity; the comparison direction is preserved.}
artifacts/_project/paper/appendix_qlora.tex:30:A second run with LoRA rank 32 and seed 123 yields 5-class F1\,=\,0.587 ($\pm$0.005) and 3-class F1\,=\,0.905 ($\pm$0.004), confirming stability across hyperparameter and seed variation ($\Delta < 1$\,pp on both metrics).
artifacts/_project/paper/appendix_feature_distributions.tex:18:Panel (b) shows the 3-class view: gen-0 forms a separable cluster, while gen-1 and gen-2+ overlap substantially, explaining the classification difficulty at this boundary.
artifacts/_project/paper/appendix_cross_temp.tex:7:[Omitted long matching line]
artifacts/_project/paper/appendix_cross_temp.tex:20:\item \textbf{Binary robustness}: Binary classification (gen-0/1 vs.\ gen-2+) is more robust to temperature mismatch (0.900--0.958 across all conditions) than 3-class, suggesting the coarser gen-0 vs.\ machine boundary is less sensitive to decoding parameters than fine-grained depth discrimination.
artifacts/_project/paper/appendix_confusion_matrix.tex:17:\caption{Aggregated 3-class confusion matrix from 6-generator LOGO evaluation ($N=27{,}529$). Each cell shows count and row-normalized percentage. Gen-0 is near-perfectly identified. Gen-1 errors are asymmetric: misclassification as gen-2+ (18.8\%) is 3$\times$ more frequent than as gen-0 (6.2\%), indicating that gen-1 text already carries detectable recursive distortion.}
artifacts/_project/paper/appendix_downstream.tex:25:Cross-seed variance is below 0.002 across all variants, confirming the robustness of this null result.
artifacts/_project/paper/appendix_downstream.tex:32:TOST confirms equivalence ($p = 1.1 \times 10^{-4}$), indicating the two curation strategies yield practically indistinguishable downstream quality within the $\pm$2\% margin.
artifacts/_project/paper/appendix_downstream.tex:35:Comparing the full dataset ($n$\,=\,12{,}299, ppl\,=\,2.335) against the depth-filtered subset ($n$\,=\,3{,}951, ppl\,=\,2.387): TOST \emph{rejects} equivalence (minimum equivalence margin\,=\,0.053, exceeding the $\pm$2\% bound), confirming that data quantity drives perplexity reduction beyond what depth-aware selection can recover.
artifacts/_project/paper/appendix_downstream.tex:41:To assess the robustness of the equivalence conclusion to margin choice, we repeat the TOST procedure across multiple equivalence margins \cite{lakens_equivalence}, following the recommendation to report sensitivity across plausible bounds rather than relying on a single threshold (Table~\ref{tab:tost-margins}).
artifacts/_project/paper/appendix_human_edit.tex:23:At 10\% replacement, binary F1 remains 0.614, well above the 0.50 random baseline, indicating that depth signal survives moderate perturbation.
artifacts/_project/paper/appendix_human_edit.tex:32:Random word replacement drastically alters per-token context, making entropy features (computed over the full token sequence) extremely sensitive to noise.
artifacts/_project/paper/conclusion.tex:6:The signal degrades substantially under instruction tuning and may further compress at larger scales (our largest generator is 8B), defining the current scope boundaries.
artifacts/_project/paper/appendix_lofo.tex:28:Six of seven features contribute positively to the ensemble, confirming that the 7-feature design is not over-specified.
artifacts/_project/paper/discussion.tex:12:Three classes represent the practical resolution ceiling: 5-class F1 drops to ${\approx}$0.50 (Appendix~\ref{app:finer-depth}), and ordinal-specific methods (CORAL, Frank-Hall) yield no improvement over standard XGBoost (Appendix~\ref{app:classifier}), suggesting that the gen-1/gen-2+ boundary rather than ordinal structure is the bottleneck.
artifacts/_project/paper/discussion.tex:13:DDR is distinct from model collapse \cite{curse_of_recursion,strong_model_collapse}: inference-chain drift occurs with fixed parameters, is fully reversible, and approximately preserves distributional shape, suggesting compression within existing capacity rather than erosion of it.
artifacts/_project/paper/method.tex:7:[Omitted long matching line]
artifacts/_project/paper/method.tex:17:We frame depth estimation as an ordinal classification task over three classes rather than binary real-vs-synthetic detection, enabling finer-grained provenance characterization.
artifacts/_project/paper/method.tex:24:This selection covers parameter scales from 0.6B to 8B and diverse pretraining corpora, enabling evaluation of cross-generator and cross-scale generalization.
artifacts/_project/paper/method.tex:28:We use shared seeds across generators to ensure that cross-generator comparisons control for input content, isolating the effect of the generation model from source text variation.
artifacts/_project/paper/method.tex:29:In LOGO evaluation, gen-0 samples from the held-out generator's chains also appear (with the same text) in the training generators' chains, creating a potential train--test overlap for the gen-0 class.
artifacts/_project/paper/method.tex:31:Each seed is iteratively fed through the generator to produce a chain of depth 4 (i.e., gen-0 through gen-4), using the prompt ``\texttt{Continue the following text: \{text\}}''.
artifacts/_project/paper/method.tex:42:This two-pronged design is validated through leave-one-feature-out analysis (Appendix~\ref{app:lofo}) and cross-group ablation (\S\ref{sec:results-differential}), confirming that both feature groups contribute to depth discrimination.
artifacts/_project/paper/method.tex:48:We use ``entropy'' as shorthand for token-level NLL throughout, following convention in prior detection work; these are point-wise NLL values, not Shannon entropy of the full distribution.
artifacts/_project/paper/method.tex:52:    \item \textbf{entropy\_mean}: mean token-level NLL, capturing the average predictability of the text under the reference model;
artifacts/_project/paper/method.tex:53:    \item \textbf{entropy\_std}: standard deviation of token-level NLL, measuring the spread of per-token surprise;
artifacts/_project/paper/method.tex:54:    \item \textbf{entropy\_max}: maximum token-level NLL, capturing the most surprising token;
artifacts/_project/paper/method.tex:55:    \item \textbf{entropy\_min}: minimum token-level NLL, capturing the most predictable token. As generation depth increases, the floor of token-level surprise drops, reflecting the model's increasing confidence on its own outputs.
artifacts/_project/paper/method.tex:56:    Retained because removing it does not improve performance (LOFO $\Delta$F1\,=\,+0.01\,pp, within bootstrap noise) and it completes the four-number NLL summary (mean, std, max, min), ensuring the classifier has access to the full marginal distribution shape;
artifacts/_project/paper/method.tex:59:    The slope captures how steeply the reference model's probability mass decays beyond high-probability tokens, characterizing the shape of the distribution tail.
artifacts/_project/paper/method.tex:84:We use XGBoost \cite{xgboost} throughout ($n\_\text{estimators}{=}200$, $\max\_\text{depth}{=}6$, learning rate $0.1$), with identical hyperparameters across all methods in Table~\ref{tab:baselines}.
artifacts/_project/paper/method.tex:86:Alternative classifiers and ordinal-specific methods (CORAL \cite{coral_ordinal}, Frank-Hall \cite{frank_hall_ordinal}) yield comparable performance (Appendix~\ref{app:classifier}), confirming that discriminative power resides in the features.
artifacts/_project/paper/method.tex:96:Each baseline score is used as a univariate feature in the same XGBoost framework under LOGO cross-validation, ensuring a controlled comparison.
artifacts/_project/paper/limitations.tex:5:This is a deliberate design choice: base models isolate the generation mechanism from instruction-tuning effects, enabling controlled study of recursive distributional drift.
artifacts/_project/paper/limitations.tex:8:Length-matched analysis yields near-zero correlations ($|\rho| < 0.02$) and binary classification near chance (F1\,$\approx$\,0.5) for Qwen models, leaving interpretation ambiguous.
artifacts/_project/paper/limitations.tex:24:Cross-domain evaluation (Appendix~\ref{app:domain}) shows that depth signal persists across News, Academic, and Code domains (binary F1 $>$ 0.73 under LOGO at $t{=}1.0$), though a domain $\times$ temperature interaction exists: certain domain/generator combinations at lower temperature approach chance level (e.g., Academic domain binary F1\,=\,0.628 at $t{=}0.7$), suggesting that reference model calibration is critical for cross-domain deployment.
artifacts/_project/paper/limitations.tex:28:Our default analysis uses fixed decoding parameters (temperature 0.7, nucleus $p{=}0.9$). A sampling ablation (Appendix~\ref{app:sampling-sensitivity}) shows robustness to moderate variation ($t \in [0.5, 0.7]$, ${\leq}0.3$\,pp) but substantial degradation at $t{=}1.0$ ($-6$\,pp), indicating that depth fingerprinting assumes standard decoding regimes.
artifacts/_project/paper/limitations.tex:30:We use 3-class granularity (gen-0\,/\,gen-1\,/\,gen-2+). A 5-class evaluation (Appendix~\ref{app:finer-depth}) yields LOGO F1\,$\approx$\,0.50, with depths 2--4 mutually indistinguishable, validating the 3-class design as the practical resolution limit.
artifacts/_project/paper/appendix_length.tex:10:Spearman rank correlation between word count and generation depth is weak across all eight generators ($|\rho| < 0.14$), indicating that depth does not systematically shorten or lengthen text in our corpus.
artifacts/_project/paper/appendix_length.tex:16:This motivates the length-matched evaluation below: if length mediates some depth--feature association, controlling for length will reduce classification performance.
artifacts/_project/paper/appendix_length.tex:21:To distinguish this from a sample-size effect, we run a random-subsample control at equal $N$ without length matching: F1\,=\,0.767, confirming that the 0.046 drop reflects genuine length deconfounding rather than reduced data.
artifacts/_project/paper/appendix_error_analysis.tex:10:The monotonic decrease confirms that deeper generations accumulate progressively stronger fingerprints, making the gen-1$\to$gen-2 transition the hardest to detect.
artifacts/_project/paper/appendix_error_analysis.tex:13:Table~\ref{tab:error-by-gen} shows error rates vary substantially across generators, correlating with model scale: larger models (Mistral-7B, Qwen3-8B) produce text closer to gen-1 characteristics, making depth discrimination harder.
artifacts/_project/paper/appendix_error_analysis.tex:39:Misclassified gen-2+ samples have systematically higher TTR (0.464 vs.\ 0.302 for correct) and entropy\_mean (2.26 vs.\ 1.57), indicating they retain gen-1-like lexical diversity and have not undergone the distributional convergence characteristic of deeper generations.
artifacts/_project/paper/ethics.tex:15:All experiments were conducted on 4$\times$ NVIDIA RTX 5090 GPUs (32\,GB each), totaling approximately 62 GPU-hours.
artifacts/_project/paper/abstract.tex:3:LLM-generated text increasingly re-enters the web and seeds subsequent generation, producing recursive chains whose outputs progressively diverge from human-written text.
artifacts/_project/paper/abstract.tex:4:We ask whether this drift is structured enough to classify how many generation steps a text has undergone, framing this as \emph{generation depth classification} (gen-0\,/\,gen-1\,/\,gen-2+ rather than binary real-vs-synthetic).
artifacts/_project/paper/abstract.tex:6:A 7-feature ensemble achieves leak-free binary F1\,=\,0.694 under eight-generator leave-one-generator-out (LOGO) evaluation and 0.764 on cross-model chains (five-generator subset), using a single 410M-parameter reference model.
artifacts/_project/paper/abstract.tex:7:The depth signal degrades substantially under instruction tuning, restricting current applicability to base models.
artifacts/_project/paper/results.tex:16:The higher cross-model performance relative to single-generator LOGO (3-class: 0.809 vs.\ 0.762) suggests that generator heterogeneity amplifies distributional shifts between depths, making each recursive step more distinct.
artifacts/_project/paper/results.tex:19:Leave-one-family-out (LOFO) evaluation yields average binary F1\,=\,0.686, confirming transfer across architectural families.
artifacts/_project/paper/results.tex:82:At $t{=}1.0$, performance degrades by ${\sim}6$\,pp as the primary depth signal collapses: entropy mean's Spearman correlation with depth drops from $\rho = -0.60$ to $\rho = -0.002$, indicating that high-temperature sampling injects sufficient token-level randomness to mask the systematic location shift that DDR exploits.
artifacts/_project/paper/results.tex:113:[Omitted long matching line]
artifacts/_project/paper/introduction.tex:6:[Omitted long matching line]
artifacts/_project/paper/introduction.tex:8:We formulate \emph{generation depth classification}, classifying text by generation depth (gen-0\,/\,gen-1\,/\,gen-2+) rather than a binary label, and refer to the overall framework as \emph{depth fingerprinting}.
artifacts/_project/paper/introduction.tex:15:The combination of drifting and stationary features yields a 7-feature ensemble that, under eight-generator leave-one-generator-out (LOGO) evaluation, achieves leak-free binary F1\,=\,0.694 and 0.764 on cross-model chains (five-generator subset), using a single 410M-parameter reference model.
artifacts/_project/paper/introduction.tex:21:    \item We formulate generation depth classification, moving beyond binary real-vs-synthetic detection to classify text as gen-0\,/\,gen-1\,/\,gen-2+, and construct an evaluation suite of 37K texts from eight base-model generators spanning five families (0.6B--8B parameters).
artifacts/_project/paper/appendix_finer_depth.tex:21:\caption{5-class LOGO evaluation. Each row holds out one generator for testing, training on the remaining five.}
artifacts/_project/paper/appendix_finer_depth.tex:51:All classifiers perform comparably to the default XGBoost ensemble (0.501), ruling out classifier capacity as the bottleneck.
artifacts/_project/paper/appendix_finer_depth.tex:53:At the 3-class level, ordinal-specific methods (CORAL ordinal regression, Frank-Hall reduction) similarly fail to improve over multiclass XGBoost (\S\ref{sec:results}), confirming that the bottleneck is feature separability across all granularities, not the modeling of label ordinality.
artifacts/_project/paper/appendix_domain.tex:21:All three non-Wikipedia domains achieve binary F1 $>$ 0.73 under leave-one-generator-out evaluation, demonstrating that depth signal is not an artifact of Wikipedia text properties.
artifacts/_project/paper/appendix_domain.tex:30:In the cross-domain setting, 3-class F1 (0.62--0.65) falls below binary F1 (0.74--0.75), reversing the pattern observed in the main experiment (3-class 0.762 $>$ binary 0.694).
artifacts/_project/paper/appendix_domain.tex:31:This inversion reflects degraded gen-0 vs.\ gen-1 separation: the Pythia-410M reference model is calibrated to Wikipedia text, so its baseline entropy estimates are less discriminative for out-of-domain human text, compressing the feature distance between gen-0 and gen-1.
artifacts/_project/paper/appendix_classifier.tex:31:Ordinal-specific methods (CORAL \cite{coral_ordinal}, Frank-Hall \cite{frank_hall_ordinal}) achieve comparable F1 with overlapping CIs, confirming that 3-class granularity provides insufficient resolution for ranking-aware losses to improve over standard multiclass classification.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "a533ff5a-8b9f-4275-a33f-fce90181449f",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "artifacts/_project/paper/related_work.tex:26:\\citet{broken_telephone} analyze paraphrasing and translation chains, showing progressive information loss.\nartifacts/_project/paper/related_work.tex:28:We differ in three respects: (i) we study \\emph{non-paraphrastic continuation} chains, where the absence of semantic anchoring permits richer depth signal; (ii) we use handcrafted features rather than model-internal representations, enabling the DDR decomposition into drifting vs.\\ stationary components; and (iii) we focus on \\emph{estimating} depth from text rather than characterizing the convergence dynamics of the generation process.\nartifacts/_project/paper/related_work.tex:32:We observe the same bound empirically through feature-space compression: inter-class KS statistics drop sharply after depth 2 (gen-1$\\rightarrow$gen-2: KS\\,=\\,0.28 vs.\\ gen-2$\\rightarrow$gen-3: KS\\,=\\,0.09 for entropy mean), collapsing discriminative margins.\nartifacts/_project/paper/related_work.tex:33:The approaches are complementary: their theoretical framework explains \\emph{why} convergence occurs (attractor dynamics in semantic space), while our DDR decomposition reveals \\emph{what} converges (location properties) versus what remains stable (distributional shape), providing an empirical signature that can be exploited for detection without access to model internals.\nartifacts/_project/paper/related_work.tex:39:Our surface features (TTR and hapax ratio) are classical stylometric measures \\cite{stamatatos_survey,koppel_authorship} that we apply to inference chains, showing monotonic diversity decline across depths without model retraining.\nartifacts/_project/paper/related_work.tex:46:Proactive watermarking \\cite{watermark_llm,synthid_text,aaronson_watermark} embeds identifiable patterns, but watermark strength decays across multi-step chains \\cite{chainwash}, motivating passive post-hoc methods like ours.\nartifacts/_project/paper/appendix_prompt_type.tex:7:Leave-one-prompt-type-out evaluation yields average F1\\,=\\,0.753, confirming that depth signal transfers across prompt types. Feature decay rates differ: continuation shows the strongest drift (16.9\\% per depth step), followed by rewriting (6.1\\%) and elaboration (1.4\\%), consistent with continuation chains applying less semantic constraint on the output.\nartifacts/_project/paper/appendix_qlora.tex:4:We fine-tune Qwen3-0.6B-Base with LoRA rank 16, learning rate $2 \\times 10^{-4}$, and 3 epochs, framing depth estimation as 5-class sequence classification (gen-0 through gen-4).\\footnote{Evaluated on the original 6-generator subset; XGBoost 3-class F1\\,=\\,0.789. We expect 8-generator training to further improve given additional diversity; the comparison direction is preserved.}\nartifacts/_project/paper/appendix_qlora.tex:30:A second run with LoRA rank 32 and seed 123 yields 5-class F1\\,=\\,0.587 ($\\pm$0.005) and 3-class F1\\,=\\,0.905 ($\\pm$0.004), confirming stability across hyperparameter and seed variation ($\\Delta < 1$\\,pp on both metrics).\nartifacts/_project/paper/appendix_feature_distributions.tex:18:Panel (b) shows the 3-class view: gen-0 forms a separable cluster, while gen-1 and gen-2+ overlap substantially, explaining the classification difficulty at this boundary.\nartifacts/_project/paper/appendix_cross_temp.tex:7:[Omitted long matching line]\nartifacts/_project/paper/appendix_cross_temp.tex:20:\\item \\textbf{Binary robustness}: Binary classification (gen-0/1 vs.\\ gen-2+) is more robust to temperature mismatch (0.900--0.958 across all conditions) than 3-class, suggesting the coarser gen-0 vs.\\ machine boundary is less sensitive to decoding parameters than fine-grained depth discrimination.\nartifacts/_project/paper/appendix_confusion_matrix.tex:17:\\caption{Aggregated 3-class confusion matrix from 6-generator LOGO evaluation ($N=27{,}529$). Each cell shows count and row-normalized percentage. Gen-0 is near-perfectly identified. Gen-1 errors are asymmetric: misclassification as gen-2+ (18.8\\%) is 3$\\times$ more frequent than as gen-0 (6.2\\%), indicating that gen-1 text already carries detectable recursive distortion.}\nartifacts/_project/paper/appendix_downstream.tex:25:Cross-seed variance is below 0.002 across all variants, confirming the robustness of this null result.\nartifacts/_project/paper/appendix_downstream.tex:32:TOST confirms equivalence ($p = 1.1 \\times 10^{-4}$), indicating the two curation strategies yield practically indistinguishable downstream quality within the $\\pm$2\\% margin.\nartifacts/_project/paper/appendix_downstream.tex:35:Comparing the full dataset ($n$\\,=\\,12{,}299, ppl\\,=\\,2.335) against the depth-filtered subset ($n$\\,=\\,3{,}951, ppl\\,=\\,2.387): TOST \\emph{rejects} equivalence (minimum equivalence margin\\,=\\,0.053, exceeding the $\\pm$2\\% bound), confirming that data quantity drives perplexity reduction beyond what depth-aware selection can recover.\nartifacts/_project/paper/appendix_downstream.tex:41:To assess the robustness of the equivalence conclusion to margin choice, we repeat the TOST procedure across multiple equivalence margins \\cite{lakens_equivalence}, following the recommendation to report sensitivity across plausible bounds rather than relying on a single threshold (Table~\\ref{tab:tost-margins}).\nartifacts/_project/paper/appendix_human_edit.tex:23:At 10\\% replacement, binary F1 remains 0.614, well above the 0.50 random baseline, indicating that depth signal survives moderate perturbation.\nartifacts/_project/paper/appendix_human_edit.tex:32:Random word replacement drastically alters per-token context, making entropy features (computed over the full token sequence) extremely sensitive to noise.\nartifacts/_project/paper/conclusion.tex:6:The signal degrades substantially under instruction tuning and may further compress at larger scales (our largest generator is 8B), defining the current scope boundaries.\nartifacts/_project/paper/appendix_lofo.tex:28:Six of seven features contribute positively to the ensemble, confirming that the 7-feature design is not over-specified.\nartifacts/_project/paper/discussion.tex:12:Three classes represent the practical resolution ceiling: 5-class F1 drops to ${\\approx}$0.50 (Appendix~\\ref{app:finer-depth}), and ordinal-specific methods (CORAL, Frank-Hall) yield no improvement over standard XGBoost (Appendix~\\ref{app:classifier}), suggesting that the gen-1/gen-2+ boundary rather than ordinal structure is the bottleneck.\nartifacts/_project/paper/discussion.tex:13:DDR is distinct from model collapse \\cite{curse_of_recursion,strong_model_collapse}: inference-chain drift occurs with fixed parameters, is fully reversible, and approximately preserves distributional shape, suggesting compression within existing capacity rather than erosion of it.\nartifacts/_project/paper/method.tex:7:[Omitted long matching line]\nartifacts/_project/paper/method.tex:17:We frame depth estimation as an ordinal classification task over three classes rather than binary real-vs-synthetic detection, enabling finer-grained provenance characterization.\nartifacts/_project/paper/method.tex:24:This selection covers parameter scales from 0.6B to 8B and diverse pretraining corpora, enabling evaluation of cross-generator and cross-scale generalization.\nartifacts/_project/paper/method.tex:28:We use shared seeds across generators to ensure that cross-generator comparisons control for input content, isolating the effect of the generation model from source text variation.\nartifacts/_project/paper/method.tex:29:In LOGO evaluation, gen-0 samples from the held-out generator's chains also appear (with the same text) in the training generators' chains, creating a potential train--test overlap for the gen-0 class.\nartifacts/_project/paper/method.tex:31:Each seed is iteratively fed through the generator to produce a chain of depth 4 (i.e., gen-0 through gen-4), using the prompt ``\\texttt{Continue the following text: \\{text\\}}''.\nartifacts/_project/paper/method.tex:42:This two-pronged design is validated through leave-one-feature-out analysis (Appendix~\\ref{app:lofo}) and cross-group ablation (\\S\\ref{sec:results-differential}), confirming that both feature groups contribute to depth discrimination.\nartifacts/_project/paper/method.tex:48:We use ``entropy'' as shorthand for token-level NLL throughout, following convention in prior detection work; these are point-wise NLL values, not Shannon entropy of the full distribution.\nartifacts/_project/paper/method.tex:52:    \\item \\textbf{entropy\\_mean}: mean token-level NLL, capturing the average predictability of the text under the reference model;\nartifacts/_project/paper/method.tex:53:    \\item \\textbf{entropy\\_std}: standard deviation of token-level NLL, measuring the spread of per-token surprise;\nartifacts/_project/paper/method.tex:54:    \\item \\textbf{entropy\\_max}: maximum token-level NLL, capturing the most surprising token;\nartifacts/_project/paper/method.tex:55:    \\item \\textbf{entropy\\_min}: minimum token-level NLL, capturing the most predictable token. As generation depth increases, the floor of token-level surprise drops, reflecting the model's increasing confidence on its own outputs.\nartifacts/_project/paper/method.tex:56:    Retained because removing it does not improve performance (LOFO $\\Delta$F1\\,=\\,+0.01\\,pp, within bootstrap noise) and it completes the four-number NLL summary (mean, std, max, min), ensuring the classifier has access to the full marginal distribution shape;\nartifacts/_project/paper/method.tex:59:    The slope captures how steeply the reference model's probability mass decays beyond high-probability tokens, characterizing the shape of the distribution tail.\nartifacts/_project/paper/method.tex:84:We use XGBoost \\cite{xgboost} throughout ($n\\_\\text{estimators}{=}200$, $\\max\\_\\text{depth}{=}6$, learning rate $0.1$), with identical hyperparameters across all methods in Table~\\ref{tab:baselines}.\nartifacts/_project/paper/method.tex:86:Alternative classifiers and ordinal-specific methods (CORAL \\cite{coral_ordinal}, Frank-Hall \\cite{frank_hall_ordinal}) yield comparable performance (Appendix~\\ref{app:classifier}), confirming that discriminative power resides in the features.\nartifacts/_project/paper/method.tex:96:Each baseline score is used as a univariate feature in the same XGBoost framework under LOGO cross-validation, ensuring a controlled comparison.\nartifacts/_project/paper/limitations.tex:5:This is a deliberate design choice: base models isolate the generation mechanism from instruction-tuning effects, enabling controlled study of recursive distributional drift.\nartifacts/_project/paper/limitations.tex:8:Length-matched analysis yields near-zero correlations ($|\\rho| < 0.02$) and binary classification near chance (F1\\,$\\approx$\\,0.5) for Qwen models, leaving interpretation ambiguous.\nartifacts/_project/paper/limitations.tex:24:Cross-domain evaluation (Appendix~\\ref{app:domain}) shows that depth signal persists across News, Academic, and Code domains (binary F1 $>$ 0.73 under LOGO at $t{=}1.0$), though a domain $\\times$ temperature interaction exists: certain domain/generator combinations at lower temperature approach chance level (e.g., Academic domain binary F1\\,=\\,0.628 at $t{=}0.7$), suggesting that reference model calibration is critical for cross-domain deployment.\nartifacts/_project/paper/limitations.tex:28:Our default analysis uses fixed decoding parameters (temperature 0.7, nucleus $p{=}0.9$). A sampling ablation (Appendix~\\ref{app:sampling-sensitivity}) shows robustness to moderate variation ($t \\in [0.5, 0.7]$, ${\\leq}0.3$\\,pp) but substantial degradation at $t{=}1.0$ ($-6$\\,pp), indicating that depth fingerprinting assumes standard decoding regimes.\nartifacts/_project/paper/limitations.tex:30:We use 3-class granularity (gen-0\\,/\\,gen-1\\,/\\,gen-2+). A 5-class evaluation (Appendix~\\ref{app:finer-depth}) yields LOGO F1\\,$\\approx$\\,0.50, with depths 2--4 mutually indistinguishable, validating the 3-class design as the practical resolution limit.\nartifacts/_project/paper/appendix_length.tex:10:Spearman rank correlation between word count and generation depth is weak across all eight generators ($|\\rho| < 0.14$), indicating that depth does not systematically shorten or lengthen text in our corpus.\nartifacts/_project/paper/appendix_length.tex:16:This motivates the length-matched evaluation below: if length mediates some depth--feature association, controlling for length will reduce classification performance.\nartifacts/_project/paper/appendix_length.tex:21:To distinguish this from a sample-size effect, we run a random-subsample control at equal $N$ without length matching: F1\\,=\\,0.767, confirming that the 0.046 drop reflects genuine length deconfounding rather than reduced data.\nartifacts/_project/paper/appendix_error_analysis.tex:10:The monotonic decrease confirms that deeper generations accumulate progressively stronger fingerprints, making the gen-1$\\to$gen-2 transition the hardest to detect.\nartifacts/_project/paper/appendix_error_analysis.tex:13:Table~\\ref{tab:error-by-gen} shows error rates vary substantially across generators, correlating with model scale: larger models (Mistral-7B, Qwen3-8B) produce text closer to gen-1 characteristics, making depth discrimination harder.\nartifacts/_project/paper/appendix_error_analysis.tex:39:Misclassified gen-2+ samples have systematically higher TTR (0.464 vs.\\ 0.302 for correct) and entropy\\_mean (2.26 vs.\\ 1.57), indicating they retain gen-1-like lexical diversity and have not undergone the distributional convergence characteristic of deeper generations.\nartifacts/_project/paper/ethics.tex:15:All experiments were conducted on 4$\\times$ NVIDIA RTX 5090 GPUs (32\\,GB each), totaling approximately 62 GPU-hours.\nartifacts/_project/paper/abstract.tex:3:LLM-generated text increasingly re-enters the web and seeds subsequent generation, producing recursive chains whose outputs progressively diverge from human-written text.\nartifacts/_project/paper/abstract.tex:4:We ask whether this drift is structured enough to classify how many generation steps a text has undergone, framing this as \\emph{generation depth classification} (gen-0\\,/\\,gen-1\\,/\\,gen-2+ rather than binary real-vs-synthetic).\nartifacts/_project/paper/abstract.tex:6:A 7-feature ensemble achieves leak-free binary F1\\,=\\,0.694 under eight-generator leave-one-generator-out (LOGO) evaluation and 0.764 on cross-model chains (five-generator subset), using a single 410M-parameter reference model.\nartifacts/_project/paper/abstract.tex:7:The depth signal degrades substantially under instruction tuning, restricting current applicability to base models.\nartifacts/_project/paper/results.tex:16:The higher cross-model performance relative to single-generator LOGO (3-class: 0.809 vs.\\ 0.762) suggests that generator heterogeneity amplifies distributional shifts between depths, making each recursive step more distinct.\nartifacts/_project/paper/results.tex:19:Leave-one-family-out (LOFO) evaluation yields average binary F1\\,=\\,0.686, confirming transfer across architectural families.\nartifacts/_project/paper/results.tex:82:At $t{=}1.0$, performance degrades by ${\\sim}6$\\,pp as the primary depth signal collapses: entropy mean's Spearman correlation with depth drops from $\\rho = -0.60$ to $\\rho = -0.002$, indicating that high-temperature sampling injects sufficient token-level randomness to mask the systematic location shift that DDR exploits.\nartifacts/_project/paper/results.tex:113:[Omitted long matching line]\nartifacts/_project/paper/introduction.tex:6:[Omitted long matching line]\nartifacts/_project/paper/introduction.tex:8:We formulate \\emph{generation depth classification}, classifying text by generation depth (gen-0\\,/\\,gen-1\\,/\\,gen-2+) rather than a binary label, and refer to the overall framework as \\emph{depth fingerprinting}.\nartifacts/_project/paper/introduction.tex:15:The combination of drifting and stationary features yields a 7-feature ensemble that, under eight-generator leave-one-generator-out (LOGO) evaluation, achieves leak-free binary F1\\,=\\,0.694 and 0.764 on cross-model chains (five-generator subset), using a single 410M-parameter reference model.\nartifacts/_project/paper/introduction.tex:21:    \\item We formulate generation depth classification, moving beyond binary real-vs-synthetic detection to classify text as gen-0\\,/\\,gen-1\\,/\\,gen-2+, and construct an evaluation suite of 37K texts from eight base-model generators spanning five families (0.6B--8B parameters).\nartifacts/_project/paper/appendix_finer_depth.tex:21:\\caption{5-class LOGO evaluation. Each row holds out one generator for testing, training on the remaining five.}\nartifacts/_project/paper/appendix_finer_depth.tex:51:All classifiers perform comparably to the default XGBoost ensemble (0.501), ruling out classifier capacity as the bottleneck.\nartifacts/_project/paper/appendix_finer_depth.tex:53:At the 3-class level, ordinal-specific methods (CORAL ordinal regression, Frank-Hall reduction) similarly fail to improve over multiclass XGBoost (\\S\\ref{sec:results}), confirming that the bottleneck is feature separability across all granularities, not the modeling of label ordinality.\nartifacts/_project/paper/appendix_domain.tex:21:All three non-Wikipedia domains achieve binary F1 $>$ 0.73 under leave-one-generator-out evaluation, demonstrating that depth signal is not an artifact of Wikipedia text properties.\nartifacts/_project/paper/appendix_domain.tex:30:In the cross-domain setting, 3-class F1 (0.62--0.65) falls below binary F1 (0.74--0.75), reversing the pattern observed in the main experiment (3-class 0.762 $>$ binary 0.694).\nartifacts/_project/paper/appendix_domain.tex:31:This inversion reflects degraded gen-0 vs.\\ gen-1 separation: the Pythia-410M reference model is calibrated to Wikipedia text, so its baseline entropy estimates are less discriminative for out-of-domain human text, compressing the feature distance between gen-0 and gen-1.\nartifacts/_project/paper/appendix_classifier.tex:31:Ordinal-specific methods (CORAL \\cite{coral_ordinal}, Frank-Hall \\cite{frank_hall_ordinal}) achieve comparable F1 with overlapping CIs, confirming that 3-class granularity provides insufficient resolution for ranking-aware losses to improve over standard multiclass classification.",
    "numLines": 71
  }
}
```

</details>

---


### Tool call

_source line 16_

<details open><summary>🔧 Tool call — Grep · `toolu_01C9P32rYymDYBXWdsbsRJRP`</summary>

```json
{
  "pattern": ", (suggesting|indicating|demonstrating|highlighting|enabling|achieving|preserving|revealing|confirming|yielding|providing|establishing|outperforming|reflecting|supporting|reinforcing|motivating|limiting|restricting|reducing|showing|making|offering|allowing|producing|capturing|leveraging|underscoring|illustrating)",
  "glob": "*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper",
  "output_mode": "content",
  "-n": true,
  "head_limit": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "0d55a9fa-1892-4168-9988-faa9d4d92e21",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QLTcq2iLiLa84wJTzFkiqa",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2684,
      "cache_read_input_tokens": 25521,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2684
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

_source line 17 · 2026-05-17T19:51:54.927Z_

<details><summary>↩ Tool result · `toolu_01C9P32rYymDYBXWdsbsRJRP`</summary>

```text
artifacts/_project/paper/related_work.tex:26:\citet{broken_telephone} analyze paraphrasing and translation chains, showing progressive information loss.
artifacts/_project/paper/related_work.tex:28:We differ in three respects: (i) we study \emph{non-paraphrastic continuation} chains, where the absence of semantic anchoring permits richer depth signal; (ii) we use handcrafted features rather than model-internal representations, enabling the DDR decomposition into drifting vs.\ stationary components; and (iii) we focus on \emph{estimating} depth from text rather than characterizing the convergence dynamics of the generation process.
artifacts/_project/paper/related_work.tex:33:The approaches are complementary: their theoretical framework explains \emph{why} convergence occurs (attractor dynamics in semantic space), while our DDR decomposition reveals \emph{what} converges (location properties) versus what remains stable (distributional shape), providing an empirical signature that can be exploited for detection without access to model internals.
artifacts/_project/paper/related_work.tex:39:Our surface features (TTR and hapax ratio) are classical stylometric measures \cite{stamatatos_survey,koppel_authorship} that we apply to inference chains, showing monotonic diversity decline across depths without model retraining.
artifacts/_project/paper/related_work.tex:46:Proactive watermarking \cite{watermark_llm,synthid_text,aaronson_watermark} embeds identifiable patterns, but watermark strength decays across multi-step chains \cite{chainwash}, motivating passive post-hoc methods like ours.
artifacts/_project/paper/appendix_prompt_type.tex:7:Leave-one-prompt-type-out evaluation yields average F1\,=\,0.753, confirming that depth signal transfers across prompt types. Feature decay rates differ: continuation shows the strongest drift (16.9\% per depth step), followed by rewriting (6.1\%) and elaboration (1.4\%), consistent with continuation chains applying less semantic constraint on the output.
artifacts/_project/paper/appendix_qlora.tex:30:A second run with LoRA rank 32 and seed 123 yields 5-class F1\,=\,0.587 ($\pm$0.005) and 3-class F1\,=\,0.905 ($\pm$0.004), confirming stability across hyperparameter and seed variation ($\Delta < 1$\,pp on both metrics).
artifacts/_project/paper/appendix_cross_temp.tex:7:[Omitted long matching line]
artifacts/_project/paper/appendix_cross_temp.tex:20:\item \textbf{Binary robustness}: Binary classification (gen-0/1 vs.\ gen-2+) is more robust to temperature mismatch (0.900--0.958 across all conditions) than 3-class, suggesting the coarser gen-0 vs.\ machine boundary is less sensitive to decoding parameters than fine-grained depth discrimination.
artifacts/_project/paper/appendix_confusion_matrix.tex:17:\caption{Aggregated 3-class confusion matrix from 6-generator LOGO evaluation ($N=27{,}529$). Each cell shows count and row-normalized percentage. Gen-0 is near-perfectly identified. Gen-1 errors are asymmetric: misclassification as gen-2+ (18.8\%) is 3$\times$ more frequent than as gen-0 (6.2\%), indicating that gen-1 text already carries detectable recursive distortion.}
artifacts/_project/paper/appendix_downstream.tex:25:Cross-seed variance is below 0.002 across all variants, confirming the robustness of this null result.
artifacts/_project/paper/appendix_downstream.tex:32:TOST confirms equivalence ($p = 1.1 \times 10^{-4}$), indicating the two curation strategies yield practically indistinguishable downstream quality within the $\pm$2\% margin.
artifacts/_project/paper/appendix_downstream.tex:35:Comparing the full dataset ($n$\,=\,12{,}299, ppl\,=\,2.335) against the depth-filtered subset ($n$\,=\,3{,}951, ppl\,=\,2.387): TOST \emph{rejects} equivalence (minimum equivalence margin\,=\,0.053, exceeding the $\pm$2\% bound), confirming that data quantity drives perplexity reduction beyond what depth-aware selection can recover.
artifacts/_project/paper/appendix_human_edit.tex:23:At 10\% replacement, binary F1 remains 0.614, well above the 0.50 random baseline, indicating that depth signal survives moderate perturbation.
artifacts/_project/paper/appendix_human_edit.tex:32:Random word replacement drastically alters per-token context, making entropy features (computed over the full token sequence) extremely sensitive to noise.
artifacts/_project/paper/appendix_lofo.tex:28:Six of seven features contribute positively to the ensemble, confirming that the 7-feature design is not over-specified.
artifacts/_project/paper/discussion.tex:12:Three classes represent the practical resolution ceiling: 5-class F1 drops to ${\approx}$0.50 (Appendix~\ref{app:finer-depth}), and ordinal-specific methods (CORAL, Frank-Hall) yield no improvement over standard XGBoost (Appendix~\ref{app:classifier}), suggesting that the gen-1/gen-2+ boundary rather than ordinal structure is the bottleneck.
artifacts/_project/paper/discussion.tex:13:DDR is distinct from model collapse \cite{curse_of_recursion,strong_model_collapse}: inference-chain drift occurs with fixed parameters, is fully reversible, and approximately preserves distributional shape, suggesting compression within existing capacity rather than erosion of it.
artifacts/_project/paper/method.tex:7:[Omitted long matching line]
artifacts/_project/paper/method.tex:17:We frame depth estimation as an ordinal classification task over three classes rather than binary real-vs-synthetic detection, enabling finer-grained provenance characterization.
artifacts/_project/paper/method.tex:24:This selection covers parameter scales from 0.6B to 8B and diverse pretraining corpora, enabling evaluation of cross-generator and cross-scale generalization.
artifacts/_project/paper/method.tex:42:This two-pronged design is validated through leave-one-feature-out analysis (Appendix~\ref{app:lofo}) and cross-group ablation (\S\ref{sec:results-differential}), confirming that both feature groups contribute to depth discrimination.
artifacts/_project/paper/method.tex:52:    \item \textbf{entropy\_mean}: mean token-level NLL, capturing the average predictability of the text under the reference model;
artifacts/_project/paper/method.tex:54:    \item \textbf{entropy\_max}: maximum token-level NLL, capturing the most surprising token;
artifacts/_project/paper/method.tex:55:    \item \textbf{entropy\_min}: minimum token-level NLL, capturing the most predictable token. As generation depth increases, the floor of token-level surprise drops, reflecting the model's increasing confidence on its own outputs.
artifacts/_project/paper/method.tex:86:Alternative classifiers and ordinal-specific methods (CORAL \cite{coral_ordinal}, Frank-Hall \cite{frank_hall_ordinal}) yield comparable performance (Appendix~\ref{app:classifier}), confirming that discriminative power resides in the features.
artifacts/_project/paper/limitations.tex:5:This is a deliberate design choice: base models isolate the generation mechanism from instruction-tuning effects, enabling controlled study of recursive distributional drift.
artifacts/_project/paper/limitations.tex:24:Cross-domain evaluation (Appendix~\ref{app:domain}) shows that depth signal persists across News, Academic, and Code domains (binary F1 $>$ 0.73 under LOGO at $t{=}1.0$), though a domain $\times$ temperature interaction exists: certain domain/generator combinations at lower temperature approach chance level (e.g., Academic domain binary F1\,=\,0.628 at $t{=}0.7$), suggesting that reference model calibration is critical for cross-domain deployment.
artifacts/_project/paper/limitations.tex:28:Our default analysis uses fixed decoding parameters (temperature 0.7, nucleus $p{=}0.9$). A sampling ablation (Appendix~\ref{app:sampling-sensitivity}) shows robustness to moderate variation ($t \in [0.5, 0.7]$, ${\leq}0.3$\,pp) but substantial degradation at $t{=}1.0$ ($-6$\,pp), indicating that depth fingerprinting assumes standard decoding regimes.
artifacts/_project/paper/appendix_length.tex:10:Spearman rank correlation between word count and generation depth is weak across all eight generators ($|\rho| < 0.14$), indicating that depth does not systematically shorten or lengthen text in our corpus.
artifacts/_project/paper/appendix_length.tex:21:To distinguish this from a sample-size effect, we run a random-subsample control at equal $N$ without length matching: F1\,=\,0.767, confirming that the 0.046 drop reflects genuine length deconfounding rather than reduced data.
artifacts/_project/paper/appendix_error_analysis.tex:10:The monotonic decrease confirms that deeper generations accumulate progressively stronger fingerprints, making the gen-1$\to$gen-2 transition the hardest to detect.
artifacts/_project/paper/appendix_error_analysis.tex:13:Table~\ref{tab:error-by-gen} shows error rates vary substantially across generators, correlating with model scale: larger models (Mistral-7B, Qwen3-8B) produce text closer to gen-1 characteristics, making depth discrimination harder.
artifacts/_project/paper/appendix_error_analysis.tex:39:Misclassified gen-2+ samples have systematically higher TTR (0.464 vs.\ 0.302 for correct) and entropy\_mean (2.26 vs.\ 1.57), indicating they retain gen-1-like lexical diversity and have not undergone the distributional convergence characteristic of deeper generations.
artifacts/_project/paper/abstract.tex:3:LLM-generated text increasingly re-enters the web and seeds subsequent generation, producing recursive chains whose outputs progressively diverge from human-written text.
artifacts/_project/paper/abstract.tex:7:The depth signal degrades substantially under instruction tuning, restricting current applicability to base models.
artifacts/_project/paper/appendix_classifier.tex:31:Ordinal-specific methods (CORAL \cite{coral_ordinal}, Frank-Hall \cite{frank_hall_ordinal}) achieve comparable F1 with overlapping CIs, confirming that 3-class granularity provides insufficient resolution for ranking-aware losses to improve over standard multiclass classification.
artifacts/_project/paper/appendix_domain.tex:21:All three non-Wikipedia domains achieve binary F1 $>$ 0.73 under leave-one-generator-out evaluation, demonstrating that depth signal is not an artifact of Wikipedia text properties.
artifacts/_project/paper/appendix_finer_depth.tex:52:The gen-2/gen-3 boundary is the primary failure mode across all methods: these two classes are effectively inseparable with the current feature set, establishing 3-class granularity as the practical ceiling for surface and entropy features.
artifacts/_project/paper/appendix_finer_depth.tex:53:At the 3-class level, ordinal-specific methods (CORAL ordinal regression, Frank-Hall reduction) similarly fail to improve over multiclass XGBoost (\S\ref{sec:results}), confirming that the bottleneck is feature separability across all granularities, not the modeling of label ordinality.
artifacts/_project/paper/results.tex:16:The higher cross-model performance relative to single-generator LOGO (3-class: 0.809 vs.\ 0.762) suggests that generator heterogeneity amplifies distributional shifts between depths, making each recursive step more distinct.
artifacts/_project/paper/results.tex:19:Leave-one-family-out (LOFO) evaluation yields average binary F1\,=\,0.686, confirming transfer across architectural families.
artifacts/_project/paper/results.tex:70:Levene tests reject equal variance for all features ($p < 10^{-10}$), but effect sizes differ markedly: shape-feature CV shift $<$3\% vs.\ $>$15\% for drifting features, supporting ``approximately preserves'' as a practical characterization rather than a strict invariance claim.
artifacts/_project/paper/results.tex:78:Alternative references (OLMo-2-1B, Qwen3-0.6B) achieve comparable LOGO F1 (spread 0.013; Table~\ref{tab:cross-ref} in Appendix~\ref{app:cross-ref}), with consistently negative entropy drift, confirming DDR is a property of recursive generation.
artifacts/_project/paper/results.tex:82:At $t{=}1.0$, performance degrades by ${\sim}6$\,pp as the primary depth signal collapses: entropy mean's Spearman correlation with depth drops from $\rho = -0.60$ to $\rho = -0.002$, indicating that high-temperature sampling injects sufficient token-level randomness to mask the systematic location shift that DDR exploits.
artifacts/_project/paper/results.tex:113:[Omitted long matching line]
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "1d2db9b9-5a66-497d-af9d-a024a6acd9fe",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "artifacts/_project/paper/related_work.tex:26:\\citet{broken_telephone} analyze paraphrasing and translation chains, showing progressive information loss.\nartifacts/_project/paper/related_work.tex:28:We differ in three respects: (i) we study \\emph{non-paraphrastic continuation} chains, where the absence of semantic anchoring permits richer depth signal; (ii) we use handcrafted features rather than model-internal representations, enabling the DDR decomposition into drifting vs.\\ stationary components; and (iii) we focus on \\emph{estimating} depth from text rather than characterizing the convergence dynamics of the generation process.\nartifacts/_project/paper/related_work.tex:33:The approaches are complementary: their theoretical framework explains \\emph{why} convergence occurs (attractor dynamics in semantic space), while our DDR decomposition reveals \\emph{what} converges (location properties) versus what remains stable (distributional shape), providing an empirical signature that can be exploited for detection without access to model internals.\nartifacts/_project/paper/related_work.tex:39:Our surface features (TTR and hapax ratio) are classical stylometric measures \\cite{stamatatos_survey,koppel_authorship} that we apply to inference chains, showing monotonic diversity decline across depths without model retraining.\nartifacts/_project/paper/related_work.tex:46:Proactive watermarking \\cite{watermark_llm,synthid_text,aaronson_watermark} embeds identifiable patterns, but watermark strength decays across multi-step chains \\cite{chainwash}, motivating passive post-hoc methods like ours.\nartifacts/_project/paper/appendix_prompt_type.tex:7:Leave-one-prompt-type-out evaluation yields average F1\\,=\\,0.753, confirming that depth signal transfers across prompt types. Feature decay rates differ: continuation shows the strongest drift (16.9\\% per depth step), followed by rewriting (6.1\\%) and elaboration (1.4\\%), consistent with continuation chains applying less semantic constraint on the output.\nartifacts/_project/paper/appendix_qlora.tex:30:A second run with LoRA rank 32 and seed 123 yields 5-class F1\\,=\\,0.587 ($\\pm$0.005) and 3-class F1\\,=\\,0.905 ($\\pm$0.004), confirming stability across hyperparameter and seed variation ($\\Delta < 1$\\,pp on both metrics).\nartifacts/_project/paper/appendix_cross_temp.tex:7:[Omitted long matching line]\nartifacts/_project/paper/appendix_cross_temp.tex:20:\\item \\textbf{Binary robustness}: Binary classification (gen-0/1 vs.\\ gen-2+) is more robust to temperature mismatch (0.900--0.958 across all conditions) than 3-class, suggesting the coarser gen-0 vs.\\ machine boundary is less sensitive to decoding parameters than fine-grained depth discrimination.\nartifacts/_project/paper/appendix_confusion_matrix.tex:17:\\caption{Aggregated 3-class confusion matrix from 6-generator LOGO evaluation ($N=27{,}529$). Each cell shows count and row-normalized percentage. Gen-0 is near-perfectly identified. Gen-1 errors are asymmetric: misclassification as gen-2+ (18.8\\%) is 3$\\times$ more frequent than as gen-0 (6.2\\%), indicating that gen-1 text already carries detectable recursive distortion.}\nartifacts/_project/paper/appendix_downstream.tex:25:Cross-seed variance is below 0.002 across all variants, confirming the robustness of this null result.\nartifacts/_project/paper/appendix_downstream.tex:32:TOST confirms equivalence ($p = 1.1 \\times 10^{-4}$), indicating the two curation strategies yield practically indistinguishable downstream quality within the $\\pm$2\\% margin.\nartifacts/_project/paper/appendix_downstream.tex:35:Comparing the full dataset ($n$\\,=\\,12{,}299, ppl\\,=\\,2.335) against the depth-filtered subset ($n$\\,=\\,3{,}951, ppl\\,=\\,2.387): TOST \\emph{rejects} equivalence (minimum equivalence margin\\,=\\,0.053, exceeding the $\\pm$2\\% bound), confirming that data quantity drives perplexity reduction beyond what depth-aware selection can recover.\nartifacts/_project/paper/appendix_human_edit.tex:23:At 10\\% replacement, binary F1 remains 0.614, well above the 0.50 random baseline, indicating that depth signal survives moderate perturbation.\nartifacts/_project/paper/appendix_human_edit.tex:32:Random word replacement drastically alters per-token context, making entropy features (computed over the full token sequence) extremely sensitive to noise.\nartifacts/_project/paper/appendix_lofo.tex:28:Six of seven features contribute positively to the ensemble, confirming that the 7-feature design is not over-specified.\nartifacts/_project/paper/discussion.tex:12:Three classes represent the practical resolution ceiling: 5-class F1 drops to ${\\approx}$0.50 (Appendix~\\ref{app:finer-depth}), and ordinal-specific methods (CORAL, Frank-Hall) yield no improvement over standard XGBoost (Appendix~\\ref{app:classifier}), suggesting that the gen-1/gen-2+ boundary rather than ordinal structure is the bottleneck.\nartifacts/_project/paper/discussion.tex:13:DDR is distinct from model collapse \\cite{curse_of_recursion,strong_model_collapse}: inference-chain drift occurs with fixed parameters, is fully reversible, and approximately preserves distributional shape, suggesting compression within existing capacity rather than erosion of it.\nartifacts/_project/paper/method.tex:7:[Omitted long matching line]\nartifacts/_project/paper/method.tex:17:We frame depth estimation as an ordinal classification task over three classes rather than binary real-vs-synthetic detection, enabling finer-grained provenance characterization.\nartifacts/_project/paper/method.tex:24:This selection covers parameter scales from 0.6B to 8B and diverse pretraining corpora, enabling evaluation of cross-generator and cross-scale generalization.\nartifacts/_project/paper/method.tex:42:This two-pronged design is validated through leave-one-feature-out analysis (Appendix~\\ref{app:lofo}) and cross-group ablation (\\S\\ref{sec:results-differential}), confirming that both feature groups contribute to depth discrimination.\nartifacts/_project/paper/method.tex:52:    \\item \\textbf{entropy\\_mean}: mean token-level NLL, capturing the average predictability of the text under the reference model;\nartifacts/_project/paper/method.tex:54:    \\item \\textbf{entropy\\_max}: maximum token-level NLL, capturing the most surprising token;\nartifacts/_project/paper/method.tex:55:    \\item \\textbf{entropy\\_min}: minimum token-level NLL, capturing the most predictable token. As generation depth increases, the floor of token-level surprise drops, reflecting the model's increasing confidence on its own outputs.\nartifacts/_project/paper/method.tex:86:Alternative classifiers and ordinal-specific methods (CORAL \\cite{coral_ordinal}, Frank-Hall \\cite{frank_hall_ordinal}) yield comparable performance (Appendix~\\ref{app:classifier}), confirming that discriminative power resides in the features.\nartifacts/_project/paper/limitations.tex:5:This is a deliberate design choice: base models isolate the generation mechanism from instruction-tuning effects, enabling controlled study of recursive distributional drift.\nartifacts/_project/paper/limitations.tex:24:Cross-domain evaluation (Appendix~\\ref{app:domain}) shows that depth signal persists across News, Academic, and Code domains (binary F1 $>$ 0.73 under LOGO at $t{=}1.0$), though a domain $\\times$ temperature interaction exists: certain domain/generator combinations at lower temperature approach chance level (e.g., Academic domain binary F1\\,=\\,0.628 at $t{=}0.7$), suggesting that reference model calibration is critical for cross-domain deployment.\nartifacts/_project/paper/limitations.tex:28:Our default analysis uses fixed decoding parameters (temperature 0.7, nucleus $p{=}0.9$). A sampling ablation (Appendix~\\ref{app:sampling-sensitivity}) shows robustness to moderate variation ($t \\in [0.5, 0.7]$, ${\\leq}0.3$\\,pp) but substantial degradation at $t{=}1.0$ ($-6$\\,pp), indicating that depth fingerprinting assumes standard decoding regimes.\nartifacts/_project/paper/appendix_length.tex:10:Spearman rank correlation between word count and generation depth is weak across all eight generators ($|\\rho| < 0.14$), indicating that depth does not systematically shorten or lengthen text in our corpus.\nartifacts/_project/paper/appendix_length.tex:21:To distinguish this from a sample-size effect, we run a random-subsample control at equal $N$ without length matching: F1\\,=\\,0.767, confirming that the 0.046 drop reflects genuine length deconfounding rather than reduced data.\nartifacts/_project/paper/appendix_error_analysis.tex:10:The monotonic decrease confirms that deeper generations accumulate progressively stronger fingerprints, making the gen-1$\\to$gen-2 transition the hardest to detect.\nartifacts/_project/paper/appendix_error_analysis.tex:13:Table~\\ref{tab:error-by-gen} shows error rates vary substantially across generators, correlating with model scale: larger models (Mistral-7B, Qwen3-8B) produce text closer to gen-1 characteristics, making depth discrimination harder.\nartifacts/_project/paper/appendix_error_analysis.tex:39:Misclassified gen-2+ samples have systematically higher TTR (0.464 vs.\\ 0.302 for correct) and entropy\\_mean (2.26 vs.\\ 1.57), indicating they retain gen-1-like lexical diversity and have not undergone the distributional convergence characteristic of deeper generations.\nartifacts/_project/paper/abstract.tex:3:LLM-generated text increasingly re-enters the web and seeds subsequent generation, producing recursive chains whose outputs progressively diverge from human-written text.\nartifacts/_project/paper/abstract.tex:7:The depth signal degrades substantially under instruction tuning, restricting current applicability to base models.\nartifacts/_project/paper/appendix_classifier.tex:31:Ordinal-specific methods (CORAL \\cite{coral_ordinal}, Frank-Hall \\cite{frank_hall_ordinal}) achieve comparable F1 with overlapping CIs, confirming that 3-class granularity provides insufficient resolution for ranking-aware losses to improve over standard multiclass classification.\nartifacts/_project/paper/appendix_domain.tex:21:All three non-Wikipedia domains achieve binary F1 $>$ 0.73 under leave-one-generator-out evaluation, demonstrating that depth signal is not an artifact of Wikipedia text properties.\nartifacts/_project/paper/appendix_finer_depth.tex:52:The gen-2/gen-3 boundary is the primary failure mode across all methods: these two classes are effectively inseparable with the current feature set, establishing 3-class granularity as the practical ceiling for surface and entropy features.\nartifacts/_project/paper/appendix_finer_depth.tex:53:At the 3-class level, ordinal-specific methods (CORAL ordinal regression, Frank-Hall reduction) similarly fail to improve over multiclass XGBoost (\\S\\ref{sec:results}), confirming that the bottleneck is feature separability across all granularities, not the modeling of label ordinality.\nartifacts/_project/paper/results.tex:16:The higher cross-model performance relative to single-generator LOGO (3-class: 0.809 vs.\\ 0.762) suggests that generator heterogeneity amplifies distributional shifts between depths, making each recursive step more distinct.\nartifacts/_project/paper/results.tex:19:Leave-one-family-out (LOFO) evaluation yields average binary F1\\,=\\,0.686, confirming transfer across architectural families.\nartifacts/_project/paper/results.tex:70:Levene tests reject equal variance for all features ($p < 10^{-10}$), but effect sizes differ markedly: shape-feature CV shift $<$3\\% vs.\\ $>$15\\% for drifting features, supporting ``approximately preserves'' as a practical characterization rather than a strict invariance claim.\nartifacts/_project/paper/results.tex:78:Alternative references (OLMo-2-1B, Qwen3-0.6B) achieve comparable LOGO F1 (spread 0.013; Table~\\ref{tab:cross-ref} in Appendix~\\ref{app:cross-ref}), with consistently negative entropy drift, confirming DDR is a property of recursive generation.\nartifacts/_project/paper/results.tex:82:At $t{=}1.0$, performance degrades by ${\\sim}6$\\,pp as the primary depth signal collapses: entropy mean's Spearman correlation with depth drops from $\\rho = -0.60$ to $\\rho = -0.002$, indicating that high-temperature sampling injects sufficient token-level randomness to mask the systematic location shift that DDR exploits.\nartifacts/_project/paper/results.tex:113:[Omitted long matching line]",
    "numLines": 46
  }
}
```

</details>

---


### Assistant

_source line 18_

<details><summary>Logged reasoning block</summary>

```text
Now I have a comprehensive list of potential -ing participle phrases to review. Let me categorize them into those that need fixing (AI-style dangling participles) and those that are legitimate uses.

Let me go through each match systematically:

**Needs fixing (AI-style -ing participle phrases):**

1. `related_work.tex:26`: "showing progressive information loss" — dangling participle at end
2. `related_work.tex:28`: "enabling the DDR decomposition" — dangling -ing
3. `related_work.tex:33`: "providing an empirical signature" — dangling -ing


4. `related_work.tex:39`: "showing monotonic diversity decline" — dangling -ing
5. `related_work.tex:46`: "motivating passive post-hoc methods like ours" — dangling -ing
6. `appendix_prompt_type.tex:7`: "confirming that depth signal transfers" — -ing phrase
7. `appendix_qlora.tex:30`: "confirming stability across" — -ing phrase
8. `appendix_cross_temp.tex:20`: "suggesting the coarser gen-0 vs.\ machine boundary" — -ing phrase
9. `appendix_confusion_matrix.tex:17`: "indicating that gen-1 text already carries" — -ing phrase
10. `appendix_downstream.tex:25`: "confirming the" — -ing phrase (appears truncated)
11. `appendix_downstream.tex:32`: "indicating the two curation strategies yield" — -ing phrase
12. `appendix_downstream.tex:35`: "confirming that data quantity drives" — -ing phrase
13. `appendix_human_edit.tex:23`: "indicating that depth signal survives" — -ing phrase
14. `appendix_human_edit.tex:32`: "making entropy features ... extremely sensitive" — -ing phrase
15. `appendix_lofo.tex:28`: "confirming that the 7-feature design" — -ing phrase
16. `discussion.tex:12`: "suggesting that the gen-1/gen-2+ boundary" — -ing phrase
17. `discussion.tex:13`: "suggesting compression within existing capacity" — -ing phrase
18. `method.tex` — continuing through the document

I'm working through the manuscript systematically, identifying dangling participles and -ing phrases that need revision across multiple sections. Continuing through the remaining instances where gerunds appear in the abstract and appendices, capturing the pattern of how these constructions frame methodological contributions and findings throughout the paper. I'm continuing through the dangling participle phrases in the LaTeX files, and this one at `results.tex:82` with "indicating that high-temperature sampling injects" follows the same pattern as the others I've been cataloging.

Looking back at my notes, I need to distinguish between legitimate uses and the AI-style commentary phrases. The key distinction is whether the -ing phrase is a loose end-of-sentence modifier versus a proper grammatical construction. For the method.tex feature descriptions like "capturing..." and "measuring...", these are actually standard list-item appositives that describe what each feature does, so they're acceptable even though they technically have dangling participle structure. But the ones ending sentences with "indicating," "suggesting," "demonstrating" — those are the problematic AI patterns I should flag. I'm reviewing the feature definitions in the list and noticing that some use the ", capturing..." pattern the user flagged. These are appositives that clarify what each feature measures, which is pretty standard in academic writing, so I think they're acceptable as-is. Let me focus on the more problematic cases first and come back to these if needed.

The user's instructions are clear about which -ing patterns to fix: demonstrating, suggesting, highlighting, enabling, indicating, achieving, and similar constructions. I'm building a comprehensive list of these key verbs so I can systematically identify and rewrite them throughout the document.

Now I need to tackle this methodically. There are quite a few instances scattered across multiple files, so I'll prioritize by file and work through the ones with the most occurrences first—method.tex has the heaviest concentration, followed by related_work.tex. Let me start reading through each file to understand the full context before making edits. Now I'm seeing the scope of this task — there are formatting issues scattered across many files. Rather than trying to parallelize this, I should work through the main paper sections first, then tackle the appendices systematically. Let me start reading and editing the core files in order.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "1411c97e-459b-47c1-85a0-d580ab6a339f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0195r3LUfohzwasZKKFc5fm2",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8831,
      "cache_read_input_tokens": 28205,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8831
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

_source line 19_

Found many candidates. Let me now read the affected files to confirm context and make edits. I'll start with the main paper files.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "e622f1db-9990-4123-860c-be53d920b695",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0195r3LUfohzwasZKKFc5fm2",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8831,
      "cache_read_input_tokens": 28205,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8831
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

_source line 20_

<details open><summary>🔧 Tool call — Read · `toolu_01VJKPschMMf4x7r8tRY1fHp`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "7df31f13-6773-4173-acf9-946b22d50fb2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0195r3LUfohzwasZKKFc5fm2",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8831,
      "cache_read_input_tokens": 28205,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8831
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

_source line 21 · 2026-05-17T19:52:45.094Z_

<details><summary>↩ Tool result · `toolu_01VJKPschMMf4x7r8tRY1fHp`</summary>

```text
1	% Abstract — Depth Fingerprinting of Recursive LLM Generation Chains
2	\begin{abstract}
3	LLM-generated text increasingly re-enters the web and seeds subsequent generation, producing recursive chains whose outputs progressively diverge from human-written text.
4	We ask whether this drift is structured enough to classify how many generation steps a text has undergone, framing this as \emph{generation depth classification} (gen-0\,/\,gen-1\,/\,gen-2+ rather than binary real-vs-synthetic).
5	Studying eight base (pretrained) models from five families (0.6B--8B parameters), we identify a \emph{differential depth response} (DDR): central-tendency features (mean entropy, lexical diversity) drift monotonically with generation depth, while shape features (entropy max, vocabulary tail slope) remain near-stationary, consistent with a location shift in the token-level NLL distribution that approximately preserves distributional shape.
6	A 7-feature ensemble achieves leak-free binary F1\,=\,0.694 under eight-generator leave-one-generator-out (LOGO) evaluation and 0.764 on cross-model chains (five-generator subset), using a single 410M-parameter reference model.
7	The depth signal degrades substantially under instruction tuning, restricting current applicability to base models.
8	\end{abstract}
9	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "1b984ac5-a45e-44e6-9870-bad1400d7ab4",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/abstract.tex",
      "content": "% Abstract — Depth Fingerprinting of Recursive LLM Generation Chains\n\\begin{abstract}\nLLM-generated text increasingly re-enters the web and seeds subsequent generation, producing recursive chains whose outputs progressively diverge from human-written text.\nWe ask whether this drift is structured enough to classify how many generation steps a text has undergone, framing this as \\emph{generation depth classification} (gen-0\\,/\\,gen-1\\,/\\,gen-2+ rather than binary real-vs-synthetic).\nStudying eight base (pretrained) models from five families (0.6B--8B parameters), we identify a \\emph{differential depth response} (DDR): central-tendency features (mean entropy, lexical diversity) drift monotonically with generation depth, while shape features (entropy max, vocabulary tail slope) remain near-stationary, consistent with a location shift in the token-level NLL distribution that approximately preserves distributional shape.\nA 7-feature ensemble achieves leak-free binary F1\\,=\\,0.694 under eight-generator leave-one-generator-out (LOGO) evaluation and 0.764 on cross-model chains (five-generator subset), using a single 410M-parameter reference model.\nThe depth signal degrades substantially under instruction tuning, restricting current applicability to base models.\n\\end{abstract}\n",
      "numLines": 9,
      "startLine": 1,
      "totalLines": 9
    }
  }
}
```

</details>

---


### Tool call

_source line 22_

<details open><summary>🔧 Tool call — Read · `toolu_01G63yfUiriTZFXUGu4B2Cw1`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "58217db4-2c7b-4f09-8aab-3b52331cc4be",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0195r3LUfohzwasZKKFc5fm2",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8831,
      "cache_read_input_tokens": 28205,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8831
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

_source line 23 · 2026-05-17T19:52:45.563Z_

<details><summary>↩ Tool result · `toolu_01G63yfUiriTZFXUGu4B2Cw1`</summary>

```text
1	\section{Introduction}
2	\label{sec:introduction}
3	
4	LLM-generated text increasingly re-enters the web and seeds subsequent generation \cite{dolma,fineweb}, with estimates suggesting that 7--17\% of recent scientific papers and peer reviews contain substantial LLM-modified content \cite{mapping_llm_science,monitoring_ai_review}.
5	The result is recursive generation chains whose outputs progressively diverge from human-written text.
6	Understanding how distributional features evolve across recursive generation depths is a fundamental question for characterizing recursive generation dynamics, yet existing methods \cite{fast_detectgpt,binoculars,ld_score,detectgpt} provide only binary real-vs-synthetic decisions, conflating qualitatively different material: a first-generation continuation retains much of the source distribution's lexical properties, while deeper recursive text exhibits measurably reduced vocabulary diversity and compressed perplexity.
7	
8	We formulate \emph{generation depth classification}, classifying text by generation depth (gen-0\,/\,gen-1\,/\,gen-2+) rather than a binary label, and refer to the overall framework as \emph{depth fingerprinting}.
9	No existing method addresses this task in non-paraphrastic continuation chains.
10	
11	The key finding is a \emph{differential depth response} (DDR): when we measure how eight base-model generators from five families (Pythia, OLMo, Qwen, Llama, Mistral; 0.6B--8B parameters) transform text across recursive depths, central-tendency and diversity features (reference-model mean entropy, type-token ratio, hapax ratio) drift monotonically, while shape features (entropy max, tail decay) remain near-stationary.
12	This pattern is consistent with recursive generation inducing a location shift in the token-level NLL distribution while approximately preserving its shape: the softmax architecture and fixed sampling parameters constrain distributional shape under standard decoding regimes, while each successive generation compresses the location toward the model's preferred output distribution.
13	We restrict to base (pretrained) models as a deliberate design choice, since instruction-tuning introduces confounds (length regulation, format constraints, safety-driven shaping) that obscure this intrinsic mechanism; preliminary experiments confirm substantially degraded depth signal under instruction tuning (\S\ref{sec:discussion}).
14	
15	The combination of drifting and stationary features yields a 7-feature ensemble that, under eight-generator leave-one-generator-out (LOGO) evaluation, achieves leak-free binary F1\,=\,0.694 and 0.764 on cross-model chains (five-generator subset), using a single 410M-parameter reference model.
16	Multi-detector ensembles achieve moderately higher F1 at 2.4$\times$ the computational cost (\S\ref{sec:results-baselines}).
17	The signal is prompt-type dependent: continuation chains show stronger drift than elaboration or rewriting (\S\ref{sec:discussion}).
18	
19	Our empirical contributions are twofold:
20	\begin{enumerate}[nosep,leftmargin=*]
21	    \item We formulate generation depth classification, moving beyond binary real-vs-synthetic detection to classify text as gen-0\,/\,gen-1\,/\,gen-2+, and construct an evaluation suite of 37K texts from eight base-model generators spanning five families (0.6B--8B parameters).
22	    \item We characterize a \emph{differential depth response} (DDR): central-tendency features show monotonic drift under recursive generation ($|\rho| > 0.60$) while distributional shape remains approximately stationary ($|\rho| < 0.10$). A 7-feature ensemble exploiting this structure achieves leak-free binary F1\,=\,0.694 under eight-generator LOGO evaluation with a single 410M reference model.
23	\end{enumerate}
24	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "6256a078-7dd1-40c7-88f1-4d5f3e740b8e",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/introduction.tex",
      "content": "\\section{Introduction}\n\\label{sec:introduction}\n\nLLM-generated text increasingly re-enters the web and seeds subsequent generation \\cite{dolma,fineweb}, with estimates suggesting that 7--17\\% of recent scientific papers and peer reviews contain substantial LLM-modified content \\cite{mapping_llm_science,monitoring_ai_review}.\nThe result is recursive generation chains whose outputs progressively diverge from human-written text.\nUnderstanding how distributional features evolve across recursive generation depths is a fundamental question for characterizing recursive generation dynamics, yet existing methods \\cite{fast_detectgpt,binoculars,ld_score,detectgpt} provide only binary real-vs-synthetic decisions, conflating qualitatively different material: a first-generation continuation retains much of the source distribution's lexical properties, while deeper recursive text exhibits measurably reduced vocabulary diversity and compressed perplexity.\n\nWe formulate \\emph{generation depth classification}, classifying text by generation depth (gen-0\\,/\\,gen-1\\,/\\,gen-2+) rather than a binary label, and refer to the overall framework as \\emph{depth fingerprinting}.\nNo existing method addresses this task in non-paraphrastic continuation chains.\n\nThe key finding is a \\emph{differential depth response} (DDR): when we measure how eight base-model generators from five families (Pythia, OLMo, Qwen, Llama, Mistral; 0.6B--8B parameters) transform text across recursive depths, central-tendency and diversity features (reference-model mean entropy, type-token ratio, hapax ratio) drift monotonically, while shape features (entropy max, tail decay) remain near-stationary.\nThis pattern is consistent with recursive generation inducing a location shift in the token-level NLL distribution while approximately preserving its shape: the softmax architecture and fixed sampling parameters constrain distributional shape under standard decoding regimes, while each successive generation compresses the location toward the model's preferred output distribution.\nWe restrict to base (pretrained) models as a deliberate design choice, since instruction-tuning introduces confounds (length regulation, format constraints, safety-driven shaping) that obscure this intrinsic mechanism; preliminary experiments confirm substantially degraded depth signal under instruction tuning (\\S\\ref{sec:discussion}).\n\nThe combination of drifting and stationary features yields a 7-feature ensemble that, under eight-generator leave-one-generator-out (LOGO) evaluation, achieves leak-free binary F1\\,=\\,0.694 and 0.764 on cross-model chains (five-generator subset), using a single 410M-parameter reference model.\nMulti-detector ensembles achieve moderately higher F1 at 2.4$\\times$ the computational cost (\\S\\ref{sec:results-baselines}).\nThe signal is prompt-type dependent: continuation chains show stronger drift than elaboration or rewriting (\\S\\ref{sec:discussion}).\n\nOur empirical contributions are twofold:\n\\begin{enumerate}[nosep,leftmargin=*]\n    \\item We formulate generation depth classification, moving beyond binary real-vs-synthetic detection to classify text as gen-0\\,/\\,gen-1\\,/\\,gen-2+, and construct an evaluation suite of 37K texts from eight base-model generators spanning five families (0.6B--8B parameters).\n    \\item We characterize a \\emph{differential depth response} (DDR): central-tendency features show monotonic drift under recursive generation ($|\\rho| > 0.60$) while distributional shape remains approximately stationary ($|\\rho| < 0.10$). A 7-feature ensemble exploiting this structure achieves leak-free binary F1\\,=\\,0.694 under eight-generator LOGO evaluation with a single 410M reference model.\n\\end{enumerate}\n",
      "numLines": 24,
      "startLine": 1,
      "totalLines": 24
    }
  }
}
```

</details>

---


### Tool call

_source line 24_

<details open><summary>🔧 Tool call — Read · `toolu_01DKaozKDHDQ1QH6XpSCa2ND`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "9befe9f1-7e18-440b-8ad1-3cc11ab50a0f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0195r3LUfohzwasZKKFc5fm2",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8831,
      "cache_read_input_tokens": 28205,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8831
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

_source line 25 · 2026-05-17T19:52:46.021Z_

<details><summary>↩ Tool result · `toolu_01DKaozKDHDQ1QH6XpSCa2ND`</summary>

```text
1	\section{Method}
2	\label{sec:method}
3	
4	\begin{figure*}[t]
5	\centering
6	\includegraphics[width=\textwidth]{fig2_framework.pdf}
7	\caption{Depth fingerprinting framework. (a)~Recursive generation chains are constructed by iteratively feeding text through a generator $G$. (b)~Seven features are extracted per text: five NLL statistics from a Pythia-410M reference model and two surface diversity measures. Horizontal bars show Spearman $\rho$ with generation depth, revealing differential depth response: drifting features ($|\rho| > 0.6$) capture the monotonic location shift, while stationary features ($|\rho| < 0.1$) provide a stable baseline. (c)~An XGBoost classifier trained under Leave-One-Generator-Out (LOGO) cross-validation predicts depth class (gen-0\,/\,gen-1\,/\,gen-2+).}
8	\label{fig:framework}
9	\end{figure*}
10	
11	\subsection{Task Formulation}
12	\label{sec:task}
13	
14	Given a text $x$, the goal is to predict its \emph{generation depth} $d \in \{0, 1, 2{+}\}$, where $d{=}0$ denotes human-written text, $d{=}1$ denotes first-generation LLM output conditioned on human text, and $d{=}2{+}$ denotes text produced by recursively conditioning an LLM on its own prior output at least twice.
15	Formally, let $\mathcal{C}_0$ be a reference corpus of human-written text.
16	A generation chain of depth $k$ is defined recursively: $x^{(0)} \sim \mathcal{C}_0$, and $x^{(k)} = G(x^{(k-1)})$ for $k \geq 1$, where $G$ denotes stochastic LLM generation conditioned on its input.
17	We frame depth estimation as an ordinal classification task over three classes rather than binary real-vs-synthetic detection, enabling finer-grained provenance characterization.
18	Depths beyond 2 are merged into a single $2{+}$ class, consistent with monotonic feature convergence that compresses inter-class margins beyond depth 2 (\S\ref{sec:results-differential}).
19	
20	\subsection{Generation Chain Construction}
21	\label{sec:generation}
22	
23	We construct generation chains using eight generators spanning five model families: \textbf{Pythia} (2.8B, 1B) \cite{pythia}, \textbf{OLMo} (OLMo-2-1B) \cite{olmo}, \textbf{Qwen} (Qwen3-1.7B, Qwen3-0.6B, Qwen3-8B-Base) \cite{qwen3}, \textbf{Llama} (Llama-3.2-3B) \cite{llama3}, and \textbf{Mistral} (Mistral-7B-v0.3) \cite{mistral7b}.
24	This selection covers parameter scales from 0.6B to 8B and diverse pretraining corpora, enabling evaluation of cross-generator and cross-scale generalization.
25	
26	For each generator, we sample approximately 1{,}000 seed passages from English Wikipedia as $\mathcal{C}_0$.
27	The same pool of seed passages serves as gen-0 for all generators.
28	We use shared seeds across generators to ensure that cross-generator comparisons control for input content, isolating the effect of the generation model from source text variation.
29	In LOGO evaluation, gen-0 samples from the held-out generator's chains also appear (with the same text) in the training generators' chains, creating a potential train--test overlap for the gen-0 class.
30	We address this with a supplementary binary evaluation excluding gen-0 entirely (\S\ref{sec:results-baselines}).
31	Each seed is iteratively fed through the generator to produce a chain of depth 4 (i.e., gen-0 through gen-4), using the prompt ``\texttt{Continue the following text: \{text\}}''.
32	All generation uses temperature $\tau{=}0.7$, nucleus sampling with $p{=}0.9$, and maximum length of 256 new tokens.
33	The theoretical yield is $8 \times {\sim}1{,}000 \times 5 = 39{,}815$ texts; after removing 2{,}746 chain breaks (empty or degenerate outputs at intermediate depths that prevented deeper generation) and 11 passages too short for feature extraction, 37{,}058 texts remain (Appendix~\ref{app:dataset-stats}).
34	For classification, depths 2--4 are collapsed into the $2{+}$ class.
35	
36	\subsection{Feature Extraction}
37	\label{sec:features}
38	
39	The seven features are motivated by two complementary views of distributional drift.
40	Reference-model features capture how the text's token-level surprise distribution shifts relative to a fixed model; surface features capture how lexical diversity contracts under recursive generation.
41	Together, they span both the generative mechanism (what the model produces) and the surface manifestation (how the vocabulary changes); Figure~\ref{fig:framework} provides an overview.
42	This two-pronged design is validated through leave-one-feature-out analysis (Appendix~\ref{app:lofo}) and cross-group ablation (\S\ref{sec:results-differential}), confirming that both feature groups contribute to depth discrimination.
43	
44	We extract seven distributional features per text, organized into two groups based on what they measure rather than how they are computed.
45	
46	\paragraph{Reference-model features.}
47	A held-out reference model (Pythia-410M, chosen to be smaller than all generators) computes per-token negative log-likelihood (NLL) for each text.
48	We use ``entropy'' as shorthand for token-level NLL throughout, following convention in prior detection work; these are point-wise NLL values, not Shannon entropy of the full distribution.
49	Although Pythia-410M shares the GPT-NeoX architecture with two of the eight generators, cross-family reference model experiments (\S\ref{sec:results-differential}) confirm that depth features are not reference-specific (LOGO F1 varies by $\leq$0.013 across Pythia, OLMo, and Qwen references).
50	From the resulting NLL sequence, we extract five statistics:
51	\begin{itemize}[nosep,leftmargin=*]
52	    \item \textbf{entropy\_mean}: mean token-level NLL, capturing the average predictability of the text under the reference model;
53	    \item \textbf{entropy\_std}: standard deviation of token-level NLL, measuring the spread of per-token surprise;
54	    \item \textbf{entropy\_max}: maximum token-level NLL, capturing the most surprising token;
55	    \item \textbf{entropy\_min}: minimum token-level NLL, capturing the most predictable token. As generation depth increases, the floor of token-level surprise drops, reflecting the model's increasing confidence on its own outputs.
56	    Retained because removing it does not improve performance (LOFO $\Delta$F1\,=\,+0.01\,pp, within bootstrap noise) and it completes the four-number NLL summary (mean, std, max, min), ensuring the classifier has access to the full marginal distribution shape;
57	    \item \textbf{tail\_decay}: slope of the vocabulary-level averaged log-probability distribution in the mid-rank region (ranks 100--1000).
58	    For each text, we compute the mean log-probability of each vocabulary token across all positions under the reference model, sort tokens in descending order of mean log-probability, and fit a linear regression to ranks 100--1000.
59	    The slope captures how steeply the reference model's probability mass decays beyond high-probability tokens, characterizing the shape of the distribution tail.
60	    We select ranks 100--1000 because high-frequency tokens (ranks $<$ 100) exhibit minimal discriminative variance across depths, while ranks beyond 1000 are sparsely populated and noisy.
61	\end{itemize}
62	
63	\paragraph{Surface features.}
64	Two features capture lexical diversity without requiring a reference model:
65	\begin{itemize}[nosep,leftmargin=*]
66	    \item \textbf{TTR}: type-token ratio (number of unique word types divided by total tokens);
67	    \item \textbf{hapax\_ratio}: proportion of words appearing exactly once (\emph{hapax legomena}).
68	\end{itemize}
69	
70	\paragraph{Feature complementarity.}
71	The grouping reflects an empirical pattern we term \emph{differential depth response}: central-tendency and diversity features (entropy\_mean, TTR, hapax\_ratio) show substantial monotonic drift with generation depth ($|\rho| = 0.60$--$0.63$); entropy\_min and entropy\_std show moderate drift ($|\rho| = 0.17$--$0.41$); and shape features (entropy\_max, tail\_decay) remain near-stationary ($|\rho| < 0.10$).
72	This differential behavior, consistent with recursive generation shifting the location of the NLL distribution while approximately preserving distributional shape, motivates combining both feature types.
73	As shown in \S\ref{sec:results}, the full 7-feature set significantly outperforms either group alone.
74	
75	\subsection{Evaluation Protocol}
76	\label{sec:evaluation}
77	
78	\paragraph{Cross-validation.}
79	To evaluate generalization to unseen generators, we use \textbf{Leave-One-Generator-Out (LOGO)} cross-validation over all eight generators; \textbf{Leave-One-Family-Out (LOFO)} holds out entire model families.
80	Cross-model chains use the original five-generator subset (Pythia-2.8B/1B, OLMo-2-1B, Qwen3-1.7B/0.6B); Llama and Mistral were added subsequently for single-generator LOGO only.
81	Some appendix analyses predate this expansion and use six generators (the original five plus Qwen3-8B); each table notes its generator subset.
82	
83	\paragraph{Classifier.}
84	We use XGBoost \cite{xgboost} throughout ($n\_\text{estimators}{=}200$, $\max\_\text{depth}{=}6$, learning rate $0.1$), with identical hyperparameters across all methods in Table~\ref{tab:baselines}.
85	LOGO F1 is stable across random seeds (std\,$<$\,0.001 over 5 seeds).
86	Alternative classifiers and ordinal-specific methods (CORAL \cite{coral_ordinal}, Frank-Hall \cite{frank_hall_ordinal}) yield comparable performance (Appendix~\ref{app:classifier}), confirming that discriminative power resides in the features.
87	
88	\paragraph{Metrics and statistical testing.}
89	The primary metric is \textbf{macro-averaged F1} over the three depth classes.
90	We report 95\% confidence intervals via percentile bootstrap ($n{=}1{,}000$), McNemar tests for pairwise comparisons, and paired bootstrap for baseline comparisons.
91	All $p$-values are two-sided; Bonferroni correction is applied within each family of simultaneous tests: the 21 distributional comparisons (7 features $\times$ 3 depth-group pairs, \S\ref{sec:results-differential}) and the 4 pairwise baseline comparisons (\S\ref{sec:results-baselines}).
92	Feature--depth correlations (\S\ref{sec:results-differential}) use class-balanced subsamples to control for depth-class imbalance.
93	
94	\paragraph{Baselines.}
95	We compare the 7-feature ensemble against four single-score detection methods repurposed as depth predictors: Avg-LogProb, FastDetectGPT \cite{fast_detectgpt}, Binoculars \cite{binoculars}, and LD-Score \cite{ld_score}.
96	Each baseline score is used as a univariate feature in the same XGBoost framework under LOGO cross-validation, ensuring a controlled comparison.
97	
98	\paragraph{Length confound control.}
99	Since TTR and hapax\_ratio are mechanically length-dependent, we verify depth signal is not a length artifact via length-matched subsampling that equalizes length distributions across depth classes (\S\ref{sec:results-classification}; Appendix~\ref{app:length}).
100	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "f100c479-c784-4176-a9a8-2510f39d118d",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex",
      "content": "\\section{Method}\n\\label{sec:method}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{fig2_framework.pdf}\n\\caption{Depth fingerprinting framework. (a)~Recursive generation chains are constructed by iteratively feeding text through a generator $G$. (b)~Seven features are extracted per text: five NLL statistics from a Pythia-410M reference model and two surface diversity measures. Horizontal bars show Spearman $\\rho$ with generation depth, revealing differential depth response: drifting features ($|\\rho| > 0.6$) capture the monotonic location shift, while stationary features ($|\\rho| < 0.1$) provide a stable baseline. (c)~An XGBoost classifier trained under Leave-One-Generator-Out (LOGO) cross-validation predicts depth class (gen-0\\,/\\,gen-1\\,/\\,gen-2+).}\n\\label{fig:framework}\n\\end{figure*}\n\n\\subsection{Task Formulation}\n\\label{sec:task}\n\nGiven a text $x$, the goal is to predict its \\emph{generation depth} $d \\in \\{0, 1, 2{+}\\}$, where $d{=}0$ denotes human-written text, $d{=}1$ denotes first-generation LLM output conditioned on human text, and $d{=}2{+}$ denotes text produced by recursively conditioning an LLM on its own prior output at least twice.\nFormally, let $\\mathcal{C}_0$ be a reference corpus of human-written text.\nA generation chain of depth $k$ is defined recursively: $x^{(0)} \\sim \\mathcal{C}_0$, and $x^{(k)} = G(x^{(k-1)})$ for $k \\geq 1$, where $G$ denotes stochastic LLM generation conditioned on its input.\nWe frame depth estimation as an ordinal classification task over three classes rather than binary real-vs-synthetic detection, enabling finer-grained provenance characterization.\nDepths beyond 2 are merged into a single $2{+}$ class, consistent with monotonic feature convergence that compresses inter-class margins beyond depth 2 (\\S\\ref{sec:results-differential}).\n\n\\subsection{Generation Chain Construction}\n\\label{sec:generation}\n\nWe construct generation chains using eight generators spanning five model families: \\textbf{Pythia} (2.8B, 1B) \\cite{pythia}, \\textbf{OLMo} (OLMo-2-1B) \\cite{olmo}, \\textbf{Qwen} (Qwen3-1.7B, Qwen3-0.6B, Qwen3-8B-Base) \\cite{qwen3}, \\textbf{Llama} (Llama-3.2-3B) \\cite{llama3}, and \\textbf{Mistral} (Mistral-7B-v0.3) \\cite{mistral7b}.\nThis selection covers parameter scales from 0.6B to 8B and diverse pretraining corpora, enabling evaluation of cross-generator and cross-scale generalization.\n\nFor each generator, we sample approximately 1{,}000 seed passages from English Wikipedia as $\\mathcal{C}_0$.\nThe same pool of seed passages serves as gen-0 for all generators.\nWe use shared seeds across generators to ensure that cross-generator comparisons control for input content, isolating the effect of the generation model from source text variation.\nIn LOGO evaluation, gen-0 samples from the held-out generator's chains also appear (with the same text) in the training generators' chains, creating a potential train--test overlap for the gen-0 class.\nWe address this with a supplementary binary evaluation excluding gen-0 entirely (\\S\\ref{sec:results-baselines}).\nEach seed is iteratively fed through the generator to produce a chain of depth 4 (i.e., gen-0 through gen-4), using the prompt ``\\texttt{Continue the following text: \\{text\\}}''.\nAll generation uses temperature $\\tau{=}0.7$, nucleus sampling with $p{=}0.9$, and maximum length of 256 new tokens.\nThe theoretical yield is $8 \\times {\\sim}1{,}000 \\times 5 = 39{,}815$ texts; after removing 2{,}746 chain breaks (empty or degenerate outputs at intermediate depths that prevented deeper generation) and 11 passages too short for feature extraction, 37{,}058 texts remain (Appendix~\\ref{app:dataset-stats}).\nFor classification, depths 2--4 are collapsed into the $2{+}$ class.\n\n\\subsection{Feature Extraction}\n\\label{sec:features}\n\nThe seven features are motivated by two complementary views of distributional drift.\nReference-model features capture how the text's token-level surprise distribution shifts relative to a fixed model; surface features capture how lexical diversity contracts under recursive generation.\nTogether, they span both the generative mechanism (what the model produces) and the surface manifestation (how the vocabulary changes); Figure~\\ref{fig:framework} provides an overview.\nThis two-pronged design is validated through leave-one-feature-out analysis (Appendix~\\ref{app:lofo}) and cross-group ablation (\\S\\ref{sec:results-differential}), confirming that both feature groups contribute to depth discrimination.\n\nWe extract seven distributional features per text, organized into two groups based on what they measure rather than how they are computed.\n\n\\paragraph{Reference-model features.}\nA held-out reference model (Pythia-410M, chosen to be smaller than all generators) computes per-token negative log-likelihood (NLL) for each text.\nWe use ``entropy'' as shorthand for token-level NLL throughout, following convention in prior detection work; these are point-wise NLL values, not Shannon entropy of the full distribution.\nAlthough Pythia-410M shares the GPT-NeoX architecture with two of the eight generators, cross-family reference model experiments (\\S\\ref{sec:results-differential}) confirm that depth features are not reference-specific (LOGO F1 varies by $\\leq$0.013 across Pythia, OLMo, and Qwen references).\nFrom the resulting NLL sequence, we extract five statistics:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{entropy\\_mean}: mean token-level NLL, capturing the average predictability of the text under the reference model;\n    \\item \\textbf{entropy\\_std}: standard deviation of token-level NLL, measuring the spread of per-token surprise;\n    \\item \\textbf{entropy\\_max}: maximum token-level NLL, capturing the most surprising token;\n    \\item \\textbf{entropy\\_min}: minimum token-level NLL, capturing the most predictable token. As generation depth increases, the floor of token-level surprise drops, reflecting the model's increasing confidence on its own outputs.\n    Retained because removing it does not improve performance (LOFO $\\Delta$F1\\,=\\,+0.01\\,pp, within bootstrap noise) and it completes the four-number NLL summary (mean, std, max, min), ensuring the classifier has access to the full marginal distribution shape;\n    \\item \\textbf{tail\\_decay}: slope of the vocabulary-level averaged log-probability distribution in the mid-rank region (ranks 100--1000).\n    For each text, we compute the mean log-probability of each vocabulary token across all positions under the reference model, sort tokens in descending order of mean log-probability, and fit a linear regression to ranks 100--1000.\n    The slope captures how steeply the reference model's probability mass decays beyond high-probability tokens, characterizing the shape of the distribution tail.\n    We select ranks 100--1000 because high-frequency tokens (ranks $<$ 100) exhibit minimal discriminative variance across depths, while ranks beyond 1000 are sparsely populated and noisy.\n\\end{itemize}\n\n\\paragraph{Surface features.}\nTwo features capture lexical diversity without requiring a reference model:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{TTR}: type-token ratio (number of unique word types divided by total tokens);\n    \\item \\textbf{hapax\\_ratio}: proportion of words appearing exactly once (\\emph{hapax legomena}).\n\\end{itemize}\n\n\\paragraph{Feature complementarity.}\nThe grouping reflects an empirical pattern we term \\emph{differential depth response}: central-tendency and diversity features (entropy\\_mean, TTR, hapax\\_ratio) show substantial monotonic drift with generation depth ($|\\rho| = 0.60$--$0.63$); entropy\\_min and entropy\\_std show moderate drift ($|\\rho| = 0.17$--$0.41$); and shape features (entropy\\_max, tail\\_decay) remain near-stationary ($|\\rho| < 0.10$).\nThis differential behavior, consistent with recursive generation shifting the location of the NLL distribution while approximately preserving distributional shape, motivates combining both feature types.\nAs shown in \\S\\ref{sec:results}, the full 7-feature set significantly outperforms either group alone.\n\n\\subsection{Evaluation Protocol}\n\\label{sec:evaluation}\n\n\\paragraph{Cross-validation.}\nTo evaluate generalization to unseen generators, we use \\textbf{Leave-One-Generator-Out (LOGO)} cross-validation over all eight generators; \\textbf{Leave-One-Family-Out (LOFO)} holds out entire model families.\nCross-model chains use the original five-generator subset (Pythia-2.8B/1B, OLMo-2-1B, Qwen3-1.7B/0.6B); Llama and Mistral were added subsequently for single-generator LOGO only.\nSome appendix analyses predate this expansion and use six generators (the original five plus Qwen3-8B); each table notes its generator subset.\n\n\\paragraph{Classifier.}\nWe use XGBoost \\cite{xgboost} throughout ($n\\_\\text{estimators}{=}200$, $\\max\\_\\text{depth}{=}6$, learning rate $0.1$), with identical hyperparameters across all methods in Table~\\ref{tab:baselines}.\nLOGO F1 is stable across random seeds (std\\,$<$\\,0.001 over 5 seeds).\nAlternative classifiers and ordinal-specific methods (CORAL \\cite{coral_ordinal}, Frank-Hall \\cite{frank_hall_ordinal}) yield comparable performance (Appendix~\\ref{app:classifier}), confirming that discriminative power resides in the features.\n\n\\paragraph{Metrics and statistical testing.}\nThe primary metric is \\textbf{macro-averaged F1} over the three depth classes.\nWe report 95\\% confidence intervals via percentile bootstrap ($n{=}1{,}000$), McNemar tests for pairwise comparisons, and paired bootstrap for baseline comparisons.\nAll $p$-values are two-sided; Bonferroni correction is applied within each family of simultaneous tests: the 21 distributional comparisons (7 features $\\times$ 3 depth-group pairs, \\S\\ref{sec:results-differential}) and the 4 pairwise baseline comparisons (\\S\\ref{sec:results-baselines}).\nFeature--depth correlations (\\S\\ref{sec:results-differential}) use class-balanced subsamples to control for depth-class imbalance.\n\n\\paragraph{Baselines.}\nWe compare the 7-feature ensemble against four single-score detection methods repurposed as depth predictors: Avg-LogProb, FastDetectGPT \\cite{fast_detectgpt}, Binoculars \\cite{binoculars}, and LD-Score \\cite{ld_score}.\nEach baseline score is used as a univariate feature in the same XGBoost framework under LOGO cross-validation, ensuring a controlled comparison.\n\n\\paragraph{Length confound control.}\nSince TTR and hapax\\_ratio are mechanically length-dependent, we verify depth signal is not a length artifact via length-matched subsampling that equalizes length distributions across depth classes (\\S\\ref{sec:results-classification}; Appendix~\\ref{app:length}).\n",
      "numLines": 100,
      "startLine": 1,
      "totalLines": 100
    }
  }
}
```

</details>

---


### Tool call

_source line 26_

<details open><summary>🔧 Tool call — Read · `toolu_01FKtnMxvVVehUyopnRv9Npz`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "df66921e-3f3a-4a82-ab31-c4424d5aacda",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0195r3LUfohzwasZKKFc5fm2",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8831,
      "cache_read_input_tokens": 28205,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8831
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

_source line 27 · 2026-05-17T19:52:46.561Z_

<details><summary>↩ Tool result · `toolu_01FKtnMxvVVehUyopnRv9Npz`</summary>

```text
1	\section{Results}
2	\label{sec:results}
3	
4	\subsection{Depth Classification Performance}
5	\label{sec:results-classification}
6	
7	The 7-feature ensemble achieves 3-class LOGO F1\,=\,0.762 (95\% CI [0.758, 0.766]; $N$\,=\,37{,}058) across eight generators from five families (Table~\ref{tab:logo-results}).
8	Because gen-0 seeds are shared across generators (\S\ref{sec:generation}), gen-0 classification is near-perfect (per-class F1\,$\approx$\,0.94) and the 3-class metric is inflated by this overlap.
9	We therefore adopt leak-free binary F1 (gen-1 vs.\ gen-2+)\,=\,0.694, CI [0.688, 0.700], as the primary metric throughout; it excludes gen-0 entirely and is unaffected by seed sharing.
10	Per-generator binary F1 ranges from 0.633 (Mistral-7B) to 0.724 (Pythia-2.8B); the primary difficulty is distinguishing gen-1 from gen-2+ (Appendix~\ref{app:confusion}).
11	Larger generators show moderate degradation (Qwen3-8B: 0.692, Mistral-7B: 0.633) relative to the 0.694 average.
12	The Pythia-1B/2.8B crossover between three-class and binary scores (0.806 vs.\ 0.798 and 0.718 vs.\ 0.724, respectively) reflects differences in gen-0 classification accuracy rather than in depth discrimination per se.
13	
14	\paragraph{Cross-model generalization.}
15	Cross-model chains (randomly selected generator per step) yield 3-class F1\,=\,0.809 and binary F1\,=\,0.764 under 5-fold CV,\footnote{Cross-model chains use the original five-generator subset (Pythia, OLMo, Qwen); Llama and Mistral were added later for single-generator evaluation.} confirming that depth signal persists when text passes through heterogeneous generators.
16	The higher cross-model performance relative to single-generator LOGO (3-class: 0.809 vs.\ 0.762) suggests that generator heterogeneity amplifies distributional shifts between depths, making each recursive step more distinct.
17	Under class balancing, macro F1 reaches 0.831 (per-class breakdown in Appendix~\ref{app:cross-model-detail}).
18	
19	Leave-one-family-out (LOFO) evaluation yields average binary F1\,=\,0.686, confirming transfer across architectural families.
20	A scale effect emerges: Pythia generators achieve the highest binary F1 (0.718--0.724), while larger models show degradation (Mistral-7B: 0.633), consistent with higher-capacity models compressing the feature margins DDR exploits.
21	The signal generalizes across text domains with variation (Appendix~\ref{app:domain}).
22	
23	\paragraph{Length confound control.}
24	Length-matched subsampling yields binary F1\,=\,0.724 (vs.\ 0.770 unmatched); a random-subsample control confirms the drop reflects deconfounding, not sample-size reduction (Appendix~\ref{app:length}).
25	
26	
27	\begin{table}[t]
28	\centering
29	\footnotesize
30	\resizebox{\columnwidth}{!}{%
31	\begin{tabular}{llcccc}
32	\toprule
33	\textbf{Model} & \textbf{Family} & \textbf{Params} & \textbf{3-cl F1} & \textbf{Bin F1} & \textbf{95\% CI} \\
34	\midrule
35	Pythia-2.8B     & Pythia  & 2.8B & 0.798 & \textbf{0.724} & [.707, .742] \\
36	Pythia-1B       & Pythia  & 1.0B & \textbf{0.806} & 0.718 & [.700, .735] \\
37	Qwen3-1.7B     & Qwen    & 1.7B & 0.772 & 0.709 & [.693, .726] \\
38	Llama-3.2-3B   & Llama   & 3.2B & 0.775 & 0.697 & [.680, .713] \\
39	OLMo-2-1B      & OLMo    & 1.5B & 0.781 & 0.695 & [.679, .711] \\
40	Qwen3-8B       & Qwen    & 8.2B & 0.714 & 0.692 & [.674, .708] \\
41	Qwen3-0.6B     & Qwen    & 0.6B & 0.780 & 0.691 & [.673, .709] \\
42	Mistral-7B     & Mistral & 7.0B & 0.682 & 0.633 & [.617, .648] \\
43	\midrule
44	\multicolumn{3}{l}{\textbf{Average (8-gen LOGO)}} & \textbf{0.762} & \textbf{0.694} & [.688, .700] \\
45	\bottomrule
46	\end{tabular}}
47	\caption{8-generator LOGO macro-F1 for the 7-feature ensemble (bootstrap 95\% CIs, $n$\,=\,1000). Binary F1 (gen-1 vs.\ gen-2+) is the primary metric. Note: 3-class F1 may carry upward bias from gen-0 seed sharing across generators; binary F1 is leak-free. Cross-model chains (Table~\ref{tab:cross-ref}) use sample-level CV without this issue.}
48	\label{tab:logo-results}
49	\end{table}
50	
51	\subsection{Differential Depth Response}
52	\label{sec:results-differential}
53	
54	Features exhibit \emph{differential depth response} (DDR): central-tendency and diversity measures drift monotonically with depth, while shape measures remain near-stationary, consistent with recursive generation inducing a location shift in the NLL distribution while approximately preserving its functional form (shape-feature CV shift $<$3\% vs.\ $>$15\% for drifting features).
55	
56	\begin{figure}[t]
57	\centering
58	\includegraphics[width=\columnwidth]{fig1_differential_response.pdf}
59	\caption{Differential depth response: Spearman correlations between individual features and generation depth. Central-tendency and diversity features (hapax ratio, TTR, entropy mean) show substantial monotonic drift; entropy std ($|\rho|{=}0.17$) occupies an intermediate position; shape features (entropy max, tail decay) remain near-stationary ($|\rho| < 0.10$).}
60	\label{fig:feature-drift}
61	\end{figure}
62	
63	Pooled class-balanced Spearman correlations with depth confirm the split (Figure~\ref{fig:feature-drift}):
64	drifting features show substantial monotonic trends (hapax ratio $\rho = -0.63$, TTR $\rho = -0.61$, entropy mean $\rho = -0.60$),
65	while shape features remain near-stationary (tail decay $|\rho| = 0.04$).
66	The six-fold magnitude gap between drifting ($|\rho| > 0.60$) and shape features ($|\rho| < 0.10$) serves as the operative criterion for the DDR split, with entropy std occupying an intermediate position ($|\rho| = 0.17$); shifting these descriptive thresholds by $\pm 0.10$ does not alter feature grouping.
67	
68	\paragraph{Distributional shift quantification.}
69	Two-sample KS tests between gen-1 and gen-2+ distributions confirm the split: drifting-feature KS statistics (0.516--0.537) are ${\sim}10\times$ larger than shape-feature statistics (0.043--0.052; all $p \approx 0$ after Bonferroni correction).
70	Levene tests reject equal variance for all features ($p < 10^{-10}$), but effect sizes differ markedly: shape-feature CV shift $<$3\% vs.\ $>$15\% for drifting features, supporting ``approximately preserves'' as a practical characterization rather than a strict invariance claim.
71	
72	\paragraph{Feature complementarity.}
73	Under 10-fold stratified CV, the full 7-feature set (F1\,=\,0.773) outperforms surface-only (F1\,=\,0.688) and reference-only (F1\,=\,0.713; McNemar $p \approx 0$; Table~\ref{tab:ablation} in Appendix~\ref{app:ablation-table}).
74	Reference-only yields higher binary F1 (0.833 vs.\ 0.695) since surface features introduce noise at the gen-1/gen-2+ boundary, but surface features are essential for 3-class gen-0 discrimination (Full 0.773 vs.\ Reference-only 0.713).
75	Permutation importance: hapax ratio (0.35), entropy mean (0.23), TTR (0.18); leave-one-feature-out confirms 6 of 7 features contribute positively (Appendix~\ref{app:lofo}).
76	
77	\paragraph{Cross-family reference models.}
78	Alternative references (OLMo-2-1B, Qwen3-0.6B) achieve comparable LOGO F1 (spread 0.013; Table~\ref{tab:cross-ref} in Appendix~\ref{app:cross-ref}), with consistently negative entropy drift, confirming DDR is a property of recursive generation.
79	
80	\paragraph{Temperature sensitivity.}
81	The method operates reliably within $t \in [0.5, 0.9]$: F1 varies by at most 1\,pp from the default $t{=}0.7$ across this range (Appendix~\ref{app:sampling-sensitivity}).
82	At $t{=}1.0$, performance degrades by ${\sim}6$\,pp as the primary depth signal collapses: entropy mean's Spearman correlation with depth drops from $\rho = -0.60$ to $\rho = -0.002$, indicating that high-temperature sampling injects sufficient token-level randomness to mask the systematic location shift that DDR exploits.
83	
84	
85	\subsection{Comparison with Detection Baselines}
86	\label{sec:results-baselines}
87	
88	We repurpose four detection scores as ordinal depth predictors using the same XGBoost framework and LOGO splits (Table~\ref{tab:baselines}, Figure~\ref{fig:baseline-ci}).
89	
90	\begin{figure}[t]
91	\centering
92	\includegraphics[width=\columnwidth]{fig3_baseline_comparison.pdf}
93	\caption{LOGO binary F1 with 95\% bootstrap CIs. Per-generator variance is higher for single detectors than for the ensemble.}
94	\label{fig:baseline-ci}
95	\end{figure}
96	
97	\begin{table}[t]
98	\centering
99	\footnotesize
100	\begin{tabular}{lcccc}
101	\toprule
102	\textbf{Method} & \textbf{Feat.} & \textbf{3-cl F1} & \textbf{Bin F1} & \textbf{ms/text} \\
103	\midrule
104	4-det.\ + surface     & 6 & \textbf{0.795} & \textbf{0.708} & 22.8 \\
105	4-detector ens.\      & 4 & 0.785 & 0.700 & 22.8 \\
106	7-feature (ours)      & 7 & 0.774 & 0.705 & \textbf{9.7} \\
107	Avg-LogProb           & 1 & 0.707 & 0.673 & --- \\
108	FastDetectGPT         & 1 & 0.660 & 0.569 & --- \\
109	LD-Score              & 1 & 0.630 & 0.675 & --- \\
110	Binoculars            & 1 & 0.411 & 0.539 & --- \\
111	\bottomrule
112	\end{tabular}
113	\caption{Depth classification (8-gen LOGO, pooled evaluation: predictions from all held-out folds are concatenated before computing F1, yielding slightly higher scores than the per-generator macro average in Table~\ref{tab:logo-results}). All methods use identical XGBoost configuration ($n_\text{estimators}{=}200$, $\max_\text{depth}{=}6$). Binary: gen-1 vs.\ gen-2+. Inference cost: 7-feature requires one 410M reference model (905\,MB); 4-det ensembles require two models totaling 1.4B parameters (2{,}868\,MB).}
114	\label{tab:baselines}
115	\end{table}
116	
117	The 7-feature ensemble exceeds all individual baselines in 3-class F1 ($\Delta$\,=\,6.7--14.4\,pp vs.\ Avg-LogProb through LD-Score).
118	Multi-detector ensembles achieve higher 3-class F1 (0.795 vs.\ 0.774, +2.1\,pp) and marginally higher binary F1 (0.708 vs.\ 0.705, +0.3\,pp), but require 2.4$\times$ longer inference and 3.2$\times$ more GPU memory.
119	
120	
121	Preliminary downstream evaluation (fine-tuning OLMo-2-0425-1B on depth-stratified data; Appendix~\ref{app:downstream}) finds that depth composition does not determine training utility at fixed sample count, though the evidence is limited (three seeds, single perplexity metric).
122	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "01359405-468e-42ba-a037-14e02b02ca51",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex",
      "content": "\\section{Results}\n\\label{sec:results}\n\n\\subsection{Depth Classification Performance}\n\\label{sec:results-classification}\n\nThe 7-feature ensemble achieves 3-class LOGO F1\\,=\\,0.762 (95\\% CI [0.758, 0.766]; $N$\\,=\\,37{,}058) across eight generators from five families (Table~\\ref{tab:logo-results}).\nBecause gen-0 seeds are shared across generators (\\S\\ref{sec:generation}), gen-0 classification is near-perfect (per-class F1\\,$\\approx$\\,0.94) and the 3-class metric is inflated by this overlap.\nWe therefore adopt leak-free binary F1 (gen-1 vs.\\ gen-2+)\\,=\\,0.694, CI [0.688, 0.700], as the primary metric throughout; it excludes gen-0 entirely and is unaffected by seed sharing.\nPer-generator binary F1 ranges from 0.633 (Mistral-7B) to 0.724 (Pythia-2.8B); the primary difficulty is distinguishing gen-1 from gen-2+ (Appendix~\\ref{app:confusion}).\nLarger generators show moderate degradation (Qwen3-8B: 0.692, Mistral-7B: 0.633) relative to the 0.694 average.\nThe Pythia-1B/2.8B crossover between three-class and binary scores (0.806 vs.\\ 0.798 and 0.718 vs.\\ 0.724, respectively) reflects differences in gen-0 classification accuracy rather than in depth discrimination per se.\n\n\\paragraph{Cross-model generalization.}\nCross-model chains (randomly selected generator per step) yield 3-class F1\\,=\\,0.809 and binary F1\\,=\\,0.764 under 5-fold CV,\\footnote{Cross-model chains use the original five-generator subset (Pythia, OLMo, Qwen); Llama and Mistral were added later for single-generator evaluation.} confirming that depth signal persists when text passes through heterogeneous generators.\nThe higher cross-model performance relative to single-generator LOGO (3-class: 0.809 vs.\\ 0.762) suggests that generator heterogeneity amplifies distributional shifts between depths, making each recursive step more distinct.\nUnder class balancing, macro F1 reaches 0.831 (per-class breakdown in Appendix~\\ref{app:cross-model-detail}).\n\nLeave-one-family-out (LOFO) evaluation yields average binary F1\\,=\\,0.686, confirming transfer across architectural families.\nA scale effect emerges: Pythia generators achieve the highest binary F1 (0.718--0.724), while larger models show degradation (Mistral-7B: 0.633), consistent with higher-capacity models compressing the feature margins DDR exploits.\nThe signal generalizes across text domains with variation (Appendix~\\ref{app:domain}).\n\n\\paragraph{Length confound control.}\nLength-matched subsampling yields binary F1\\,=\\,0.724 (vs.\\ 0.770 unmatched); a random-subsample control confirms the drop reflects deconfounding, not sample-size reduction (Appendix~\\ref{app:length}).\n\n\n\\begin{table}[t]\n\\centering\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llcccc}\n\\toprule\n\\textbf{Model} & \\textbf{Family} & \\textbf{Params} & \\textbf{3-cl F1} & \\textbf{Bin F1} & \\textbf{95\\% CI} \\\\\n\\midrule\nPythia-2.8B     & Pythia  & 2.8B & 0.798 & \\textbf{0.724} & [.707, .742] \\\\\nPythia-1B       & Pythia  & 1.0B & \\textbf{0.806} & 0.718 & [.700, .735] \\\\\nQwen3-1.7B     & Qwen    & 1.7B & 0.772 & 0.709 & [.693, .726] \\\\\nLlama-3.2-3B   & Llama   & 3.2B & 0.775 & 0.697 & [.680, .713] \\\\\nOLMo-2-1B      & OLMo    & 1.5B & 0.781 & 0.695 & [.679, .711] \\\\\nQwen3-8B       & Qwen    & 8.2B & 0.714 & 0.692 & [.674, .708] \\\\\nQwen3-0.6B     & Qwen    & 0.6B & 0.780 & 0.691 & [.673, .709] \\\\\nMistral-7B     & Mistral & 7.0B & 0.682 & 0.633 & [.617, .648] \\\\\n\\midrule\n\\multicolumn{3}{l}{\\textbf{Average (8-gen LOGO)}} & \\textbf{0.762} & \\textbf{0.694} & [.688, .700] \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{8-generator LOGO macro-F1 for the 7-feature ensemble (bootstrap 95\\% CIs, $n$\\,=\\,1000). Binary F1 (gen-1 vs.\\ gen-2+) is the primary metric. Note: 3-class F1 may carry upward bias from gen-0 seed sharing across generators; binary F1 is leak-free. Cross-model chains (Table~\\ref{tab:cross-ref}) use sample-level CV without this issue.}\n\\label{tab:logo-results}\n\\end{table}\n\n\\subsection{Differential Depth Response}\n\\label{sec:results-differential}\n\nFeatures exhibit \\emph{differential depth response} (DDR): central-tendency and diversity measures drift monotonically with depth, while shape measures remain near-stationary, consistent with recursive generation inducing a location shift in the NLL distribution while approximately preserving its functional form (shape-feature CV shift $<$3\\% vs.\\ $>$15\\% for drifting features).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig1_differential_response.pdf}\n\\caption{Differential depth response: Spearman correlations between individual features and generation depth. Central-tendency and diversity features (hapax ratio, TTR, entropy mean) show substantial monotonic drift; entropy std ($|\\rho|{=}0.17$) occupies an intermediate position; shape features (entropy max, tail decay) remain near-stationary ($|\\rho| < 0.10$).}\n\\label{fig:feature-drift}\n\\end{figure}\n\nPooled class-balanced Spearman correlations with depth confirm the split (Figure~\\ref{fig:feature-drift}):\ndrifting features show substantial monotonic trends (hapax ratio $\\rho = -0.63$, TTR $\\rho = -0.61$, entropy mean $\\rho = -0.60$),\nwhile shape features remain near-stationary (tail decay $|\\rho| = 0.04$).\nThe six-fold magnitude gap between drifting ($|\\rho| > 0.60$) and shape features ($|\\rho| < 0.10$) serves as the operative criterion for the DDR split, with entropy std occupying an intermediate position ($|\\rho| = 0.17$); shifting these descriptive thresholds by $\\pm 0.10$ does not alter feature grouping.\n\n\\paragraph{Distributional shift quantification.}\nTwo-sample KS tests between gen-1 and gen-2+ distributions confirm the split: drifting-feature KS statistics (0.516--0.537) are ${\\sim}10\\times$ larger than shape-feature statistics (0.043--0.052; all $p \\approx 0$ after Bonferroni correction).\nLevene tests reject equal variance for all features ($p < 10^{-10}$), but effect sizes differ markedly: shape-feature CV shift $<$3\\% vs.\\ $>$15\\% for drifting features, supporting ``approximately preserves'' as a practical characterization rather than a strict invariance claim.\n\n\\paragraph{Feature complementarity.}\nUnder 10-fold stratified CV, the full 7-feature set (F1\\,=\\,0.773) outperforms surface-only (F1\\,=\\,0.688) and reference-only (F1\\,=\\,0.713; McNemar $p \\approx 0$; Table~\\ref{tab:ablation} in Appendix~\\ref{app:ablation-table}).\nReference-only yields higher binary F1 (0.833 vs.\\ 0.695) since surface features introduce noise at the gen-1/gen-2+ boundary, but surface features are essential for 3-class gen-0 discrimination (Full 0.773 vs.\\ Reference-only 0.713).\nPermutation importance: hapax ratio (0.35), entropy mean (0.23), TTR (0.18); leave-one-feature-out confirms 6 of 7 features contribute positively (Appendix~\\ref{app:lofo}).\n\n\\paragraph{Cross-family reference models.}\nAlternative references (OLMo-2-1B, Qwen3-0.6B) achieve comparable LOGO F1 (spread 0.013; Table~\\ref{tab:cross-ref} in Appendix~\\ref{app:cross-ref}), with consistently negative entropy drift, confirming DDR is a property of recursive generation.\n\n\\paragraph{Temperature sensitivity.}\nThe method operates reliably within $t \\in [0.5, 0.9]$: F1 varies by at most 1\\,pp from the default $t{=}0.7$ across this range (Appendix~\\ref{app:sampling-sensitivity}).\nAt $t{=}1.0$, performance degrades by ${\\sim}6$\\,pp as the primary depth signal collapses: entropy mean's Spearman correlation with depth drops from $\\rho = -0.60$ to $\\rho = -0.002$, indicating that high-temperature sampling injects sufficient token-level randomness to mask the systematic location shift that DDR exploits.\n\n\n\\subsection{Comparison with Detection Baselines}\n\\label{sec:results-baselines}\n\nWe repurpose four detection scores as ordinal depth predictors using the same XGBoost framework and LOGO splits (Table~\\ref{tab:baselines}, Figure~\\ref{fig:baseline-ci}).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig3_baseline_comparison.pdf}\n\\caption{LOGO binary F1 with 95\\% bootstrap CIs. Per-generator variance is higher for single detectors than for the ensemble.}\n\\label{fig:baseline-ci}\n\\end{figure}\n\n\\begin{table}[t]\n\\centering\n\\footnotesize\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Method} & \\textbf{Feat.} & \\textbf{3-cl F1} & \\textbf{Bin F1} & \\textbf{ms/text} \\\\\n\\midrule\n4-det.\\ + surface     & 6 & \\textbf{0.795} & \\textbf{0.708} & 22.8 \\\\\n4-detector ens.\\      & 4 & 0.785 & 0.700 & 22.8 \\\\\n7-feature (ours)      & 7 & 0.774 & 0.705 & \\textbf{9.7} \\\\\nAvg-LogProb           & 1 & 0.707 & 0.673 & --- \\\\\nFastDetectGPT         & 1 & 0.660 & 0.569 & --- \\\\\nLD-Score              & 1 & 0.630 & 0.675 & --- \\\\\nBinoculars            & 1 & 0.411 & 0.539 & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Depth classification (8-gen LOGO, pooled evaluation: predictions from all held-out folds are concatenated before computing F1, yielding slightly higher scores than the per-generator macro average in Table~\\ref{tab:logo-results}). All methods use identical XGBoost configuration ($n_\\text{estimators}{=}200$, $\\max_\\text{depth}{=}6$). Binary: gen-1 vs.\\ gen-2+. Inference cost: 7-feature requires one 410M reference model (905\\,MB); 4-det ensembles require two models totaling 1.4B parameters (2{,}868\\,MB).}\n\\label{tab:baselines}\n\\end{table}\n\nThe 7-feature ensemble exceeds all individual baselines in 3-class F1 ($\\Delta$\\,=\\,6.7--14.4\\,pp vs.\\ Avg-LogProb through LD-Score).\nMulti-detector ensembles achieve higher 3-class F1 (0.795 vs.\\ 0.774, +2.1\\,pp) and marginally higher binary F1 (0.708 vs.\\ 0.705, +0.3\\,pp), but require 2.4$\\times$ longer inference and 3.2$\\times$ more GPU memory.\n\n\nPreliminary downstream evaluation (fine-tuning OLMo-2-0425-1B on depth-stratified data; Appendix~\\ref{app:downstream}) finds that depth composition does not determine training utility at fixed sample count, though the evidence is limited (three seeds, single perplexity metric).\n",
      "numLines": 122,
      "startLine": 1,
      "totalLines": 122
    }
  }
}
```

</details>

---


### Tool call

_source line 28_

<details open><summary>🔧 Tool call — Read · `toolu_01982mBkKCA6eKyEX9vMuU5X`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "27bb1978-a1c4-421c-af52-78d6caa9479f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0195r3LUfohzwasZKKFc5fm2",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8831,
      "cache_read_input_tokens": 28205,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8831
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

_source line 29 · 2026-05-17T19:52:47.426Z_

<details><summary>↩ Tool result · `toolu_01982mBkKCA6eKyEX9vMuU5X`</summary>

```text
1	\section{Discussion}
2	\label{sec:discussion}
3	
4	The near-stationarity of shape features is consistent with the softmax architecture and fixed sampling parameters constraining distributional shape while allowing location to drift.
5	Sampling ablation supports this as a tendency rather than a guarantee ($t \in [0.5, 0.7]$: ${\leq}0.3$\,pp degradation; $t = 1.0$: $-6$\,pp; Appendix~\ref{app:sampling-sensitivity}), and prompt-type dependence further modulates the effect (elaboration F1\,=\,0.730 vs.\ continuation 0.781; Appendix~\ref{app:prompt-type}).
6	
7	Instruction-tuned models show substantially weaker fingerprints in preliminary experiments (OLMo-Instruct LOGO F1\,=\,0.338 vs.\ 0.763 base, 6-generator LOGO): alignment-imposed length regulation and format constraints compress the distributional variation that DDR exploits.
8	This restricts current applicability to base models and constitutes the primary scope limitation.
9	At the document level within base models, gen-1 per-class F1\,=\,0.63 is insufficient for automated filtering but sufficient for corpus-level flagging; the gen-1\,/\,gen-2+ boundary concentrates 86\% of binary errors as false negatives, with larger generators exacerbating this (Mistral-7B error rate 45\% vs.\ Pythia-1B 18\%; Appendix~\ref{app:error-analysis}).
10	Cross-temperature transfer degrades substantially ($t{=}0.7 \to t{=}1.0$: Qwen3-1.7B F1 drops from 0.789 to 0.418; Appendix~\ref{app:cross-temp}).
11	
12	Three classes represent the practical resolution ceiling: 5-class F1 drops to ${\approx}$0.50 (Appendix~\ref{app:finer-depth}), and ordinal-specific methods (CORAL, Frank-Hall) yield no improvement over standard XGBoost (Appendix~\ref{app:classifier}), suggesting that the gen-1/gen-2+ boundary rather than ordinal structure is the bottleneck.
13	DDR is distinct from model collapse \cite{curse_of_recursion,strong_model_collapse}: inference-chain drift occurs with fixed parameters, is fully reversible, and approximately preserves distributional shape, suggesting compression within existing capacity rather than erosion of it.
14	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "12fc3950-5ed1-4ada-9567-457cec1c91e9",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/discussion.tex",
      "content": "\\section{Discussion}\n\\label{sec:discussion}\n\nThe near-stationarity of shape features is consistent with the softmax architecture and fixed sampling parameters constraining distributional shape while allowing location to drift.\nSampling ablation supports this as a tendency rather than a guarantee ($t \\in [0.5, 0.7]$: ${\\leq}0.3$\\,pp degradation; $t = 1.0$: $-6$\\,pp; Appendix~\\ref{app:sampling-sensitivity}), and prompt-type dependence further modulates the effect (elaboration F1\\,=\\,0.730 vs.\\ continuation 0.781; Appendix~\\ref{app:prompt-type}).\n\nInstruction-tuned models show substantially weaker fingerprints in preliminary experiments (OLMo-Instruct LOGO F1\\,=\\,0.338 vs.\\ 0.763 base, 6-generator LOGO): alignment-imposed length regulation and format constraints compress the distributional variation that DDR exploits.\nThis restricts current applicability to base models and constitutes the primary scope limitation.\nAt the document level within base models, gen-1 per-class F1\\,=\\,0.63 is insufficient for automated filtering but sufficient for corpus-level flagging; the gen-1\\,/\\,gen-2+ boundary concentrates 86\\% of binary errors as false negatives, with larger generators exacerbating this (Mistral-7B error rate 45\\% vs.\\ Pythia-1B 18\\%; Appendix~\\ref{app:error-analysis}).\nCross-temperature transfer degrades substantially ($t{=}0.7 \\to t{=}1.0$: Qwen3-1.7B F1 drops from 0.789 to 0.418; Appendix~\\ref{app:cross-temp}).\n\nThree classes represent the practical resolution ceiling: 5-class F1 drops to ${\\approx}$0.50 (Appendix~\\ref{app:finer-depth}), and ordinal-specific methods (CORAL, Frank-Hall) yield no improvement over standard XGBoost (Appendix~\\ref{app:classifier}), suggesting that the gen-1/gen-2+ boundary rather than ordinal structure is the bottleneck.\nDDR is distinct from model collapse \\cite{curse_of_recursion,strong_model_collapse}: inference-chain drift occurs with fixed parameters, is fully reversible, and approximately preserves distributional shape, suggesting compression within existing capacity rather than erosion of it.\n",
      "numLines": 14,
      "startLine": 1,
      "totalLines": 14
    }
  }
}
```

</details>

---


### Tool call

_source line 30_

<details open><summary>🔧 Tool call — Read · `toolu_01PnTmSBgZCqAmxJuSJWoD89`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "7ef5836b-d980-4ca8-a6aa-2ec3d11355cf",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0195r3LUfohzwasZKKFc5fm2",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8831,
      "cache_read_input_tokens": 28205,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8831
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

_source line 31 · 2026-05-17T19:52:47.935Z_

<details><summary>↩ Tool result · `toolu_01PnTmSBgZCqAmxJuSJWoD89`</summary>

```text
1	\section{Related Work}
2	\label{sec:related}
3	
4	\subsection{AI-Generated Text Detection}
5	\label{sec:related-detection}
6	
7	Methods for distinguishing human-written from machine-generated text have evolved from statistical tests \cite{gltr,grover,release_strategies} to zero-shot reference-model approaches \cite{detectgpt,fast_detectgpt,binoculars,dna_gpt} and learned classifiers \cite{ghostbuster,feat_aug_transformer,reliable_detection,ld_score}.
8	Recent work pursues diverse signals including intrinsic dimensionality \cite{intrinsic_dimension}, surprisal diversity \cite{diveye}, and distributional gap measures \cite{generator_barrier}; see \citet{wu_survey_2025} and \citet{jawahar_survey} for surveys.
9	A persistent limitation is that these methods produce binary (real vs.\ synthetic) decisions.
10	Recent multi-class extensions (role recognition in human-LLM collaboration \cite{beyond_binary}, multi-generator attribution \cite{semeval2024_task8}) discriminate among different \emph{sources} rather than recursive generation \emph{depth}.
11	Even when detection scores correlate with depth, they exhibit high cross-generator variance as ordinal predictors (binary F1 from 0.52 to 0.71; Table~\ref{tab:baselines}), because each captures a single distributional property that generalizes inconsistently \cite{paraphrase_evades,detection_possibilities}.
12	Adversarial training approaches (e.g., RADAR \cite{radar}) improve robustness to paraphrasing but remain binary detectors without depth awareness.
13	Our contribution is not a new detection method but the task formulation (generation depth classification, framed within the broader ordinal classification literature \cite{gutierrez_ordinal_survey,coral_ordinal}) and the finding that combining drifting and stationary features yields consistent cross-generator performance.
14	This is orthogonal to source attribution \cite{uchendu_attribution,munir_looking_glass}, which identifies \emph{which} model generated text; our LOGO evaluation decouples generator identity from depth.
15	
16	\subsection{Model Collapse and Iterative Generation}
17	\label{sec:related-collapse}
18	
19	Self-consuming generative models progressively lose distributional coverage \cite{self_consuming_mad}, and model collapse is inevitable without fresh human data \cite{curse_of_recursion}, though careful data mixing can mitigate this \cite{model_collapse_avoidable,strong_model_collapse}.
20	These studies focus on \emph{training-loop} degradation; our setting studies \emph{inference chains}, where a fixed model generates text conditioned on its own prior output without retraining.
21	The distinction extends beyond setting: model collapse erodes distributional tail coverage irreversibly as training progresses \cite{curse_of_recursion,strong_model_collapse}, whereas the drift we observe is reversible under fixed parameters and approximately preserves distributional shape (\S\ref{sec:results-differential}).
22	The drifting/stationary feature decomposition central to our analysis has no analogue in model collapse studies, which track aggregate divergence without separating location from shape components.
23	Iterative self-refinement \cite{self_refine} represents another form of recursive LLM processing, but targets output improvement through feedback loops rather than open-ended continuation; the distributional drift we study arises specifically from unconstrained recursive generation.
24	
25	Two concurrent works are most directly relevant.
26	\citet{broken_telephone} analyze paraphrasing and translation chains, showing progressive information loss.
27	\citet{markovian_chains} demonstrate that semantic-preservation constraints induce attractor dynamics bounding distinguishable depth to approximately three classes; their analysis focuses on characterizing convergence behavior through model-based perplexity tracking.
28	We differ in three respects: (i) we study \emph{non-paraphrastic continuation} chains, where the absence of semantic anchoring permits richer depth signal; (ii) we use handcrafted features rather than model-internal representations, enabling the DDR decomposition into drifting vs.\ stationary components; and (iii) we focus on \emph{estimating} depth from text rather than characterizing the convergence dynamics of the generation process.
29	
30	That both works independently converge on approximately three distinguishable classes reflects different mechanisms reaching the same practical ceiling.
31	\citet{markovian_chains} derive this bound from Markovian attractor dynamics: semantic-preservation constraints create fixed points where successive outputs become indistinguishable under model-internal perplexity.
32	We observe the same bound empirically through feature-space compression: inter-class KS statistics drop sharply after depth 2 (gen-1$\rightarrow$gen-2: KS\,=\,0.28 vs.\ gen-2$\rightarrow$gen-3: KS\,=\,0.09 for entropy mean), collapsing discriminative margins.
33	The approaches are complementary: their theoretical framework explains \emph{why} convergence occurs (attractor dynamics in semantic space), while our DDR decomposition reveals \emph{what} converges (location properties) versus what remains stable (distributional shape), providing an empirical signature that can be exploited for detection without access to model internals.
34	
35	\subsection{Vocabulary Diversity and Stylometry}
36	\label{sec:related-diversity}
37	
38	Declining lexical diversity in LLM-generated text is documented in both training \cite{curious_decline} and deployment \cite{writing_diversity} settings.
39	Our surface features (TTR and hapax ratio) are classical stylometric measures \cite{stamatatos_survey,koppel_authorship} that we apply to inference chains, showing monotonic diversity decline across depths without model retraining.
40	We push beyond generator identity \cite{uchendu_attribution} to the \emph{depth} dimension, and show that diversity declines monotonically even under top-$p$ sampling \cite{nucleus_sampling}.
41	
42	\subsection{Data Quality and Provenance}
43	\label{sec:related-provenance}
44	
45	Scalable data curation relies on quality signals \cite{dsir,qurating,ccnet}; generation depth is a complementary provenance signal characterizing \emph{how many steps removed} text is from a human source.
46	Proactive watermarking \cite{watermark_llm,synthid_text,aaronson_watermark} embeds identifiable patterns, but watermark strength decays across multi-step chains \cite{chainwash}, motivating passive post-hoc methods like ours.
47	At the feature level, our NLL analysis connects to \citet{min_k_percent}, who use the probability tail for membership inference; we analyze the full NLL distribution for generation depth classification.
48	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "9489623b-d1ad-4502-a1a5-bba080b647ed",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/related_work.tex",
      "content": "\\section{Related Work}\n\\label{sec:related}\n\n\\subsection{AI-Generated Text Detection}\n\\label{sec:related-detection}\n\nMethods for distinguishing human-written from machine-generated text have evolved from statistical tests \\cite{gltr,grover,release_strategies} to zero-shot reference-model approaches \\cite{detectgpt,fast_detectgpt,binoculars,dna_gpt} and learned classifiers \\cite{ghostbuster,feat_aug_transformer,reliable_detection,ld_score}.\nRecent work pursues diverse signals including intrinsic dimensionality \\cite{intrinsic_dimension}, surprisal diversity \\cite{diveye}, and distributional gap measures \\cite{generator_barrier}; see \\citet{wu_survey_2025} and \\citet{jawahar_survey} for surveys.\nA persistent limitation is that these methods produce binary (real vs.\\ synthetic) decisions.\nRecent multi-class extensions (role recognition in human-LLM collaboration \\cite{beyond_binary}, multi-generator attribution \\cite{semeval2024_task8}) discriminate among different \\emph{sources} rather than recursive generation \\emph{depth}.\nEven when detection scores correlate with depth, they exhibit high cross-generator variance as ordinal predictors (binary F1 from 0.52 to 0.71; Table~\\ref{tab:baselines}), because each captures a single distributional property that generalizes inconsistently \\cite{paraphrase_evades,detection_possibilities}.\nAdversarial training approaches (e.g., RADAR \\cite{radar}) improve robustness to paraphrasing but remain binary detectors without depth awareness.\nOur contribution is not a new detection method but the task formulation (generation depth classification, framed within the broader ordinal classification literature \\cite{gutierrez_ordinal_survey,coral_ordinal}) and the finding that combining drifting and stationary features yields consistent cross-generator performance.\nThis is orthogonal to source attribution \\cite{uchendu_attribution,munir_looking_glass}, which identifies \\emph{which} model generated text; our LOGO evaluation decouples generator identity from depth.\n\n\\subsection{Model Collapse and Iterative Generation}\n\\label{sec:related-collapse}\n\nSelf-consuming generative models progressively lose distributional coverage \\cite{self_consuming_mad}, and model collapse is inevitable without fresh human data \\cite{curse_of_recursion}, though careful data mixing can mitigate this \\cite{model_collapse_avoidable,strong_model_collapse}.\nThese studies focus on \\emph{training-loop} degradation; our setting studies \\emph{inference chains}, where a fixed model generates text conditioned on its own prior output without retraining.\nThe distinction extends beyond setting: model collapse erodes distributional tail coverage irreversibly as training progresses \\cite{curse_of_recursion,strong_model_collapse}, whereas the drift we observe is reversible under fixed parameters and approximately preserves distributional shape (\\S\\ref{sec:results-differential}).\nThe drifting/stationary feature decomposition central to our analysis has no analogue in model collapse studies, which track aggregate divergence without separating location from shape components.\nIterative self-refinement \\cite{self_refine} represents another form of recursive LLM processing, but targets output improvement through feedback loops rather than open-ended continuation; the distributional drift we study arises specifically from unconstrained recursive generation.\n\nTwo concurrent works are most directly relevant.\n\\citet{broken_telephone} analyze paraphrasing and translation chains, showing progressive information loss.\n\\citet{markovian_chains} demonstrate that semantic-preservation constraints induce attractor dynamics bounding distinguishable depth to approximately three classes; their analysis focuses on characterizing convergence behavior through model-based perplexity tracking.\nWe differ in three respects: (i) we study \\emph{non-paraphrastic continuation} chains, where the absence of semantic anchoring permits richer depth signal; (ii) we use handcrafted features rather than model-internal representations, enabling the DDR decomposition into drifting vs.\\ stationary components; and (iii) we focus on \\emph{estimating} depth from text rather than characterizing the convergence dynamics of the generation process.\n\nThat both works independently converge on approximately three distinguishable classes reflects different mechanisms reaching the same practical ceiling.\n\\citet{markovian_chains} derive this bound from Markovian attractor dynamics: semantic-preservation constraints create fixed points where successive outputs become indistinguishable under model-internal perplexity.\nWe observe the same bound empirically through feature-space compression: inter-class KS statistics drop sharply after depth 2 (gen-1$\\rightarrow$gen-2: KS\\,=\\,0.28 vs.\\ gen-2$\\rightarrow$gen-3: KS\\,=\\,0.09 for entropy mean), collapsing discriminative margins.\nThe approaches are complementary: their theoretical framework explains \\emph{why} convergence occurs (attractor dynamics in semantic space), while our DDR decomposition reveals \\emph{what} converges (location properties) versus what remains stable (distributional shape), providing an empirical signature that can be exploited for detection without access to model internals.\n\n\\subsection{Vocabulary Diversity and Stylometry}\n\\label{sec:related-diversity}\n\nDeclining lexical diversity in LLM-generated text is documented in both training \\cite{curious_decline} and deployment \\cite{writing_diversity} settings.\nOur surface features (TTR and hapax ratio) are classical stylometric measures \\cite{stamatatos_survey,koppel_authorship} that we apply to inference chains, showing monotonic diversity decline across depths without model retraining.\nWe push beyond generator identity \\cite{uchendu_attribution} to the \\emph{depth} dimension, and show that diversity declines monotonically even under top-$p$ sampling \\cite{nucleus_sampling}.\n\n\\subsection{Data Quality and Provenance}\n\\label{sec:related-provenance}\n\nScalable data curation relies on quality signals \\cite{dsir,qurating,ccnet}; generation depth is a complementary provenance signal characterizing \\emph{how many steps removed} text is from a human source.\nProactive watermarking \\cite{watermark_llm,synthid_text,aaronson_watermark} embeds identifiable patterns, but watermark strength decays across multi-step chains \\cite{chainwash}, motivating passive post-hoc methods like ours.\nAt the feature level, our NLL analysis connects to \\citet{min_k_percent}, who use the probability tail for membership inference; we analyze the full NLL distribution for generation depth classification.\n",
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

_source line 32_

<details open><summary>🔧 Tool call — Read · `toolu_01E1QkXRwAhTuhzVeamRimeo`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/limitations.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "e20a562d-268f-436b-82ba-cb538ee07275",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0195r3LUfohzwasZKKFc5fm2",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8831,
      "cache_read_input_tokens": 28205,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8831
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

_source line 33 · 2026-05-17T19:52:48.438Z_

<details><summary>↩ Tool result · `toolu_01E1QkXRwAhTuhzVeamRimeo`</summary>

```text
1	\section*{Limitations}
2	\label{sec:limitations}
3	
4	All eight generators are base (pretrained) models.
5	This is a deliberate design choice: base models isolate the generation mechanism from instruction-tuning effects, enabling controlled study of recursive distributional drift.
6	However, web text is predominantly produced by instruction-tuned and RLHF-aligned models.
7	Preliminary instruct experiments confirm that depth signal degrades substantially under instruction tuning: OLMo-2-1B-Instruct drops to LOGO F1\,=\,0.338 (vs.\ 0.763 base) and Qwen3-0.6B with chat template to 0.667 (vs.\ 0.816 base); these comparisons use earlier LOGO subsets (5--6 generators) predating the full 8-generator expansion in Table~\ref{tab:logo-results}.
8	Length-matched analysis yields near-zero correlations ($|\rho| < 0.02$) and binary classification near chance (F1\,$\approx$\,0.5) for Qwen models, leaving interpretation ambiguous.
9	Extending depth fingerprinting to instruct models requires addressing these confounds (length regulation, format constraints, safety-driven distribution shaping) that instruction tuning introduces.
10	
11	Our experiments include generators up to 8.2B parameters (Qwen3-8B).
12	Depth signal persists at this scale (Qwen3-8B 3-class F1\,=\,0.714), but cross-scale transfer incurs a moderate gap vs.\ $\leq$2.8B generators (F1\,=\,0.77--0.81).
13	Frontier models (70B+) remain untested; their higher fluency may further compress feature margins.
14	
15	Differential depth response strength is prompt-type dependent: continuation chains show strongest drift (within-type F1\,=\,0.781) compared to elaboration (0.730), rewriting (0.737), and paraphrastic chains (binary F1\,=\,0.671 vs.\ 0.749 for continuation).
16	DDR is most reliably detected in continuation-style generation; near-paraphrastic settings approach the method's detection floor.
17	Cross-prompt-type transfer (LOPTO F1\,=\,0.753) confirms shared signal, yet additional prompt types (e.g., summarization, instruction following) and cross-generator $\times$ cross-prompt interactions remain untested.
18	
19	Our primary evaluation uses single-generator chains; cross-model chains (\S\ref{sec:results-classification}) confirm depth signal under generator heterogeneity (3-class F1\,=\,0.809, binary F1\,=\,0.764), though the eight generators represent a controlled laboratory setting rather than the full diversity of real-world contamination.
20	Simulated human editing (\S\ref{sec:discussion}) suggests graceful degradation, but the gap between simulated token replacement and real-world post-processing remains untested.
21	
22	The reference model is fixed to Pythia-410M throughout, although cross-family reference experiments (\S\ref{sec:results-differential}) confirm the phenomenon is not reference-specific (spread 0.013 across three references).
23	All seed texts in the main evaluation are English Wikipedia excerpts.
24	Cross-domain evaluation (Appendix~\ref{app:domain}) shows that depth signal persists across News, Academic, and Code domains (binary F1 $>$ 0.73 under LOGO at $t{=}1.0$), though a domain $\times$ temperature interaction exists: certain domain/generator combinations at lower temperature approach chance level (e.g., Academic domain binary F1\,=\,0.628 at $t{=}0.7$), suggesting that reference model calibration is critical for cross-domain deployment.
25	The reference model dependency (Pythia-410M, English-centric pretraining) limits non-English applicability and adds inference overhead relative to surface-feature-only approaches.
26	Generalization to other languages remains untested.
27	
28	Our default analysis uses fixed decoding parameters (temperature 0.7, nucleus $p{=}0.9$). A sampling ablation (Appendix~\ref{app:sampling-sensitivity}) shows robustness to moderate variation ($t \in [0.5, 0.7]$, ${\leq}0.3$\,pp) but substantial degradation at $t{=}1.0$ ($-6$\,pp), indicating that depth fingerprinting assumes standard decoding regimes.
29	
30	We use 3-class granularity (gen-0\,/\,gen-1\,/\,gen-2+). A 5-class evaluation (Appendix~\ref{app:finer-depth}) yields LOGO F1\,$\approx$\,0.50, with depths 2--4 mutually indistinguishable, validating the 3-class design as the practical resolution limit.
31	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "0d423441-e03f-4466-b6f1-9d3372058f78",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/limitations.tex",
      "content": "\\section*{Limitations}\n\\label{sec:limitations}\n\nAll eight generators are base (pretrained) models.\nThis is a deliberate design choice: base models isolate the generation mechanism from instruction-tuning effects, enabling controlled study of recursive distributional drift.\nHowever, web text is predominantly produced by instruction-tuned and RLHF-aligned models.\nPreliminary instruct experiments confirm that depth signal degrades substantially under instruction tuning: OLMo-2-1B-Instruct drops to LOGO F1\\,=\\,0.338 (vs.\\ 0.763 base) and Qwen3-0.6B with chat template to 0.667 (vs.\\ 0.816 base); these comparisons use earlier LOGO subsets (5--6 generators) predating the full 8-generator expansion in Table~\\ref{tab:logo-results}.\nLength-matched analysis yields near-zero correlations ($|\\rho| < 0.02$) and binary classification near chance (F1\\,$\\approx$\\,0.5) for Qwen models, leaving interpretation ambiguous.\nExtending depth fingerprinting to instruct models requires addressing these confounds (length regulation, format constraints, safety-driven distribution shaping) that instruction tuning introduces.\n\nOur experiments include generators up to 8.2B parameters (Qwen3-8B).\nDepth signal persists at this scale (Qwen3-8B 3-class F1\\,=\\,0.714), but cross-scale transfer incurs a moderate gap vs.\\ $\\leq$2.8B generators (F1\\,=\\,0.77--0.81).\nFrontier models (70B+) remain untested; their higher fluency may further compress feature margins.\n\nDifferential depth response strength is prompt-type dependent: continuation chains show strongest drift (within-type F1\\,=\\,0.781) compared to elaboration (0.730), rewriting (0.737), and paraphrastic chains (binary F1\\,=\\,0.671 vs.\\ 0.749 for continuation).\nDDR is most reliably detected in continuation-style generation; near-paraphrastic settings approach the method's detection floor.\nCross-prompt-type transfer (LOPTO F1\\,=\\,0.753) confirms shared signal, yet additional prompt types (e.g., summarization, instruction following) and cross-generator $\\times$ cross-prompt interactions remain untested.\n\nOur primary evaluation uses single-generator chains; cross-model chains (\\S\\ref{sec:results-classification}) confirm depth signal under generator heterogeneity (3-class F1\\,=\\,0.809, binary F1\\,=\\,0.764), though the eight generators represent a controlled laboratory setting rather than the full diversity of real-world contamination.\nSimulated human editing (\\S\\ref{sec:discussion}) suggests graceful degradation, but the gap between simulated token replacement and real-world post-processing remains untested.\n\nThe reference model is fixed to Pythia-410M throughout, although cross-family reference experiments (\\S\\ref{sec:results-differential}) confirm the phenomenon is not reference-specific (spread 0.013 across three references).\nAll seed texts in the main evaluation are English Wikipedia excerpts.\nCross-domain evaluation (Appendix~\\ref{app:domain}) shows that depth signal persists across News, Academic, and Code domains (binary F1 $>$ 0.73 under LOGO at $t{=}1.0$), though a domain $\\times$ temperature interaction exists: certain domain/generator combinations at lower temperature approach chance level (e.g., Academic domain binary F1\\,=\\,0.628 at $t{=}0.7$), suggesting that reference model calibration is critical for cross-domain deployment.\nThe reference model dependency (Pythia-410M, English-centric pretraining) limits non-English applicability and adds inference overhead relative to surface-feature-only approaches.\nGeneralization to other languages remains untested.\n\nOur default analysis uses fixed decoding parameters (temperature 0.7, nucleus $p{=}0.9$). A sampling ablation (Appendix~\\ref{app:sampling-sensitivity}) shows robustness to moderate variation ($t \\in [0.5, 0.7]$, ${\\leq}0.3$\\,pp) but substantial degradation at $t{=}1.0$ ($-6$\\,pp), indicating that depth fingerprinting assumes standard decoding regimes.\n\nWe use 3-class granularity (gen-0\\,/\\,gen-1\\,/\\,gen-2+). A 5-class evaluation (Appendix~\\ref{app:finer-depth}) yields LOGO F1\\,$\\approx$\\,0.50, with depths 2--4 mutually indistinguishable, validating the 3-class design as the practical resolution limit.\n",
      "numLines": 31,
      "startLine": 1,
      "totalLines": 31
    }
  }
}
```

</details>

---


### Tool call

_source line 34_

<details open><summary>🔧 Tool call — Read · `toolu_01W7sgyvrVuL72zRK35yazWR`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "b7ce4286-594e-490a-a77a-bf3c81e7e96b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0195r3LUfohzwasZKKFc5fm2",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8831,
      "cache_read_input_tokens": 28205,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8831
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

_source line 35 · 2026-05-17T19:52:48.683Z_

<details><summary>↩ Tool result · `toolu_01W7sgyvrVuL72zRK35yazWR`</summary>

```text
1	\section{Conclusion}
2	\label{sec:conclusion}
3	
4	We introduced generation depth classification and documented a differential depth response across eight base-model generators from five families: recursive generation is consistent with a systematic location shift in the token-level NLL distribution that approximately preserves distributional shape.
5	A lightweight 7-feature ensemble detects this drift with leak-free binary F1\,=\,0.694 under eight-generator LOGO evaluation (0.764 on cross-model chains; five-generator subset).
6	The signal degrades substantially under instruction tuning and may further compress at larger scales (our largest generator is 8B), defining the current scope boundaries.
7	All code, data, and trained models will be released upon publication.
8	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "5da1fbdd-7215-4285-98f4-75c6b8c38407",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/conclusion.tex",
      "content": "\\section{Conclusion}\n\\label{sec:conclusion}\n\nWe introduced generation depth classification and documented a differential depth response across eight base-model generators from five families: recursive generation is consistent with a systematic location shift in the token-level NLL distribution that approximately preserves distributional shape.\nA lightweight 7-feature ensemble detects this drift with leak-free binary F1\\,=\\,0.694 under eight-generator LOGO evaluation (0.764 on cross-model chains; five-generator subset).\nThe signal degrades substantially under instruction tuning and may further compress at larger scales (our largest generator is 8B), defining the current scope boundaries.\nAll code, data, and trained models will be released upon publication.\n",
      "numLines": 8,
      "startLine": 1,
      "totalLines": 8
    }
  }
}
```

</details>

---


### Assistant

_source line 36_

<details><summary>Logged reasoning block</summary>

```text
Now let me read the appendix files that have -ing issues.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "62c1ffd9-c5de-4061-9b2e-1c8fcaad87b4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017xkXHvDxAnSVEeKDWfcvEG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15722,
      "cache_read_input_tokens": 37036,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15722
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

Now let me read the appendix files with -ing issues.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "a795ad17-e36f-455f-9250-caa53ae14a12",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017xkXHvDxAnSVEeKDWfcvEG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15722,
      "cache_read_input_tokens": 37036,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15722
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

<details open><summary>🔧 Tool call — Read · `toolu_01W2gLAmtxKTBotPvndqGqWP`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_prompt_type.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "148d477d-88de-4510-bd23-88adabd7138f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017xkXHvDxAnSVEeKDWfcvEG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15722,
      "cache_read_input_tokens": 37036,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15722
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

_source line 39 · 2026-05-17T19:52:54.204Z_

<details><summary>↩ Tool result · `toolu_01W2gLAmtxKTBotPvndqGqWP`</summary>

```text
1	We evaluate depth fingerprinting under three prompt types using Pythia-2.8B: \emph{continuation} (``Continue the following text''), \emph{elaboration} (``Elaborate on the following text''), and \emph{inspired rewriting} (``Write a new passage inspired by the following text''). Each uses 995 seeds $\times$ 5 depths.
2	
3	\paragraph{Within-prompt-type classification.}
4	5-fold CV macro-F1: continuation 0.78, rewriting 0.74, elaboration 0.73. All three prompt types exhibit the same differential depth response pattern: drifting features (hapax ratio, TTR, entropy mean) show consistent monotonic trends, while stationary features (entropy std, tail decay) change by less than 5\%.
5	
6	\paragraph{Cross-prompt-type transfer (LOPTO).}
7	Leave-one-prompt-type-out evaluation yields average F1\,=\,0.753, confirming that depth signal transfers across prompt types. Feature decay rates differ: continuation shows the strongest drift (16.9\% per depth step), followed by rewriting (6.1\%) and elaboration (1.4\%), consistent with continuation chains applying less semantic constraint on the output.
8	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "db06917b-955b-4d00-8bd9-fb0fa30c8187",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_prompt_type.tex",
      "content": "We evaluate depth fingerprinting under three prompt types using Pythia-2.8B: \\emph{continuation} (``Continue the following text''), \\emph{elaboration} (``Elaborate on the following text''), and \\emph{inspired rewriting} (``Write a new passage inspired by the following text''). Each uses 995 seeds $\\times$ 5 depths.\n\n\\paragraph{Within-prompt-type classification.}\n5-fold CV macro-F1: continuation 0.78, rewriting 0.74, elaboration 0.73. All three prompt types exhibit the same differential depth response pattern: drifting features (hapax ratio, TTR, entropy mean) show consistent monotonic trends, while stationary features (entropy std, tail decay) change by less than 5\\%.\n\n\\paragraph{Cross-prompt-type transfer (LOPTO).}\nLeave-one-prompt-type-out evaluation yields average F1\\,=\\,0.753, confirming that depth signal transfers across prompt types. Feature decay rates differ: continuation shows the strongest drift (16.9\\% per depth step), followed by rewriting (6.1\\%) and elaboration (1.4\\%), consistent with continuation chains applying less semantic constraint on the output.\n",
      "numLines": 8,
      "startLine": 1,
      "totalLines": 8
    }
  }
}
```

</details>

---


### Tool call

_source line 40_

<details open><summary>🔧 Tool call — Read · `toolu_01KcC6KpagfB5LdoYJ9uriza`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_qlora.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "472287ab-adbe-40c6-a764-759f67dd998c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017xkXHvDxAnSVEeKDWfcvEG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15722,
      "cache_read_input_tokens": 37036,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15722
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

_source line 41 · 2026-05-17T19:52:54.688Z_

<details><summary>↩ Tool result · `toolu_01KcC6KpagfB5LdoYJ9uriza`</summary>

```text
1	To assess whether depth signal extends beyond handcrafted features, we fine-tune a pretrained language model end-to-end as a depth classifier using QLoRA \cite{qlora}.
2	
3	\paragraph{Setup.}
4	We fine-tune Qwen3-0.6B-Base with LoRA rank 16, learning rate $2 \times 10^{-4}$, and 3 epochs, framing depth estimation as 5-class sequence classification (gen-0 through gen-4).\footnote{Evaluated on the original 6-generator subset; XGBoost 3-class F1\,=\,0.789. We expect 8-generator training to further improve given additional diversity; the comparison direction is preserved.}
5	For 3-class evaluation, we collapse predictions into gen-0\,/\,gen-1\,/\,gen-2+ post hoc.
6	All results use the same LOGO protocol as the main experiments.
7	
8	\begin{table}[h]
9	\centering
10	\small
11	\caption{QLoRA end-to-end depth classification vs.\ XGBoost on handcrafted features, under LOGO evaluation.}
12	\label{tab:qlora}
13	\resizebox{\linewidth}{!}{%
14	\begin{tabular}{lccc}
15	\toprule
16	\textbf{Method} & \textbf{5-class F1} & \textbf{3-class F1} & \textbf{Per-class F1 (5-class)} \\
17	\midrule
18	XGBoost (7 features) & 0.501 $\pm$ 0.038 & 0.789 & --- \\
19	QLoRA (Qwen3-0.6B)   & 0.583 $\pm$ 0.010 & 0.905 $\pm$ 0.003 & 0.999\,/\,0.796\,/\,0.413\,/\,0.259\,/\,0.447 \\
20	\bottomrule
21	\end{tabular}}
22	\end{table}
23	
24	\paragraph{Results.}
25	QLoRA achieves 3-class LOGO F1\,=\,0.905 ($\pm$0.003), a +11.6\,pp improvement over the XGBoost baseline (0.789).
26	On 5-class evaluation, QLoRA reaches F1\,=\,0.583 ($\pm$0.010) vs.\ 0.501 for XGBoost (+8.2\,pp), with the largest gains at gen-1 (0.796 vs.\ 0.634) and gen-2 (0.413 vs.\ 0.268).
27	The gen-2/gen-3 boundary remains the primary failure mode (gen-3 F1\,=\,0.259), consistent with the feature-level analysis in \S\ref{sec:discussion}.
28	
29	\paragraph{Hyperparameter robustness.}
30	A second run with LoRA rank 32 and seed 123 yields 5-class F1\,=\,0.587 ($\pm$0.005) and 3-class F1\,=\,0.905 ($\pm$0.004), confirming stability across hyperparameter and seed variation ($\Delta < 1$\,pp on both metrics).
31	
32	\paragraph{Implications.}
33	The substantial 3-class improvement demonstrates that raw token embeddings contain depth signal beyond what summary statistics capture; the seven handcrafted features are a strong but lossy compression of the full distributional information.
34	End-to-end fine-tuning exploits token-level patterns (e.g., positional regularities, n-gram repetitions) that aggregate features cannot represent.
35	This confirms that the depth signal documented in our main analysis is real and exploitable beyond engineered features, while the handcrafted approach retains practical advantages: interpretability, computational efficiency (no GPU inference), and the ability to reveal the differential depth response pattern that motivates the task formulation.
36	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "8b8fc246-6a19-4789-88db-ddb4f439ce4a",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_qlora.tex",
      "content": "To assess whether depth signal extends beyond handcrafted features, we fine-tune a pretrained language model end-to-end as a depth classifier using QLoRA \\cite{qlora}.\n\n\\paragraph{Setup.}\nWe fine-tune Qwen3-0.6B-Base with LoRA rank 16, learning rate $2 \\times 10^{-4}$, and 3 epochs, framing depth estimation as 5-class sequence classification (gen-0 through gen-4).\\footnote{Evaluated on the original 6-generator subset; XGBoost 3-class F1\\,=\\,0.789. We expect 8-generator training to further improve given additional diversity; the comparison direction is preserved.}\nFor 3-class evaluation, we collapse predictions into gen-0\\,/\\,gen-1\\,/\\,gen-2+ post hoc.\nAll results use the same LOGO protocol as the main experiments.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{QLoRA end-to-end depth classification vs.\\ XGBoost on handcrafted features, under LOGO evaluation.}\n\\label{tab:qlora}\n\\resizebox{\\linewidth}{!}{%\n\\begin{tabular}{lccc}\n\\toprule\n\\textbf{Method} & \\textbf{5-class F1} & \\textbf{3-class F1} & \\textbf{Per-class F1 (5-class)} \\\\\n\\midrule\nXGBoost (7 features) & 0.501 $\\pm$ 0.038 & 0.789 & --- \\\\\nQLoRA (Qwen3-0.6B)   & 0.583 $\\pm$ 0.010 & 0.905 $\\pm$ 0.003 & 0.999\\,/\\,0.796\\,/\\,0.413\\,/\\,0.259\\,/\\,0.447 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Results.}\nQLoRA achieves 3-class LOGO F1\\,=\\,0.905 ($\\pm$0.003), a +11.6\\,pp improvement over the XGBoost baseline (0.789).\nOn 5-class evaluation, QLoRA reaches F1\\,=\\,0.583 ($\\pm$0.010) vs.\\ 0.501 for XGBoost (+8.2\\,pp), with the largest gains at gen-1 (0.796 vs.\\ 0.634) and gen-2 (0.413 vs.\\ 0.268).\nThe gen-2/gen-3 boundary remains the primary failure mode (gen-3 F1\\,=\\,0.259), consistent with the feature-level analysis in \\S\\ref{sec:discussion}.\n\n\\paragraph{Hyperparameter robustness.}\nA second run with LoRA rank 32 and seed 123 yields 5-class F1\\,=\\,0.587 ($\\pm$0.005) and 3-class F1\\,=\\,0.905 ($\\pm$0.004), confirming stability across hyperparameter and seed variation ($\\Delta < 1$\\,pp on both metrics).\n\n\\paragraph{Implications.}\nThe substantial 3-class improvement demonstrates that raw token embeddings contain depth signal beyond what summary statistics capture; the seven handcrafted features are a strong but lossy compression of the full distributional information.\nEnd-to-end fine-tuning exploits token-level patterns (e.g., positional regularities, n-gram repetitions) that aggregate features cannot represent.\nThis confirms that the depth signal documented in our main analysis is real and exploitable beyond engineered features, while the handcrafted approach retains practical advantages: interpretability, computational efficiency (no GPU inference), and the ability to reveal the differential depth response pattern that motivates the task formulation.\n",
      "numLines": 36,
      "startLine": 1,
      "totalLines": 36
    }
  }
}
```

</details>

---


### Tool call

_source line 42_

<details open><summary>🔧 Tool call — Read · `toolu_01MGvdDAVotdBKrhb4NyqysK`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_cross_temp.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "02e25e65-cd4b-456e-826f-b4cb76552f31",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017xkXHvDxAnSVEeKDWfcvEG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15722,
      "cache_read_input_tokens": 37036,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15722
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

_source line 43 · 2026-05-17T19:52:58.214Z_

<details><summary>↩ Tool result · `toolu_01MGvdDAVotdBKrhb4NyqysK`</summary>

```text
1	Figure~\ref{fig:cross-temp} shows cross-temperature transfer results for the 6-generator LOGO pipeline.
2	We evaluate four train$\rightarrow$test temperature conditions using Qwen3-1.7B data regenerated at $t{=}1.0$ (remaining five generators retain $t{=}0.7$).
3	
4	\begin{figure*}[ht]
5	\centering
6	\includegraphics[width=\textwidth]{fig_appendix_cross_temp.pdf}
7	\caption{Cross-temperature transfer evaluation (6-gen LOGO). (a) Overall F1 by train$\rightarrow$test temperature condition. Matched conditions (0.7$\rightarrow$0.7, 1.0$\rightarrow$1.0) outperform cross-temperature transfer, with 0.7$\rightarrow$1.0 showing the largest degradation ($-6.6$\,pp in 3-class F1). (b) Per-generator 3-class F1 heatmap: Qwen3-1.7B shows dramatic degradation under cross-temperature conditions (0.418) while other generators remain stable, indicating the temperature mismatch disproportionately affects the generator whose data was regenerated.}
8	\label{fig:cross-temp}
9	\end{figure*}
10	
11	Key observations from the cross-temperature analysis:
12	
13	\begin{enumerate}[nosep]
14	\item \textbf{Matched-temperature robustness}: Both $t{=}0.7$ and $t{=}1.0$ matched conditions yield comparable performance (3-class F1: 0.789 vs.\ 0.726), with the gap attributable to weaker depth signal at high temperature rather than classifier degradation.
15	
16	\item \textbf{Asymmetric transfer}: Training at $t{=}1.0$ and testing at $t{=}0.7$ (F1\,=\,0.791) transfers well, but the reverse (0.7$\rightarrow$1.0, F1\,=\,0.723) degrades. This asymmetry reflects the information structure: features learned from high-variance (high-temperature) data generalize to low-variance settings, but not vice versa.
17	
18	\item \textbf{Generator-specific vulnerability}: Qwen3-1.7B, the only generator with temperature-mismatched test data, drops to F1\,=\,0.418 under cross-temperature conditions while all other generators maintain F1 $>$ 0.76. This confirms that depth features are calibrated to the specific decoding regime.
19	
20	\item \textbf{Binary robustness}: Binary classification (gen-0/1 vs.\ gen-2+) is more robust to temperature mismatch (0.900--0.958 across all conditions) than 3-class, suggesting the coarser gen-0 vs.\ machine boundary is less sensitive to decoding parameters than fine-grained depth discrimination.
21	\end{enumerate}
22	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "86de5af9-c44b-4b40-80be-b4f2895df7d1",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_cross_temp.tex",
      "content": "Figure~\\ref{fig:cross-temp} shows cross-temperature transfer results for the 6-generator LOGO pipeline.\nWe evaluate four train$\\rightarrow$test temperature conditions using Qwen3-1.7B data regenerated at $t{=}1.0$ (remaining five generators retain $t{=}0.7$).\n\n\\begin{figure*}[ht]\n\\centering\n\\includegraphics[width=\\textwidth]{fig_appendix_cross_temp.pdf}\n\\caption{Cross-temperature transfer evaluation (6-gen LOGO). (a) Overall F1 by train$\\rightarrow$test temperature condition. Matched conditions (0.7$\\rightarrow$0.7, 1.0$\\rightarrow$1.0) outperform cross-temperature transfer, with 0.7$\\rightarrow$1.0 showing the largest degradation ($-6.6$\\,pp in 3-class F1). (b) Per-generator 3-class F1 heatmap: Qwen3-1.7B shows dramatic degradation under cross-temperature conditions (0.418) while other generators remain stable, indicating the temperature mismatch disproportionately affects the generator whose data was regenerated.}\n\\label{fig:cross-temp}\n\\end{figure*}\n\nKey observations from the cross-temperature analysis:\n\n\\begin{enumerate}[nosep]\n\\item \\textbf{Matched-temperature robustness}: Both $t{=}0.7$ and $t{=}1.0$ matched conditions yield comparable performance (3-class F1: 0.789 vs.\\ 0.726), with the gap attributable to weaker depth signal at high temperature rather than classifier degradation.\n\n\\item \\textbf{Asymmetric transfer}: Training at $t{=}1.0$ and testing at $t{=}0.7$ (F1\\,=\\,0.791) transfers well, but the reverse (0.7$\\rightarrow$1.0, F1\\,=\\,0.723) degrades. This asymmetry reflects the information structure: features learned from high-variance (high-temperature) data generalize to low-variance settings, but not vice versa.\n\n\\item \\textbf{Generator-specific vulnerability}: Qwen3-1.7B, the only generator with temperature-mismatched test data, drops to F1\\,=\\,0.418 under cross-temperature conditions while all other generators maintain F1 $>$ 0.76. This confirms that depth features are calibrated to the specific decoding regime.\n\n\\item \\textbf{Binary robustness}: Binary classification (gen-0/1 vs.\\ gen-2+) is more robust to temperature mismatch (0.900--0.958 across all conditions) than 3-class, suggesting the coarser gen-0 vs.\\ machine boundary is less sensitive to decoding parameters than fine-grained depth discrimination.\n\\end{enumerate}\n",
      "numLines": 22,
      "startLine": 1,
      "totalLines": 22
    }
  }
}
```

</details>

---


### Tool call

_source line 44_

<details open><summary>🔧 Tool call — Read · `toolu_01S2fjzooz64wzDcei8vBmbz`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_confusion_matrix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "a917bb68-69b9-422c-bdb1-9879818a2b11",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017xkXHvDxAnSVEeKDWfcvEG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15722,
      "cache_read_input_tokens": 37036,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15722
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

_source line 45 · 2026-05-17T19:52:58.288Z_

<details><summary>↩ Tool result · `toolu_01S2fjzooz64wzDcei8vBmbz`</summary>

```text
1	Table~\ref{tab:confusion} reports the aggregated confusion matrix from the original six-generator subset (Pythia-2.8B, Pythia-1B, OLMo-2-1B, Qwen3-1.7B, Qwen3-0.6B, Qwen3-8B) under leave-one-generator-out (LOGO) evaluation, collapsed to three ordinal classes: gen-0 (human), gen-1 (first-generation), and gen-2+ (depth $\geq$ 2).
2	The later-added Llama-3.2-3B and Mistral-7B-v0.3 are evaluated in the full 8-generator LOGO results (Table~\ref{tab:logo-results}).
3	
4	\begin{table}[h]
5	\centering
6	\small
7	\resizebox{\linewidth}{!}{%
8	\begin{tabular}{lccc}
9	\toprule
10	& \textbf{Pred gen-0} & \textbf{Pred gen-1} & \textbf{Pred gen-2+} \\
11	\midrule
12	\textbf{True gen-0} & 5{,}937 (99.4\%) & 35 (0.6\%) & 0 (0.0\%) \\
13	\textbf{True gen-1} & 368 (6.2\%) & 4{,}437 (75.0\%) & 1{,}113 (18.8\%) \\
14	\textbf{True gen-2+} & 464 (3.0\%) & 3{,}646 (23.3\%) & 11{,}529 (73.7\%) \\
15	\bottomrule
16	\end{tabular}}
17	\caption{Aggregated 3-class confusion matrix from 6-generator LOGO evaluation ($N=27{,}529$). Each cell shows count and row-normalized percentage. Gen-0 is near-perfectly identified. Gen-1 errors are asymmetric: misclassification as gen-2+ (18.8\%) is 3$\times$ more frequent than as gen-0 (6.2\%), indicating that gen-1 text already carries detectable recursive distortion.}
18	\label{tab:confusion}
19	\end{table}
20	
21	Figure~\ref{fig:confusion-heatmap} provides a heatmap visualization of the confusion matrix.
22	The row-normalized view highlights near-perfect gen-0 classification (99.4\% recall), gen-1 confusion primarily with gen-2+ (18.8\%) rather than gen-0 (6.2\%), and gen-2+ misclassification predominantly into gen-1 (23.3\%), consistent with DDR predictions.
23	
24	\begin{figure*}[ht]
25	\centering
26	\includegraphics[width=0.85\textwidth]{fig_appendix_confusion.pdf}
27	\caption{3-class LOGO confusion matrix ($N$\,=\,27{,}529). (a) Raw counts. (b) Row-normalized recall percentages. Gen-0 achieves near-perfect classification; the primary confusion axis is gen-1 $\leftrightarrow$ gen-2+.}
28	\label{fig:confusion-heatmap}
29	\end{figure*}
30	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "70c18dfc-78a4-4fc6-9cd1-2005bacd4f17",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_confusion_matrix.tex",
      "content": "Table~\\ref{tab:confusion} reports the aggregated confusion matrix from the original six-generator subset (Pythia-2.8B, Pythia-1B, OLMo-2-1B, Qwen3-1.7B, Qwen3-0.6B, Qwen3-8B) under leave-one-generator-out (LOGO) evaluation, collapsed to three ordinal classes: gen-0 (human), gen-1 (first-generation), and gen-2+ (depth $\\geq$ 2).\nThe later-added Llama-3.2-3B and Mistral-7B-v0.3 are evaluated in the full 8-generator LOGO results (Table~\\ref{tab:logo-results}).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\linewidth}{!}{%\n\\begin{tabular}{lccc}\n\\toprule\n& \\textbf{Pred gen-0} & \\textbf{Pred gen-1} & \\textbf{Pred gen-2+} \\\\\n\\midrule\n\\textbf{True gen-0} & 5{,}937 (99.4\\%) & 35 (0.6\\%) & 0 (0.0\\%) \\\\\n\\textbf{True gen-1} & 368 (6.2\\%) & 4{,}437 (75.0\\%) & 1{,}113 (18.8\\%) \\\\\n\\textbf{True gen-2+} & 464 (3.0\\%) & 3{,}646 (23.3\\%) & 11{,}529 (73.7\\%) \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Aggregated 3-class confusion matrix from 6-generator LOGO evaluation ($N=27{,}529$). Each cell shows count and row-normalized percentage. Gen-0 is near-perfectly identified. Gen-1 errors are asymmetric: misclassification as gen-2+ (18.8\\%) is 3$\\times$ more frequent than as gen-0 (6.2\\%), indicating that gen-1 text already carries detectable recursive distortion.}\n\\label{tab:confusion}\n\\end{table}\n\nFigure~\\ref{fig:confusion-heatmap} provides a heatmap visualization of the confusion matrix.\nThe row-normalized view highlights near-perfect gen-0 classification (99.4\\% recall), gen-1 confusion primarily with gen-2+ (18.8\\%) rather than gen-0 (6.2\\%), and gen-2+ misclassification predominantly into gen-1 (23.3\\%), consistent with DDR predictions.\n\n\\begin{figure*}[ht]\n\\centering\n\\includegraphics[width=0.85\\textwidth]{fig_appendix_confusion.pdf}\n\\caption{3-class LOGO confusion matrix ($N$\\,=\\,27{,}529). (a) Raw counts. (b) Row-normalized recall percentages. Gen-0 achieves near-perfect classification; the primary confusion axis is gen-1 $\\leftrightarrow$ gen-2+.}\n\\label{fig:confusion-heatmap}\n\\end{figure*}\n",
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

_source line 46_

<details open><summary>🔧 Tool call — Read · `toolu_01XwitXJHRrn7FSA7aXtXTUc`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_downstream.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "e5c976d1-5aa9-4481-8836-f028eaa46da6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017xkXHvDxAnSVEeKDWfcvEG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15722,
      "cache_read_input_tokens": 37036,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15722
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

_source line 47 · 2026-05-17T19:52:58.387Z_

<details><summary>↩ Tool result · `toolu_01XwitXJHRrn7FSA7aXtXTUc`</summary>

```text
1	Can depth-aware data curation improve downstream language model quality?
2	We fine-tune OLMo-2-0425-1B on five data variants (3 seeds each) and evaluate perplexity on a held-out test set (Table~\ref{tab:downstream}).
3	
4	\begin{table}[h]
5	\centering
6	\small
7	\begin{tabular}{lrc}
8	\toprule
9	\textbf{Variant} & \textbf{$n$} & \textbf{Test PPL} \\
10	\midrule
11	All depths            & 12{,}299 & 2.335 $\pm$ 0.000 \\
12	Size-matched (random) & 3{,}951  & 2.367 $\pm$ 0.000 \\
13	Depth 0--1 only       & 3{,}951  & 2.387 $\pm$ 0.001 \\
14	Binary-filtered       & 3{,}951  & 2.389 $\pm$ 0.000 \\
15	Depth 0 only          & 797      & 2.681 $\pm$ 0.001 \\
16	\bottomrule
17	\end{tabular}
18	\caption{Downstream fine-tuning perplexity (OLMo-2-0425-1B, mean $\pm$ std across 3 seeds). At equal sample count, random subsampling (2.367) outperforms depth-aware curation (depth 0--1: 2.387, binary-filtered: 2.389).}
19	\label{tab:downstream}
20	\end{table}
21	
22	The results are unambiguous: data quantity dominates depth composition.
23	Training on all 12{,}299 samples yields the lowest perplexity (2.335).
24	At equal sample count ($n$\,=\,3{,}951), random subsampling (2.367) \emph{outperforms} both depth-stratified selection (depth 0--1: 2.387) and binary detection filtering (2.389).
25	Cross-seed variance is below 0.002 across all variants, confirming the robustness of this null result.
26	
27	Restricting training to human-only text (depth 0, $n$\,=\,797) produces a sharp perplexity increase to 2.681, driven primarily by the 5$\times$ reduction in data volume rather than depth composition per se.
28	
29	\paragraph{Equivalence testing.}
30	We apply a two one-sided $t$-test (TOST) with a $\pm$2\% relative margin (equivalence bounds $\pm$0.047 on the ppl scale) to formally assess whether the depth-aware and random subsampling conditions produce practically indistinguishable perplexity.
31	At equal sample count ($n$\,=\,3{,}951): size-matched (random) ppl\,=\,2.367 vs.\ depth 0--1 ppl\,=\,2.387, $\Delta$\,=\,0.020.
32	TOST confirms equivalence ($p = 1.1 \times 10^{-4}$), indicating the two curation strategies yield practically indistinguishable downstream quality within the $\pm$2\% margin.
33	Cross-seed standard deviation is below 0.001 for both variants.
34	
35	Comparing the full dataset ($n$\,=\,12{,}299, ppl\,=\,2.335) against the depth-filtered subset ($n$\,=\,3{,}951, ppl\,=\,2.387): TOST \emph{rejects} equivalence (minimum equivalence margin\,=\,0.053, exceeding the $\pm$2\% bound), confirming that data quantity drives perplexity reduction beyond what depth-aware selection can recover.
36	
37	Knowing the generation depth of a document does not, by itself, make it more or less useful for training; at fixed sample count, depth-aware curation is statistically equivalent to uninformed random subsampling.
38	
39	\subsection*{Margin Sensitivity Analysis}
40	
41	To assess the robustness of the equivalence conclusion to margin choice, we repeat the TOST procedure across multiple equivalence margins \cite{lakens_equivalence}, following the recommendation to report sensitivity across plausible bounds rather than relying on a single threshold (Table~\ref{tab:tost-margins}).
42	
43	\begin{table}[h]
44	\centering
45	\small
46	\resizebox{\linewidth}{!}{%
47	\begin{tabular}{llcc}
48	\toprule
49	\textbf{Comparison} & \textbf{Margin} & \textbf{Equiv?} & \textbf{TOST $p$} \\
50	\midrule
51	Full (12{,}299) vs.\ Random (3{,}951) & $\pm$1\% & No & 1.0 \\
52	                                        & $\pm$2\% & Yes & $1 \times 10^{-6}$ \\
53	                                        & $\pm$3\% & Yes & $< 10^{-10}$ \\
54	                                        & $\pm$5\% & Yes & $< 10^{-10}$ \\
55	\midrule
56	Full (12{,}299) vs.\ Depth 0--1 (3{,}951) & $\pm$1\% & No & 1.0 \\
57	                                            & $\pm$2\% & No & 1.0 \\
58	                                            & $\pm$3\% & Yes & $< 10^{-10}$ \\
59	                                            & $\pm$5\% & Yes & $< 10^{-10}$ \\
60	\bottomrule
61	\end{tabular}}
62	\caption{TOST equivalence testing across multiple margins. ``Equiv?'' indicates whether equivalence is established at $\alpha = 0.05$.}
63	\label{tab:tost-margins}
64	\end{table}
65	
66	The full dataset vs.\ random subsample comparison passes equivalence at the $\pm$2\% margin ($p = 10^{-6}$), while the full vs.\ depth 0--1 comparison requires a $\pm$3\% margin.
67	In absolute terms, perplexity differences are small: $\Delta$\,=\,0.032 (full vs.\ random, 1.4\% of baseline) and $\Delta$\,=\,0.052 (full vs.\ depth 0--1, 2.2\% of baseline).
68	
69	Cohen's $d$ values are 86.0 (full vs.\ random) and 119.7 (full vs.\ depth 0--1).
70	These appear large but are unreliable: with only $n$\,=\,3 seeds per condition, the pooled standard deviation is extremely small ($<$0.001), artificially inflating $d$.
71	The inflated effect sizes reflect low seed-level variance (confirming reproducibility) rather than practically meaningful perplexity differences.
72	The TOST framework with pre-specified relative margins provides a more appropriate assessment than Cohen's $d$ in this low-seed regime.
73	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "5b43c80b-5f23-4032-b356-f666d68b9d86",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_downstream.tex",
      "content": "Can depth-aware data curation improve downstream language model quality?\nWe fine-tune OLMo-2-0425-1B on five data variants (3 seeds each) and evaluate perplexity on a held-out test set (Table~\\ref{tab:downstream}).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{lrc}\n\\toprule\n\\textbf{Variant} & \\textbf{$n$} & \\textbf{Test PPL} \\\\\n\\midrule\nAll depths            & 12{,}299 & 2.335 $\\pm$ 0.000 \\\\\nSize-matched (random) & 3{,}951  & 2.367 $\\pm$ 0.000 \\\\\nDepth 0--1 only       & 3{,}951  & 2.387 $\\pm$ 0.001 \\\\\nBinary-filtered       & 3{,}951  & 2.389 $\\pm$ 0.000 \\\\\nDepth 0 only          & 797      & 2.681 $\\pm$ 0.001 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Downstream fine-tuning perplexity (OLMo-2-0425-1B, mean $\\pm$ std across 3 seeds). At equal sample count, random subsampling (2.367) outperforms depth-aware curation (depth 0--1: 2.387, binary-filtered: 2.389).}\n\\label{tab:downstream}\n\\end{table}\n\nThe results are unambiguous: data quantity dominates depth composition.\nTraining on all 12{,}299 samples yields the lowest perplexity (2.335).\nAt equal sample count ($n$\\,=\\,3{,}951), random subsampling (2.367) \\emph{outperforms} both depth-stratified selection (depth 0--1: 2.387) and binary detection filtering (2.389).\nCross-seed variance is below 0.002 across all variants, confirming the robustness of this null result.\n\nRestricting training to human-only text (depth 0, $n$\\,=\\,797) produces a sharp perplexity increase to 2.681, driven primarily by the 5$\\times$ reduction in data volume rather than depth composition per se.\n\n\\paragraph{Equivalence testing.}\nWe apply a two one-sided $t$-test (TOST) with a $\\pm$2\\% relative margin (equivalence bounds $\\pm$0.047 on the ppl scale) to formally assess whether the depth-aware and random subsampling conditions produce practically indistinguishable perplexity.\nAt equal sample count ($n$\\,=\\,3{,}951): size-matched (random) ppl\\,=\\,2.367 vs.\\ depth 0--1 ppl\\,=\\,2.387, $\\Delta$\\,=\\,0.020.\nTOST confirms equivalence ($p = 1.1 \\times 10^{-4}$), indicating the two curation strategies yield practically indistinguishable downstream quality within the $\\pm$2\\% margin.\nCross-seed standard deviation is below 0.001 for both variants.\n\nComparing the full dataset ($n$\\,=\\,12{,}299, ppl\\,=\\,2.335) against the depth-filtered subset ($n$\\,=\\,3{,}951, ppl\\,=\\,2.387): TOST \\emph{rejects} equivalence (minimum equivalence margin\\,=\\,0.053, exceeding the $\\pm$2\\% bound), confirming that data quantity drives perplexity reduction beyond what depth-aware selection can recover.\n\nKnowing the generation depth of a document does not, by itself, make it more or less useful for training; at fixed sample count, depth-aware curation is statistically equivalent to uninformed random subsampling.\n\n\\subsection*{Margin Sensitivity Analysis}\n\nTo assess the robustness of the equivalence conclusion to margin choice, we repeat the TOST procedure across multiple equivalence margins \\cite{lakens_equivalence}, following the recommendation to report sensitivity across plausible bounds rather than relying on a single threshold (Table~\\ref{tab:tost-margins}).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\linewidth}{!}{%\n\\begin{tabular}{llcc}\n\\toprule\n\\textbf{Comparison} & \\textbf{Margin} & \\textbf{Equiv?} & \\textbf{TOST $p$} \\\\\n\\midrule\nFull (12{,}299) vs.\\ Random (3{,}951) & $\\pm$1\\% & No & 1.0 \\\\\n                                        & $\\pm$2\\% & Yes & $1 \\times 10^{-6}$ \\\\\n                                        & $\\pm$3\\% & Yes & $< 10^{-10}$ \\\\\n                                        & $\\pm$5\\% & Yes & $< 10^{-10}$ \\\\\n\\midrule\nFull (12{,}299) vs.\\ Depth 0--1 (3{,}951) & $\\pm$1\\% & No & 1.0 \\\\\n                                            & $\\pm$2\\% & No & 1.0 \\\\\n                                            & $\\pm$3\\% & Yes & $< 10^{-10}$ \\\\\n                                            & $\\pm$5\\% & Yes & $< 10^{-10}$ \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{TOST equivalence testing across multiple margins. ``Equiv?'' indicates whether equivalence is established at $\\alpha = 0.05$.}\n\\label{tab:tost-margins}\n\\end{table}\n\nThe full dataset vs.\\ random subsample comparison passes equivalence at the $\\pm$2\\% margin ($p = 10^{-6}$), while the full vs.\\ depth 0--1 comparison requires a $\\pm$3\\% margin.\nIn absolute terms, perplexity differences are small: $\\Delta$\\,=\\,0.032 (full vs.\\ random, 1.4\\% of baseline) and $\\Delta$\\,=\\,0.052 (full vs.\\ depth 0--1, 2.2\\% of baseline).\n\nCohen's $d$ values are 86.0 (full vs.\\ random) and 119.7 (full vs.\\ depth 0--1).\nThese appear large but are unreliable: with only $n$\\,=\\,3 seeds per condition, the pooled standard deviation is extremely small ($<$0.001), artificially inflating $d$.\nThe inflated effect sizes reflect low seed-level variance (confirming reproducibility) rather than practically meaningful perplexity differences.\nThe TOST framework with pre-specified relative margins provides a more appropriate assessment than Cohen's $d$ in this low-seed regime.\n",
      "numLines": 73,
      "startLine": 1,
      "totalLines": 73
    }
  }
}
```

</details>

---


### Tool call

_source line 48_

<details open><summary>🔧 Tool call — Read · `toolu_01Dqm1YziFy7LQKRJZmgfnEH`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_human_edit.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "9314f1f6-5221-446f-8a02-467d07a4cc15",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017xkXHvDxAnSVEeKDWfcvEG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15722,
      "cache_read_input_tokens": 37036,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15722
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

_source line 49 · 2026-05-17T19:52:58.514Z_

<details><summary>↩ Tool result · `toolu_01Dqm1YziFy7LQKRJZmgfnEH`</summary>

```text
1	We assess robustness to post-generation text modification by randomly replacing words at varying rates and re-evaluating the 8-generator LOGO pipeline (Table~\ref{tab:human-edit}).
2	Random word replacement represents a worst-case perturbation: real human editing preserves semantic coherence, so practical degradation is expected to be substantially lower than these estimates.
3	
4	\begin{table}[h]
5	\centering
6	\small
7	\caption{Robustness to random word replacement under 8-gen LOGO evaluation (binary: gen-1 vs.\ gen-2+). Bootstrap 95\% CIs on binary F1 ($n$\,=\,1000).}
8	\label{tab:human-edit}
9	\resizebox{\linewidth}{!}{%
10	\begin{tabular}{lccc}
11	\toprule
12	\textbf{Perturbation rate} & \textbf{Binary F1} & \textbf{95\% CI} & \textbf{3-class F1} \\
13	\midrule
14	0\% (baseline) & 0.695 & [0.680, 0.710] & 0.737 \\
15	5\%            & 0.650 & [0.635, 0.666] & 0.641 \\
16	10\%           & 0.614 & [0.599, 0.629] & 0.492 \\
17	20\%           & 0.591 & [0.576, 0.605] & 0.367 \\
18	\bottomrule
19	\end{tabular}}
20	\end{table}
21	
22	Binary depth discrimination (gen-1 vs.\ gen-2+) degrades sublinearly: the first 5\% replacement causes the largest drop ($-$4.6\,pp), with diminishing marginal impact thereafter ($-$3.6\,pp for 5\%$\to$10\%, $-$2.3\,pp for 10\%$\to$20\%).
23	At 10\% replacement, binary F1 remains 0.614, well above the 0.50 random baseline, indicating that depth signal survives moderate perturbation.
24	
25	Three-class classification is more sensitive (0.737$\to$0.367 at 20\%), because distinguishing gen-0 from gen-1 relies heavily on lexical diversity features (TTR, hapax ratio) that are directly disrupted by word replacement.
26	The binary metric, which excludes gen-0, is inherently more robust since it depends primarily on reference-model entropy features distributed across many tokens.
27	
28	\paragraph{Feature subset degradation.}
29	Table~\ref{tab:feature-degrade} compares perturbation robustness of the full 7-feature ensemble against an entropy-only subset (5 reference-model features).
30	The higher unperturbed binary F1 of the entropy-only subset (0.833 vs.\ 0.695) reflects the strong discriminability of reference-model features for the coarse binary task (gen-1 vs.\ gen-2+); however, lexical features are essential for the finer-grained ordinal task (3-class F1: 0.737 vs.\ 0.688) and provide greater robustness under perturbation.
31	At 20\% replacement, the 7-feature ensemble surpasses entropy-only on binary F1 (0.591 vs.\ 0.569), despite starting from a lower baseline.
32	Random word replacement drastically alters per-token context, making entropy features (computed over the full token sequence) extremely sensitive to noise.
33	Lexical features (TTR, hapax ratio), as document-level summary statistics, are more stable under per-word perturbation and act as stabilizers in the full ensemble.
34	The crossover confirms that degradation in the full feature set reflects genuine signal disruption rather than a lexical-feature artifact.
35	
36	\begin{table}[h]
37	\centering
38	\small
39	\caption{Feature subset degradation under random word replacement (8-gen LOGO). Entropy-only: 5 reference-model features; 7-feature: full ensemble including lexical features.}
40	\label{tab:feature-degrade}
41	\resizebox{\linewidth}{!}{%
42	\begin{tabular}{lcccc}
43	\toprule
44	\textbf{Perturb.} & \textbf{Ent-only Bin} & \textbf{7-feat Bin} & \textbf{Ent-only 3-cl} & \textbf{7-feat 3-cl} \\
45	\midrule
46	0\%  & 0.833 & 0.695 & 0.688 & 0.737 \\
47	5\%  & 0.738 & 0.650 & 0.539 & 0.641 \\
48	10\% & 0.667 & 0.614 & 0.427 & 0.492 \\
49	20\% & 0.569 & 0.591 & 0.314 & 0.367 \\
50	\bottomrule
51	\end{tabular}}
52	\end{table}
53	
54	\paragraph{Baseline comparison.}
55	Table~\ref{tab:baseline-robustness} compares robustness across detection methods under identical perturbation conditions (8-gen LOGO, binary: gen-1 vs.\ gen-2+).
56	
57	\begin{table}[h]
58	\centering
59	\small
60	\caption{Baseline robustness under random word replacement (8-gen LOGO, binary F1). Bold indicates highest F1 at each perturbation rate.}
61	\label{tab:baseline-robustness}
62	\begin{tabular}{lcccc}
63	\toprule
64	\textbf{Method} & \textbf{0\%} & \textbf{5\%} & \textbf{10\%} & \textbf{20\%} \\
65	\midrule
66	7-feature ensemble & \textbf{0.695} & 0.650 & 0.614 & 0.591 \\
67	LD-Score           & 0.677 & \textbf{0.673} & \textbf{0.677} & \textbf{0.671} \\
68	Avg-LogProb        & 0.682 & 0.419 & 0.335 & 0.375 \\
69	FastDetectGPT      & 0.571 & 0.437 & 0.468 & 0.514 \\
70	Binoculars\textsuperscript{\dag}         & 0.500 & 0.461 & 0.446 & 0.425 \\
71	\bottomrule
72	\end{tabular}
73	
74	\vspace{2pt}
75	{\footnotesize \textsuperscript{\dag}Binoculars operates at chance level on this binary task; its degradation figures are not meaningful.}
76	\end{table}
77	
78	The 7-feature ensemble achieves the highest unperturbed binary F1 (0.695), but LD-Score surpasses it under perturbation due to near-zero degradation ($-$0.6\,pp across the full 0\%$\to$20\% range).
79	FastDetectGPT and Avg-LogProb exhibit non-monotonic degradation at higher perturbation rates, likely because severe perturbation introduces distributional artifacts that these token-level methods detect as anomalous.
80	Avg-LogProb is the most fragile overall ($-$34.7\,pp at 10\%), while FastDetectGPT drops sharply at 5\% ($-$13.4\,pp) before partially recovering.
81	LD-Score is nearly invariant to perturbation, consistent with its reliance on corpus-level distributional divergence rather than per-token likelihoods.
82	The 7-feature ensemble offers the highest starting performance among single-reference methods, with sublinear degradation ($-$10.4\,pp at 20\%).
83	
84	\paragraph{LLM-simulated sentence regeneration.}
85	To test robustness under semantically coherent editing, we use Qwen3-0.6B-Base to randomly regenerate 1--3 sentences per passage (avg 1.69 sentences, ${\sim}$50\% edit distance) and re-evaluate the 8-gen LOGO pipeline.
86	Binary F1 drops from 0.692 to 0.647 ($-$4.5\,pp, 6.5\% relative); 3-class F1 drops from 0.739 to 0.667 ($-$7.1\,pp, 9.7\% relative).
87	The binary degradation ($-$4.5\,pp) is nearly identical to that caused by 5\% random word replacement ($-$4.6\,pp), despite the LLM rephrase altering ${\sim}$50\% of characters.
88	This asymmetry arises because LLM-generated replacements preserve the underlying statistical fingerprint of the generation process (entropy dynamics, depth-accumulated distributional drift), whereas random word substitution directly destroys local statistical signals.
89	Depth fingerprinting thus captures deep generative structure that survives semantic-preserving edits.
90	
91	\paragraph{Seed complexity.}
92	Performance is stable across seed text complexity: stratifying seeds by vocabulary richness (TTR terciles) yields maximum F1 variation of 1.1\,pp across groups.
93	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "7832c11d-6ae9-412e-86b1-dbab2223c915",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_human_edit.tex",
      "content": "We assess robustness to post-generation text modification by randomly replacing words at varying rates and re-evaluating the 8-generator LOGO pipeline (Table~\\ref{tab:human-edit}).\nRandom word replacement represents a worst-case perturbation: real human editing preserves semantic coherence, so practical degradation is expected to be substantially lower than these estimates.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Robustness to random word replacement under 8-gen LOGO evaluation (binary: gen-1 vs.\\ gen-2+). Bootstrap 95\\% CIs on binary F1 ($n$\\,=\\,1000).}\n\\label{tab:human-edit}\n\\resizebox{\\linewidth}{!}{%\n\\begin{tabular}{lccc}\n\\toprule\n\\textbf{Perturbation rate} & \\textbf{Binary F1} & \\textbf{95\\% CI} & \\textbf{3-class F1} \\\\\n\\midrule\n0\\% (baseline) & 0.695 & [0.680, 0.710] & 0.737 \\\\\n5\\%            & 0.650 & [0.635, 0.666] & 0.641 \\\\\n10\\%           & 0.614 & [0.599, 0.629] & 0.492 \\\\\n20\\%           & 0.591 & [0.576, 0.605] & 0.367 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\nBinary depth discrimination (gen-1 vs.\\ gen-2+) degrades sublinearly: the first 5\\% replacement causes the largest drop ($-$4.6\\,pp), with diminishing marginal impact thereafter ($-$3.6\\,pp for 5\\%$\\to$10\\%, $-$2.3\\,pp for 10\\%$\\to$20\\%).\nAt 10\\% replacement, binary F1 remains 0.614, well above the 0.50 random baseline, indicating that depth signal survives moderate perturbation.\n\nThree-class classification is more sensitive (0.737$\\to$0.367 at 20\\%), because distinguishing gen-0 from gen-1 relies heavily on lexical diversity features (TTR, hapax ratio) that are directly disrupted by word replacement.\nThe binary metric, which excludes gen-0, is inherently more robust since it depends primarily on reference-model entropy features distributed across many tokens.\n\n\\paragraph{Feature subset degradation.}\nTable~\\ref{tab:feature-degrade} compares perturbation robustness of the full 7-feature ensemble against an entropy-only subset (5 reference-model features).\nThe higher unperturbed binary F1 of the entropy-only subset (0.833 vs.\\ 0.695) reflects the strong discriminability of reference-model features for the coarse binary task (gen-1 vs.\\ gen-2+); however, lexical features are essential for the finer-grained ordinal task (3-class F1: 0.737 vs.\\ 0.688) and provide greater robustness under perturbation.\nAt 20\\% replacement, the 7-feature ensemble surpasses entropy-only on binary F1 (0.591 vs.\\ 0.569), despite starting from a lower baseline.\nRandom word replacement drastically alters per-token context, making entropy features (computed over the full token sequence) extremely sensitive to noise.\nLexical features (TTR, hapax ratio), as document-level summary statistics, are more stable under per-word perturbation and act as stabilizers in the full ensemble.\nThe crossover confirms that degradation in the full feature set reflects genuine signal disruption rather than a lexical-feature artifact.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Feature subset degradation under random word replacement (8-gen LOGO). Entropy-only: 5 reference-model features; 7-feature: full ensemble including lexical features.}\n\\label{tab:feature-degrade}\n\\resizebox{\\linewidth}{!}{%\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Perturb.} & \\textbf{Ent-only Bin} & \\textbf{7-feat Bin} & \\textbf{Ent-only 3-cl} & \\textbf{7-feat 3-cl} \\\\\n\\midrule\n0\\%  & 0.833 & 0.695 & 0.688 & 0.737 \\\\\n5\\%  & 0.738 & 0.650 & 0.539 & 0.641 \\\\\n10\\% & 0.667 & 0.614 & 0.427 & 0.492 \\\\\n20\\% & 0.569 & 0.591 & 0.314 & 0.367 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Baseline comparison.}\nTable~\\ref{tab:baseline-robustness} compares robustness across detection methods under identical perturbation conditions (8-gen LOGO, binary: gen-1 vs.\\ gen-2+).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Baseline robustness under random word replacement (8-gen LOGO, binary F1). Bold indicates highest F1 at each perturbation rate.}\n\\label{tab:baseline-robustness}\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Method} & \\textbf{0\\%} & \\textbf{5\\%} & \\textbf{10\\%} & \\textbf{20\\%} \\\\\n\\midrule\n7-feature ensemble & \\textbf{0.695} & 0.650 & 0.614 & 0.591 \\\\\nLD-Score           & 0.677 & \\textbf{0.673} & \\textbf{0.677} & \\textbf{0.671} \\\\\nAvg-LogProb        & 0.682 & 0.419 & 0.335 & 0.375 \\\\\nFastDetectGPT      & 0.571 & 0.437 & 0.468 & 0.514 \\\\\nBinoculars\\textsuperscript{\\dag}         & 0.500 & 0.461 & 0.446 & 0.425 \\\\\n\\bottomrule\n\\end{tabular}\n\n\\vspace{2pt}\n{\\footnotesize \\textsuperscript{\\dag}Binoculars operates at chance level on this binary task; its degradation figures are not meaningful.}\n\\end{table}\n\nThe 7-feature ensemble achieves the highest unperturbed binary F1 (0.695), but LD-Score surpasses it under perturbation due to near-zero degradation ($-$0.6\\,pp across the full 0\\%$\\to$20\\% range).\nFastDetectGPT and Avg-LogProb exhibit non-monotonic degradation at higher perturbation rates, likely because severe perturbation introduces distributional artifacts that these token-level methods detect as anomalous.\nAvg-LogProb is the most fragile overall ($-$34.7\\,pp at 10\\%), while FastDetectGPT drops sharply at 5\\% ($-$13.4\\,pp) before partially recovering.\nLD-Score is nearly invariant to perturbation, consistent with its reliance on corpus-level distributional divergence rather than per-token likelihoods.\nThe 7-feature ensemble offers the highest starting performance among single-reference methods, with sublinear degradation ($-$10.4\\,pp at 20\\%).\n\n\\paragraph{LLM-simulated sentence regeneration.}\nTo test robustness under semantically coherent editing, we use Qwen3-0.6B-Base to randomly regenerate 1--3 sentences per passage (avg 1.69 sentences, ${\\sim}$50\\% edit distance) and re-evaluate the 8-gen LOGO pipeline.\nBinary F1 drops from 0.692 to 0.647 ($-$4.5\\,pp, 6.5\\% relative); 3-class F1 drops from 0.739 to 0.667 ($-$7.1\\,pp, 9.7\\% relative).\nThe binary degradation ($-$4.5\\,pp) is nearly identical to that caused by 5\\% random word replacement ($-$4.6\\,pp), despite the LLM rephrase altering ${\\sim}$50\\% of characters.\nThis asymmetry arises because LLM-generated replacements preserve the underlying statistical fingerprint of the generation process (entropy dynamics, depth-accumulated distributional drift), whereas random word substitution directly destroys local statistical signals.\nDepth fingerprinting thus captures deep generative structure that survives semantic-preserving edits.\n\n\\paragraph{Seed complexity.}\nPerformance is stable across seed text complexity: stratifying seeds by vocabulary richness (TTR terciles) yields maximum F1 variation of 1.1\\,pp across groups.\n",
      "numLines": 93,
      "startLine": 1,
      "totalLines": 93
    }
  }
}
```

</details>

---


### Tool call

_source line 50_

<details open><summary>🔧 Tool call — Read · `toolu_01RY4Z1FVsrv4Aj1XA3GLduP`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_lofo.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "dd182311-35ce-4f72-819c-9891f442bee9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017xkXHvDxAnSVEeKDWfcvEG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15722,
      "cache_read_input_tokens": 37036,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15722
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

_source line 51 · 2026-05-17T19:52:58.552Z_

<details><summary>↩ Tool result · `toolu_01RY4Z1FVsrv4Aj1XA3GLduP`</summary>

```text
1	We complement the permutation importance analysis (\S\ref{sec:results-differential}) with a leave-one-feature-out ablation. Each row drops one of the seven features and re-evaluates the full 6-gen LOGO protocol; $\Delta$ is the change relative to the full 7-feature ensemble (F1\,=\,0.789).
2	
3	\begin{table}[h]
4	\centering
5	\small
6	\begin{tabular}{lcc}
7	\toprule
8	\textbf{Dropped feature} & \textbf{LOGO F1} & $\boldsymbol{\Delta}$ \textbf{vs Full} \\
9	\midrule
10	entropy\_max    & 0.774 & $-$1.50\,pp \\
11	entropy\_mean   & 0.783 & $-$0.63\,pp \\
12	ttr             & 0.784 & $-$0.55\,pp \\
13	hapax\_ratio    & 0.785 & $-$0.42\,pp \\
14	tail\_decay     & 0.786 & $-$0.33\,pp \\
15	entropy\_std    & 0.786 & $-$0.29\,pp \\
16	entropy\_min    & 0.789 & $+$0.01\,pp \\
17	\midrule
18	Full (7 features) & 0.789 & --- \\
19	\bottomrule
20	\end{tabular}
21	\caption{Leave-one-feature-out ablation (6-gen LOGO). Each row drops one feature and re-evaluates with the LOGO protocol. Sorted by impact magnitude.}
22	\label{tab:lofo}
23	\end{table}
24	
25	\paragraph{Analysis.}
26	Entropy\_max causes the largest degradation when removed ($-$1.5\,pp), despite ranking only fourth in permutation importance (split frequency 0.063). This indicates that entropy\_max provides unique signal (capturing the most surprising token under the reference model) that is not redundant with other features.
27	Conversely, entropy\_min is fully redundant ($\Delta$\,=\,+0.01\,pp), consistent with its near-zero permutation importance (0.015).
28	Six of seven features contribute positively to the ensemble, confirming that the 7-feature design is not over-specified.
29	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "57765b96-f7a1-46a4-8a8a-0bfd3e903e2f",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_lofo.tex",
      "content": "We complement the permutation importance analysis (\\S\\ref{sec:results-differential}) with a leave-one-feature-out ablation. Each row drops one of the seven features and re-evaluates the full 6-gen LOGO protocol; $\\Delta$ is the change relative to the full 7-feature ensemble (F1\\,=\\,0.789).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{lcc}\n\\toprule\n\\textbf{Dropped feature} & \\textbf{LOGO F1} & $\\boldsymbol{\\Delta}$ \\textbf{vs Full} \\\\\n\\midrule\nentropy\\_max    & 0.774 & $-$1.50\\,pp \\\\\nentropy\\_mean   & 0.783 & $-$0.63\\,pp \\\\\nttr             & 0.784 & $-$0.55\\,pp \\\\\nhapax\\_ratio    & 0.785 & $-$0.42\\,pp \\\\\ntail\\_decay     & 0.786 & $-$0.33\\,pp \\\\\nentropy\\_std    & 0.786 & $-$0.29\\,pp \\\\\nentropy\\_min    & 0.789 & $+$0.01\\,pp \\\\\n\\midrule\nFull (7 features) & 0.789 & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Leave-one-feature-out ablation (6-gen LOGO). Each row drops one feature and re-evaluates with the LOGO protocol. Sorted by impact magnitude.}\n\\label{tab:lofo}\n\\end{table}\n\n\\paragraph{Analysis.}\nEntropy\\_max causes the largest degradation when removed ($-$1.5\\,pp), despite ranking only fourth in permutation importance (split frequency 0.063). This indicates that entropy\\_max provides unique signal (capturing the most surprising token under the reference model) that is not redundant with other features.\nConversely, entropy\\_min is fully redundant ($\\Delta$\\,=\\,+0.01\\,pp), consistent with its near-zero permutation importance (0.015).\nSix of seven features contribute positively to the ensemble, confirming that the 7-feature design is not over-specified.\n",
      "numLines": 29,
      "startLine": 1,
      "totalLines": 29
    }
  }
}
```

</details>

---


### Tool call

_source line 52_

<details open><summary>🔧 Tool call — Read · `toolu_012PMvZV61XXUcjDVLBqr3vn`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_length.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "24810cb2-6197-4323-b93e-7e371a599f2c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017xkXHvDxAnSVEeKDWfcvEG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15722,
      "cache_read_input_tokens": 37036,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15722
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

_source line 53 · 2026-05-17T19:52:58.588Z_

<details><summary>↩ Tool result · `toolu_012PMvZV61XXUcjDVLBqr3vn`</summary>

```text
1	% Appendix — Length Confound Analysis
2	% Data source: 8-generator LOGO corpus (37,058 samples)
3	
4	Surface diversity features (TTR, hapax ratio) mechanically depend on text length:
5	shorter texts yield higher type-token ratios by construction.
6	If generation depth systematically shortens text, observed depth trends could be length artifacts rather than genuine distributional shifts.
7	We investigate with three complementary analyses.
8	
9	\paragraph{(a) Length--depth correlation.}
10	Spearman rank correlation between word count and generation depth is weak across all eight generators ($|\rho| < 0.14$), indicating that depth does not systematically shorten or lengthen text in our corpus.
11	
12	\paragraph{(b) Length--feature correlations.}
13	While length--depth correlation is weak, individual features show moderate length dependence:
14	tail\_decay ($|\rho| = 0.38$), hapax\_ratio ($|\rho| = 0.30$), and TTR ($|\rho| = 0.29$).
15	Reference-model features show weaker length correlations (entropy\_mean $|\rho| = 0.09$, entropy\_std $|\rho| = 0.18$).
16	This motivates the length-matched evaluation below: if length mediates some depth--feature association, controlling for length will reduce classification performance.
17	
18	\paragraph{(c) Length-matched classification.}
19	We subsample the dataset so that word-count distributions are equalized across depth classes (gen-0\,/\,gen-1\,/\,gen-2+), then retrain the binary XGBoost classifier under pooled LOGO (8-fold).
20	Length-matched binary F1\,=\,0.724, down from 0.770 on the unmatched set ($\Delta$\,=\,$-$0.046).
21	To distinguish this from a sample-size effect, we run a random-subsample control at equal $N$ without length matching: F1\,=\,0.767, confirming that the 0.046 drop reflects genuine length deconfounding rather than reduced data.
22	
23	\paragraph{Conclusion.}
24	Length accounts for approximately 6\% of discriminative performance ($\Delta$\,=\,0.046 out of 0.770).
25	The majority of the depth signal is length-independent: length-matched F1 (0.724) remains far above chance and significantly above all individual detection baselines (\S\ref{sec:results-baselines}).
26	Surface features (TTR, hapax\_ratio) partially co-vary with length, but their depth-discriminative contribution persists after length control, consistent with generation-induced vocabulary compression operating independently of text truncation.
27	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "db1018ab-96fc-4387-b686-00055935b3e9",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_length.tex",
      "content": "% Appendix — Length Confound Analysis\n% Data source: 8-generator LOGO corpus (37,058 samples)\n\nSurface diversity features (TTR, hapax ratio) mechanically depend on text length:\nshorter texts yield higher type-token ratios by construction.\nIf generation depth systematically shortens text, observed depth trends could be length artifacts rather than genuine distributional shifts.\nWe investigate with three complementary analyses.\n\n\\paragraph{(a) Length--depth correlation.}\nSpearman rank correlation between word count and generation depth is weak across all eight generators ($|\\rho| < 0.14$), indicating that depth does not systematically shorten or lengthen text in our corpus.\n\n\\paragraph{(b) Length--feature correlations.}\nWhile length--depth correlation is weak, individual features show moderate length dependence:\ntail\\_decay ($|\\rho| = 0.38$), hapax\\_ratio ($|\\rho| = 0.30$), and TTR ($|\\rho| = 0.29$).\nReference-model features show weaker length correlations (entropy\\_mean $|\\rho| = 0.09$, entropy\\_std $|\\rho| = 0.18$).\nThis motivates the length-matched evaluation below: if length mediates some depth--feature association, controlling for length will reduce classification performance.\n\n\\paragraph{(c) Length-matched classification.}\nWe subsample the dataset so that word-count distributions are equalized across depth classes (gen-0\\,/\\,gen-1\\,/\\,gen-2+), then retrain the binary XGBoost classifier under pooled LOGO (8-fold).\nLength-matched binary F1\\,=\\,0.724, down from 0.770 on the unmatched set ($\\Delta$\\,=\\,$-$0.046).\nTo distinguish this from a sample-size effect, we run a random-subsample control at equal $N$ without length matching: F1\\,=\\,0.767, confirming that the 0.046 drop reflects genuine length deconfounding rather than reduced data.\n\n\\paragraph{Conclusion.}\nLength accounts for approximately 6\\% of discriminative performance ($\\Delta$\\,=\\,0.046 out of 0.770).\nThe majority of the depth signal is length-independent: length-matched F1 (0.724) remains far above chance and significantly above all individual detection baselines (\\S\\ref{sec:results-baselines}).\nSurface features (TTR, hapax\\_ratio) partially co-vary with length, but their depth-discriminative contribution persists after length control, consistent with generation-induced vocabulary compression operating independently of text truncation.\n",
      "numLines": 27,
      "startLine": 1,
      "totalLines": 27
    }
  }
}
```

</details>

---


### Assistant

_source line 54_

<details><summary>Logged reasoning block</summary>

```text
Now let me read the remaining appendix files with -ing issues.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "0093775c-7f16-4031-a0a3-34eec6255303",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NMFSgw6Pv7kSnbt5QCmKos",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9476,
      "cache_read_input_tokens": 52758,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 9476
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

_source line 55_

<details open><summary>🔧 Tool call — Read · `toolu_01LNd3whkZP7mvgAb81CHkKP`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_error_analysis.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "ceb01b35-7135-4b86-afef-c1497b946e64",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NMFSgw6Pv7kSnbt5QCmKos",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9476,
      "cache_read_input_tokens": 52758,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 9476
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

_source line 56 · 2026-05-17T19:53:03.407Z_

<details><summary>↩ Tool result · `toolu_01LNd3whkZP7mvgAb81CHkKP`</summary>

```text
1	We analyze the distribution and characteristics of binary classification errors (gen-1 vs.\ gen-2+) across the 8-generator LOGO evaluation ($N$\,=\,29{,}095 samples, overall error rate 28.08\%).
2	
3	\paragraph{Error asymmetry.}
4	Errors are heavily asymmetric: 86.2\% are false negatives (gen-2+ predicted as gen-1) and only 13.8\% are false positives (gen-1 predicted as gen-2+).
5	The classifier systematically under-predicts depth, consistent with the DDR framework: shallow gen-2+ samples that have not yet accumulated sufficient distributional drift are indistinguishable from gen-1.
6	
7	\paragraph{Per-depth error rates.}
8	Error rates decrease monotonically with depth: depth-2 samples are the primary failure point (48.42\% error rate), followed by depth-3 (29.17\%) and depth-4 (20.32\%).
9	Depth-1 false positive rate is 7.11\%.
10	The monotonic decrease confirms that deeper generations accumulate progressively stronger fingerprints, making the gen-1$\to$gen-2 transition the hardest to detect.
11	
12	\paragraph{Per-generator variation.}
13	Table~\ref{tab:error-by-gen} shows error rates vary substantially across generators, correlating with model scale: larger models (Mistral-7B, Qwen3-8B) produce text closer to gen-1 characteristics, making depth discrimination harder.
14	
15	\begin{table}[h]
16	\centering
17	\small
18	\caption{Binary classification error rates by generator (8-gen LOGO). Sorted by error rate descending.}
19	\label{tab:error-by-gen}
20	\begin{tabular}{llccc}
21	\toprule
22	\textbf{Generator} & \textbf{Family} & \textbf{Samples} & \textbf{Errors} & \textbf{Error rate} \\
23	\midrule
24	Mistral-7B-v0.3 & Mistral & 3{,}853 & 1{,}734 & 45.00\% \\
25	Qwen3-8B        & Qwen    & 3{,}502 & 1{,}197 & 34.18\% \\
26	Llama-3.2-3B    & Llama   & 3{,}685 & 1{,}112 & 30.18\% \\
27	OLMo-2-1B      & OLMo    & 3{,}718 & 1{,}054 & 28.35\% \\
28	Pythia-2.8B     & Pythia  & 3{,}614 &   866 & 23.96\% \\
29	Qwen3-1.7B     & Qwen    & 3{,}621 &   814 & 22.48\% \\
30	Qwen3-0.6B     & Qwen    & 3{,}542 &   745 & 21.03\% \\
31	Pythia-1B       & Pythia  & 3{,}560 &   648 & 18.20\% \\
32	\bottomrule
33	\end{tabular}
34	\end{table}
35	
36	\paragraph{Feature-level explanation.}
37	Mann-Whitney U tests comparing correctly vs.\ incorrectly classified samples reveal that drifting features show significant distributional differences between correct and incorrect predictions: entropy\_mean ($p < 10^{-300}$), TTR ($p < 10^{-300}$), and hapax\_ratio ($p < 10^{-300}$).
38	In contrast, shape features show no discriminating power: entropy\_max ($p = 0.584$) and tail\_decay ($p = 0.653$).
39	Misclassified gen-2+ samples have systematically higher TTR (0.464 vs.\ 0.302 for correct) and entropy\_mean (2.26 vs.\ 1.57), indicating they retain gen-1-like lexical diversity and have not undergone the distributional convergence characteristic of deeper generations.
40	This is consistent with the DDR framework (\S\ref{sec:results-differential}): errors concentrate where depth-accumulated drift is insufficient, and shape features (which are near-stationary by design) provide no additional discriminative signal for error correction.
41	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "3865ed71-2e56-42a2-844e-9b6032d14d90",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_error_analysis.tex",
      "content": "We analyze the distribution and characteristics of binary classification errors (gen-1 vs.\\ gen-2+) across the 8-generator LOGO evaluation ($N$\\,=\\,29{,}095 samples, overall error rate 28.08\\%).\n\n\\paragraph{Error asymmetry.}\nErrors are heavily asymmetric: 86.2\\% are false negatives (gen-2+ predicted as gen-1) and only 13.8\\% are false positives (gen-1 predicted as gen-2+).\nThe classifier systematically under-predicts depth, consistent with the DDR framework: shallow gen-2+ samples that have not yet accumulated sufficient distributional drift are indistinguishable from gen-1.\n\n\\paragraph{Per-depth error rates.}\nError rates decrease monotonically with depth: depth-2 samples are the primary failure point (48.42\\% error rate), followed by depth-3 (29.17\\%) and depth-4 (20.32\\%).\nDepth-1 false positive rate is 7.11\\%.\nThe monotonic decrease confirms that deeper generations accumulate progressively stronger fingerprints, making the gen-1$\\to$gen-2 transition the hardest to detect.\n\n\\paragraph{Per-generator variation.}\nTable~\\ref{tab:error-by-gen} shows error rates vary substantially across generators, correlating with model scale: larger models (Mistral-7B, Qwen3-8B) produce text closer to gen-1 characteristics, making depth discrimination harder.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Binary classification error rates by generator (8-gen LOGO). Sorted by error rate descending.}\n\\label{tab:error-by-gen}\n\\begin{tabular}{llccc}\n\\toprule\n\\textbf{Generator} & \\textbf{Family} & \\textbf{Samples} & \\textbf{Errors} & \\textbf{Error rate} \\\\\n\\midrule\nMistral-7B-v0.3 & Mistral & 3{,}853 & 1{,}734 & 45.00\\% \\\\\nQwen3-8B        & Qwen    & 3{,}502 & 1{,}197 & 34.18\\% \\\\\nLlama-3.2-3B    & Llama   & 3{,}685 & 1{,}112 & 30.18\\% \\\\\nOLMo-2-1B      & OLMo    & 3{,}718 & 1{,}054 & 28.35\\% \\\\\nPythia-2.8B     & Pythia  & 3{,}614 &   866 & 23.96\\% \\\\\nQwen3-1.7B     & Qwen    & 3{,}621 &   814 & 22.48\\% \\\\\nQwen3-0.6B     & Qwen    & 3{,}542 &   745 & 21.03\\% \\\\\nPythia-1B       & Pythia  & 3{,}560 &   648 & 18.20\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Feature-level explanation.}\nMann-Whitney U tests comparing correctly vs.\\ incorrectly classified samples reveal that drifting features show significant distributional differences between correct and incorrect predictions: entropy\\_mean ($p < 10^{-300}$), TTR ($p < 10^{-300}$), and hapax\\_ratio ($p < 10^{-300}$).\nIn contrast, shape features show no discriminating power: entropy\\_max ($p = 0.584$) and tail\\_decay ($p = 0.653$).\nMisclassified gen-2+ samples have systematically higher TTR (0.464 vs.\\ 0.302 for correct) and entropy\\_mean (2.26 vs.\\ 1.57), indicating they retain gen-1-like lexical diversity and have not undergone the distributional convergence characteristic of deeper generations.\nThis is consistent with the DDR framework (\\S\\ref{sec:results-differential}): errors concentrate where depth-accumulated drift is insufficient, and shape features (which are near-stationary by design) provide no additional discriminative signal for error correction.\n",
      "numLines": 41,
      "startLine": 1,
      "totalLines": 41
    }
  }
}
```

</details>

---


### Tool call

_source line 57_

<details open><summary>🔧 Tool call — Read · `toolu_01TGjeFsSHP9ghq2FVK5dyR7`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_classifier.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "6b91a9c7-4c69-4a17-b8be-0d87debd137b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NMFSgw6Pv7kSnbt5QCmKos",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9476,
      "cache_read_input_tokens": 52758,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 9476
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

_source line 58 · 2026-05-17T19:53:03.891Z_

<details><summary>↩ Tool result · `toolu_01TGjeFsSHP9ghq2FVK5dyR7`</summary>

```text
1	To verify that the depth signal resides in the features rather than the classifier,
2	we repeat the 6-generator LOGO evaluation using Logistic Regression and Random Forest
3	in place of XGBoost (Table~\ref{tab:alt-classifier}).
4	All other settings (the same 7 features, 3-class labels, and class-balanced downsampling) are
5	kept identical. For Logistic Regression we apply standard scaling to the features.
6	
7	\begin{table}[h]
8	\centering
9	\caption{LOGO macro-F1 across three classifiers. Each column shows the held-out generator F1. (6-generator LOGO; 3-class.)}
10	\label{tab:alt-classifier}
11	\small
12	\resizebox{\linewidth}{!}{%
13	\begin{tabular}{lc cccccc}
14	\toprule
15	Classifier & Avg F1 & OLMo-2 & Py-1B & Py-2.8B & Qw-0.6B & Qw-1.7B & Qw-8B \\
16	\midrule
17	XGBoost          & 0.789 & 0.764 & 0.856 & 0.804 & 0.824 & 0.806 & 0.683 \\
18	Random Forest    & 0.790 & 0.764 & 0.856 & 0.804 & 0.825 & 0.807 & 0.684 \\
19	Logistic Regr.   & 0.725 & 0.719 & 0.781 & 0.740 & 0.745 & 0.743 & 0.624 \\
20	\bottomrule
21	\end{tabular}}
22	\end{table}
23	
24	Both tree-based classifiers achieve LOGO F1 $\approx 0.79$,
25	and even a linear model reaches $0.725$, well above the $0.33$ chance baseline for
26	three classes.
27	The per-generator ranking is also consistent across classifiers
28	(Pythia-1B easiest, Qwen3-8B hardest),
29	confirming that discriminative power originates in the entropy and lexical features,
30	not in classifier capacity.
31	Ordinal-specific methods (CORAL \cite{coral_ordinal}, Frank-Hall \cite{frank_hall_ordinal}) achieve comparable F1 with overlapping CIs, confirming that 3-class granularity provides insufficient resolution for ranking-aware losses to improve over standard multiclass classification.
32	
33	\subsection*{Sampling Sensitivity Analysis}
34	\label{app:sampling-sensitivity}
35	
36	To assess robustness to decoding hyperparameters, we regenerate Qwen3-1.7B continuation chains under three sampling configurations (the remaining five generators retain their default-configuration data) and re-evaluate the 6-generator LOGO pipeline (Table~\ref{tab:sampling-ablation}).
37	
38	\begin{table}[h]
39	\centering
40	\caption{Depth classification under varying sampling parameters. All other settings match the default pipeline. (6-generator LOGO; 3-class and binary.)}
41	\label{tab:sampling-ablation}
42	\small
43	\resizebox{\linewidth}{!}{%
44	\begin{tabular}{lcc ccc}
45	\toprule
46	Config & Temp.\ & Top-$p$ & 3-class F1 & Binary F1 & $\rho$(entropy\_mean) \\
47	\midrule
48	Low        & 0.5 & 0.80 & 0.785 & 0.797 & $-0.694$ \\
49	Default    & 0.7 & 0.90 & 0.788 & 0.799 & $-0.602$ \\
50	High       & 1.0 & 0.95 & 0.726 & 0.733 & $-0.002$ \\
51	\bottomrule
52	\end{tabular}}
53	\end{table}
54	
55	The depth signal is robust to moderate sampling variation: low and default configurations differ by at most 0.3\,pp in both 3-class and binary F1, and entropy--depth Spearman correlations remain strongly negative ($\rho \leq -0.60$).
56	At high temperature ($t{=}1.0$, top-$p{=}0.95$), classification degrades by approximately 6\,pp and the entropy--depth correlation collapses to near zero ($\rho = -0.002$).
57	This is consistent with the hypothesis that depth features are shaped by the sampling mechanism (\S\ref{sec:discussion}): elevated temperature injects sufficient randomness to flatten the distributional drift that accumulates across generation steps, effectively masking the depth signal.
58	The practical implication is that depth fingerprinting applies reliably under standard decoding regimes but should not be expected to generalize to high-entropy sampling settings.
59	
60	\subsection*{Per-Generator Performance}
61	
62	Figure~\ref{fig:per-gen} visualizes per-generator LOGO performance.
63	Pythia models (1B, 2.8B) achieve highest F1, while larger models (Mistral-7B, Qwen3-8B) show degradation.
64	The scale effect (larger models $\rightarrow$ lower F1) is consistent with higher-capacity models generating text statistically closer to human writing.
65	
66	\begin{figure*}[ht]
67	\centering
68	\includegraphics[width=\textwidth]{fig_appendix_per_gen.pdf}
69	\caption{Per-generator LOGO performance. (a) 8-generator binary and 3-class F1, sorted by binary F1. Dashed lines: pool average. (b) 6-generator LOGO detail heatmap showing the performance spread across model families.}
70	\label{fig:per-gen}
71	\end{figure*}
72	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "cf00eb50-503c-46b6-946e-4fa18716431c",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_classifier.tex",
      "content": "To verify that the depth signal resides in the features rather than the classifier,\nwe repeat the 6-generator LOGO evaluation using Logistic Regression and Random Forest\nin place of XGBoost (Table~\\ref{tab:alt-classifier}).\nAll other settings (the same 7 features, 3-class labels, and class-balanced downsampling) are\nkept identical. For Logistic Regression we apply standard scaling to the features.\n\n\\begin{table}[h]\n\\centering\n\\caption{LOGO macro-F1 across three classifiers. Each column shows the held-out generator F1. (6-generator LOGO; 3-class.)}\n\\label{tab:alt-classifier}\n\\small\n\\resizebox{\\linewidth}{!}{%\n\\begin{tabular}{lc cccccc}\n\\toprule\nClassifier & Avg F1 & OLMo-2 & Py-1B & Py-2.8B & Qw-0.6B & Qw-1.7B & Qw-8B \\\\\n\\midrule\nXGBoost          & 0.789 & 0.764 & 0.856 & 0.804 & 0.824 & 0.806 & 0.683 \\\\\nRandom Forest    & 0.790 & 0.764 & 0.856 & 0.804 & 0.825 & 0.807 & 0.684 \\\\\nLogistic Regr.   & 0.725 & 0.719 & 0.781 & 0.740 & 0.745 & 0.743 & 0.624 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\nBoth tree-based classifiers achieve LOGO F1 $\\approx 0.79$,\nand even a linear model reaches $0.725$, well above the $0.33$ chance baseline for\nthree classes.\nThe per-generator ranking is also consistent across classifiers\n(Pythia-1B easiest, Qwen3-8B hardest),\nconfirming that discriminative power originates in the entropy and lexical features,\nnot in classifier capacity.\nOrdinal-specific methods (CORAL \\cite{coral_ordinal}, Frank-Hall \\cite{frank_hall_ordinal}) achieve comparable F1 with overlapping CIs, confirming that 3-class granularity provides insufficient resolution for ranking-aware losses to improve over standard multiclass classification.\n\n\\subsection*{Sampling Sensitivity Analysis}\n\\label{app:sampling-sensitivity}\n\nTo assess robustness to decoding hyperparameters, we regenerate Qwen3-1.7B continuation chains under three sampling configurations (the remaining five generators retain their default-configuration data) and re-evaluate the 6-generator LOGO pipeline (Table~\\ref{tab:sampling-ablation}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Depth classification under varying sampling parameters. All other settings match the default pipeline. (6-generator LOGO; 3-class and binary.)}\n\\label{tab:sampling-ablation}\n\\small\n\\resizebox{\\linewidth}{!}{%\n\\begin{tabular}{lcc ccc}\n\\toprule\nConfig & Temp.\\ & Top-$p$ & 3-class F1 & Binary F1 & $\\rho$(entropy\\_mean) \\\\\n\\midrule\nLow        & 0.5 & 0.80 & 0.785 & 0.797 & $-0.694$ \\\\\nDefault    & 0.7 & 0.90 & 0.788 & 0.799 & $-0.602$ \\\\\nHigh       & 1.0 & 0.95 & 0.726 & 0.733 & $-0.002$ \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\nThe depth signal is robust to moderate sampling variation: low and default configurations differ by at most 0.3\\,pp in both 3-class and binary F1, and entropy--depth Spearman correlations remain strongly negative ($\\rho \\leq -0.60$).\nAt high temperature ($t{=}1.0$, top-$p{=}0.95$), classification degrades by approximately 6\\,pp and the entropy--depth correlation collapses to near zero ($\\rho = -0.002$).\nThis is consistent with the hypothesis that depth features are shaped by the sampling mechanism (\\S\\ref{sec:discussion}): elevated temperature injects sufficient randomness to flatten the distributional drift that accumulates across generation steps, effectively masking the depth signal.\nThe practical implication is that depth fingerprinting applies reliably under standard decoding regimes but should not be expected to generalize to high-entropy sampling settings.\n\n\\subsection*{Per-Generator Performance}\n\nFigure~\\ref{fig:per-gen} visualizes per-generator LOGO performance.\nPythia models (1B, 2.8B) achieve highest F1, while larger models (Mistral-7B, Qwen3-8B) show degradation.\nThe scale effect (larger models $\\rightarrow$ lower F1) is consistent with higher-capacity models generating text statistically closer to human writing.\n\n\\begin{figure*}[ht]\n\\centering\n\\includegraphics[width=\\textwidth]{fig_appendix_per_gen.pdf}\n\\caption{Per-generator LOGO performance. (a) 8-generator binary and 3-class F1, sorted by binary F1. Dashed lines: pool average. (b) 6-generator LOGO detail heatmap showing the performance spread across model families.}\n\\label{fig:per-gen}\n\\end{figure*}\n",
      "numLines": 72,
      "startLine": 1,
      "totalLines": 72
    }
  }
}
```

</details>

---


### Tool call

_source line 59_

<details open><summary>🔧 Tool call — Read · `toolu_01VeeLz8tfpkRkKsu8FJbuY4`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_domain.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "33ed35c9-2ec8-48ca-8973-9b721358199d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NMFSgw6Pv7kSnbt5QCmKos",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9476,
      "cache_read_input_tokens": 52758,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 9476
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

_source line 60 · 2026-05-17T19:53:04.372Z_

<details><summary>↩ Tool result · `toolu_01VeeLz8tfpkRkKsu8FJbuY4`</summary>

```text
1	We evaluate whether depth signal generalizes beyond Wikipedia by constructing generation chains from three additional domains: News articles, Academic abstracts, and Code documentation.
2	For each domain, we sample 200 seed texts and generate chains of depth 3 using three generators (Pythia-1B, Qwen3-1.7B, Mistral-7B).
3	The same 7-feature ensemble and LOGO protocol are applied.
4	
5	\begin{table}[h]
6	\centering
7	\small
8	\caption{Cross-domain depth classification under LOGO evaluation (binary: gen-1 vs.\ gen-2+). Three generators $\times$ 200 seeds per domain. Bootstrap 95\% CIs ($n$\,=\,1000).}
9	\label{tab:domain}
10	\begin{tabular}{lccc}
11	\toprule
12	\textbf{Domain} & \textbf{Binary F1} & \textbf{95\% CI} & \textbf{3-class F1} \\
13	\midrule
14	Code           & 0.754 & [0.737, 0.770] & 0.634 \\
15	News           & 0.746 & [0.726, 0.764] & 0.652 \\
16	Academic       & 0.739 & [0.720, 0.757] & 0.622 \\
17	\bottomrule
18	\end{tabular}
19	\end{table}
20	
21	All three non-Wikipedia domains achieve binary F1 $>$ 0.73 under leave-one-generator-out evaluation, demonstrating that depth signal is not an artifact of Wikipedia text properties.
22	
23	\paragraph{Domain $\times$ temperature interaction.}
24	Cross-domain generation used $t{=}1.0$, top-$p{=}1.0$ (vs.\ the main experiment's $t{=}0.7$, top-$p{=}0.9$).
25	Supplementary evaluation at $t{=}0.7$ reveals a domain $\times$ temperature interaction: the main Wikipedia experiment favors lower temperature ($t{=}0.7$ yields +6\,pp over $t{=}1.0$; Appendix~\ref{app:sampling-sensitivity}), while cross-domain evaluation favors higher temperature ($t{=}1.0$ yields +3 to +11\,pp over $t{=}0.7$; News 0.746 vs.\ 0.712, Academic 0.739 vs.\ 0.628, Code 0.754 vs.\ 0.687).
26	This asymmetry likely reflects reference-model calibration: Pythia-410M, trained predominantly on web text, detects subtle per-step drift in Wikipedia but requires larger distributional divergence (produced by higher temperature) to detect depth signal in out-of-distribution domains.
27	This finding suggests that reference model selection is a key factor for cross-domain deployment of depth fingerprinting.
28	
29	\paragraph{3-class inversion as DDR evidence.}
30	In the cross-domain setting, 3-class F1 (0.62--0.65) falls below binary F1 (0.74--0.75), reversing the pattern observed in the main experiment (3-class 0.762 $>$ binary 0.694).
31	This inversion reflects degraded gen-0 vs.\ gen-1 separation: the Pythia-410M reference model is calibrated to Wikipedia text, so its baseline entropy estimates are less discriminative for out-of-domain human text, compressing the feature distance between gen-0 and gen-1.
32	The binary task (gen-1 vs.\ gen-2+) is unaffected because both classes are generated under identical domain and decoding conditions; recursive drift is a relative change that does not depend on absolute calibration.
33	This pattern provides additional evidence that DDR captures generation-process invariants rather than domain-specific text properties: depth signal remains robust even when the human-vs-machine boundary becomes less distinct.
34	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "cb21de65-b2cf-41da-b622-9d50360a6ce6",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_domain.tex",
      "content": "We evaluate whether depth signal generalizes beyond Wikipedia by constructing generation chains from three additional domains: News articles, Academic abstracts, and Code documentation.\nFor each domain, we sample 200 seed texts and generate chains of depth 3 using three generators (Pythia-1B, Qwen3-1.7B, Mistral-7B).\nThe same 7-feature ensemble and LOGO protocol are applied.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Cross-domain depth classification under LOGO evaluation (binary: gen-1 vs.\\ gen-2+). Three generators $\\times$ 200 seeds per domain. Bootstrap 95\\% CIs ($n$\\,=\\,1000).}\n\\label{tab:domain}\n\\begin{tabular}{lccc}\n\\toprule\n\\textbf{Domain} & \\textbf{Binary F1} & \\textbf{95\\% CI} & \\textbf{3-class F1} \\\\\n\\midrule\nCode           & 0.754 & [0.737, 0.770] & 0.634 \\\\\nNews           & 0.746 & [0.726, 0.764] & 0.652 \\\\\nAcademic       & 0.739 & [0.720, 0.757] & 0.622 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nAll three non-Wikipedia domains achieve binary F1 $>$ 0.73 under leave-one-generator-out evaluation, demonstrating that depth signal is not an artifact of Wikipedia text properties.\n\n\\paragraph{Domain $\\times$ temperature interaction.}\nCross-domain generation used $t{=}1.0$, top-$p{=}1.0$ (vs.\\ the main experiment's $t{=}0.7$, top-$p{=}0.9$).\nSupplementary evaluation at $t{=}0.7$ reveals a domain $\\times$ temperature interaction: the main Wikipedia experiment favors lower temperature ($t{=}0.7$ yields +6\\,pp over $t{=}1.0$; Appendix~\\ref{app:sampling-sensitivity}), while cross-domain evaluation favors higher temperature ($t{=}1.0$ yields +3 to +11\\,pp over $t{=}0.7$; News 0.746 vs.\\ 0.712, Academic 0.739 vs.\\ 0.628, Code 0.754 vs.\\ 0.687).\nThis asymmetry likely reflects reference-model calibration: Pythia-410M, trained predominantly on web text, detects subtle per-step drift in Wikipedia but requires larger distributional divergence (produced by higher temperature) to detect depth signal in out-of-distribution domains.\nThis finding suggests that reference model selection is a key factor for cross-domain deployment of depth fingerprinting.\n\n\\paragraph{3-class inversion as DDR evidence.}\nIn the cross-domain setting, 3-class F1 (0.62--0.65) falls below binary F1 (0.74--0.75), reversing the pattern observed in the main experiment (3-class 0.762 $>$ binary 0.694).\nThis inversion reflects degraded gen-0 vs.\\ gen-1 separation: the Pythia-410M reference model is calibrated to Wikipedia text, so its baseline entropy estimates are less discriminative for out-of-domain human text, compressing the feature distance between gen-0 and gen-1.\nThe binary task (gen-1 vs.\\ gen-2+) is unaffected because both classes are generated under identical domain and decoding conditions; recursive drift is a relative change that does not depend on absolute calibration.\nThis pattern provides additional evidence that DDR captures generation-process invariants rather than domain-specific text properties: depth signal remains robust even when the human-vs-machine boundary becomes less distinct.\n",
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

_source line 61_

<details open><summary>🔧 Tool call — Read · `toolu_01WCb9qZ35i5MKDR7g955cce`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_finer_depth.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "ace1abec-97a8-4122-af96-83e8c40b3994",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NMFSgw6Pv7kSnbt5QCmKos",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9476,
      "cache_read_input_tokens": 52758,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 9476
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

_source line 62 · 2026-05-17T19:53:05.325Z_

<details><summary>↩ Tool result · `toolu_01WCb9qZ35i5MKDR7g955cce`</summary>

```text
1	We evaluate finer-grained 5-class depth classification (gen-0 through gen-4) using the same 7-feature ensemble and LOGO protocol described in \S\ref{sec:method}.
2	
3	\begin{table}[h]
4	\centering
5	\small
6	\resizebox{\linewidth}{!}{%
7	\begin{tabular}{lcccc}
8	\toprule
9	\textbf{Held-out Generator} & \textbf{Macro F1} & \textbf{Weighted F1} & \textbf{Accuracy} \\
10	\midrule
11	OLMo-2-1B       & 0.484 & 0.506 & 0.524 \\
12	Pythia-1B        & 0.543 & 0.568 & 0.575 \\
13	Pythia-2.8B      & 0.523 & 0.540 & 0.560 \\
14	Qwen3-0.6B      & 0.513 & 0.521 & 0.546 \\
15	Qwen3-1.7B      & 0.510 & 0.536 & 0.548 \\
16	Qwen3-8B        & 0.434 & 0.455 & 0.493 \\
17	\midrule
18	\textbf{Average} & \textbf{0.501 $\pm$ 0.038} & \textbf{0.521} & \textbf{0.541} \\
19	\bottomrule
20	\end{tabular}}
21	\caption{5-class LOGO evaluation. Each row holds out one generator for testing, training on the remaining five.}
22	\label{tab:5class-logo}
23	\end{table}
24	
25	\begin{table}[h]
26	\centering
27	\small
28	\resizebox{\linewidth}{!}{%
29	\begin{tabular}{lccccc}
30	\toprule
31	\textbf{Metric} & \textbf{Gen-0} & \textbf{Gen-1} & \textbf{Gen-2} & \textbf{Gen-3} & \textbf{Gen-4} \\
32	\midrule
33	Avg F1      & 0.921 & 0.634 & 0.268 & 0.259 & 0.423 \\
34	\bottomrule
35	\end{tabular}}
36	\caption{Per-class F1 averaged across all six LOGO folds.}
37	\label{tab:5class-perclass}
38	\end{table}
39	
40	\paragraph{Analysis.}
41	Moving from 3-class (gen-0 / gen-1 / gen-2+) to 5-class classification reduces LOGO macro F1 from 0.762 to approximately 0.49.
42	The degradation is concentrated in the middle depths: gen-2 and gen-3 achieve only 0.268 and 0.259 F1, respectively.
43	The aggregated confusion matrix reveals that 36.5\% of true gen-2 samples are misclassified as gen-1, while 37.8\% of true gen-3 samples are predicted as gen-4.
44	Adjacent depths (gen-2$\leftrightarrow$gen-3, gen-3$\leftrightarrow$gen-4) account for the majority of errors, consistent with the intuition that deeper recursive generations converge in surface-level statistical fingerprints.
45	Gen-0 (human text) remains highly distinguishable (F1 = 0.921), and gen-1 retains moderate separability (F1 = 0.634).
46	Shape features that are near-stationary in the 3-class setting become substantially more important under 5-class evaluation: permutation importance of entropy\_std increases by 93\% and tail\_decay by 400\% relative to 3-class, yet these gains are insufficient to resolve adjacent depths.
47	These results support the 3-class grouping adopted in the main paper: collapsing gen-2+ preserves the most informative boundary (human vs.\ first-generation vs.\ deeper recursion) while avoiding the noise introduced by near-identical adjacent depths.
48	
49	\paragraph{Classifier comparison.}
50	To verify that 5-class degradation reflects feature-level limitations rather than classifier choice, we evaluate four alternatives under the same protocol: HistGradientBoosting (macro F1\,=\,0.501, 95\% bootstrap CI [0.496, 0.506]), random forest (0.476), logistic regression (0.447), and Frank-Hall ordinal reduction (0.451).
51	All classifiers perform comparably to the default XGBoost ensemble (0.501), ruling out classifier capacity as the bottleneck.
52	The gen-2/gen-3 boundary is the primary failure mode across all methods: these two classes are effectively inseparable with the current feature set, establishing 3-class granularity as the practical ceiling for surface and entropy features.
53	At the 3-class level, ordinal-specific methods (CORAL ordinal regression, Frank-Hall reduction) similarly fail to improve over multiclass XGBoost (\S\ref{sec:results}), confirming that the bottleneck is feature separability across all granularities, not the modeling of label ordinality.
54	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "b4620155-1f01-4de4-aa8d-4bd0c668a439",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_finer_depth.tex",
      "content": "We evaluate finer-grained 5-class depth classification (gen-0 through gen-4) using the same 7-feature ensemble and LOGO protocol described in \\S\\ref{sec:method}.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\linewidth}{!}{%\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Held-out Generator} & \\textbf{Macro F1} & \\textbf{Weighted F1} & \\textbf{Accuracy} \\\\\n\\midrule\nOLMo-2-1B       & 0.484 & 0.506 & 0.524 \\\\\nPythia-1B        & 0.543 & 0.568 & 0.575 \\\\\nPythia-2.8B      & 0.523 & 0.540 & 0.560 \\\\\nQwen3-0.6B      & 0.513 & 0.521 & 0.546 \\\\\nQwen3-1.7B      & 0.510 & 0.536 & 0.548 \\\\\nQwen3-8B        & 0.434 & 0.455 & 0.493 \\\\\n\\midrule\n\\textbf{Average} & \\textbf{0.501 $\\pm$ 0.038} & \\textbf{0.521} & \\textbf{0.541} \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{5-class LOGO evaluation. Each row holds out one generator for testing, training on the remaining five.}\n\\label{tab:5class-logo}\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\linewidth}{!}{%\n\\begin{tabular}{lccccc}\n\\toprule\n\\textbf{Metric} & \\textbf{Gen-0} & \\textbf{Gen-1} & \\textbf{Gen-2} & \\textbf{Gen-3} & \\textbf{Gen-4} \\\\\n\\midrule\nAvg F1      & 0.921 & 0.634 & 0.268 & 0.259 & 0.423 \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Per-class F1 averaged across all six LOGO folds.}\n\\label{tab:5class-perclass}\n\\end{table}\n\n\\paragraph{Analysis.}\nMoving from 3-class (gen-0 / gen-1 / gen-2+) to 5-class classification reduces LOGO macro F1 from 0.762 to approximately 0.49.\nThe degradation is concentrated in the middle depths: gen-2 and gen-3 achieve only 0.268 and 0.259 F1, respectively.\nThe aggregated confusion matrix reveals that 36.5\\% of true gen-2 samples are misclassified as gen-1, while 37.8\\% of true gen-3 samples are predicted as gen-4.\nAdjacent depths (gen-2$\\leftrightarrow$gen-3, gen-3$\\leftrightarrow$gen-4) account for the majority of errors, consistent with the intuition that deeper recursive generations converge in surface-level statistical fingerprints.\nGen-0 (human text) remains highly distinguishable (F1 = 0.921), and gen-1 retains moderate separability (F1 = 0.634).\nShape features that are near-stationary in the 3-class setting become substantially more important under 5-class evaluation: permutation importance of entropy\\_std increases by 93\\% and tail\\_decay by 400\\% relative to 3-class, yet these gains are insufficient to resolve adjacent depths.\nThese results support the 3-class grouping adopted in the main paper: collapsing gen-2+ preserves the most informative boundary (human vs.\\ first-generation vs.\\ deeper recursion) while avoiding the noise introduced by near-identical adjacent depths.\n\n\\paragraph{Classifier comparison.}\nTo verify that 5-class degradation reflects feature-level limitations rather than classifier choice, we evaluate four alternatives under the same protocol: HistGradientBoosting (macro F1\\,=\\,0.501, 95\\% bootstrap CI [0.496, 0.506]), random forest (0.476), logistic regression (0.447), and Frank-Hall ordinal reduction (0.451).\nAll classifiers perform comparably to the default XGBoost ensemble (0.501), ruling out classifier capacity as the bottleneck.\nThe gen-2/gen-3 boundary is the primary failure mode across all methods: these two classes are effectively inseparable with the current feature set, establishing 3-class granularity as the practical ceiling for surface and entropy features.\nAt the 3-class level, ordinal-specific methods (CORAL ordinal regression, Frank-Hall reduction) similarly fail to improve over multiclass XGBoost (\\S\\ref{sec:results}), confirming that the bottleneck is feature separability across all granularities, not the modeling of label ordinality.\n",
      "numLines": 54,
      "startLine": 1,
      "totalLines": 54
    }
  }
}
```

</details>

---


### Tool call

_source line 63_

<details open><summary>🔧 Tool call — Read · `toolu_01RPLBoLWqY2whCtoZAwXpkE`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_feature_distributions.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "fc1203dd-e5ff-409a-a2c1-11aed47e9228",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NMFSgw6Pv7kSnbt5QCmKos",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9476,
      "cache_read_input_tokens": 52758,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 9476
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

_source line 64 · 2026-05-17T19:53:06.433Z_

<details><summary>↩ Tool result · `toolu_01RPLBoLWqY2whCtoZAwXpkE`</summary>

```text
1	\subsection*{DDR Trend Lines}
2	
3	Figure~\ref{fig:ddr-trends} shows the per-feature depth trend (mean across all samples at each depth) with individual generator traces overlaid.
4	The consistent downward trajectories for drifting features across all generators confirm that DDR is a universal property of recursive generation.
5	Shape features exhibit flat trajectories regardless of generator, with near-zero $R^2$ for the linear fit.
6	
7	\begin{figure*}[ht]
8	\centering
9	\includegraphics[width=\textwidth]{fig_appendix_ddr_trends.pdf}
10	\caption{Per-feature depth trends. Black line: pooled mean ($\pm$1 std shading) across all generators. Colored traces: individual generators. Features are labeled by DDR category (drifting, intermediate, stationary). Spearman $\rho$ and linear $R^2$ are annotated per panel.}
11	\label{fig:ddr-trends}
12	\end{figure*}
13	
14	\subsection*{UMAP Embedding}
15	
16	Figure~\ref{fig:umap} shows a 2D UMAP projection of the 7-feature space (7{,}500 stratified samples, StandardScaler normalization, $k$\,=\,30 neighbors, min\_dist\,=\,0.3).
17	Panel (a) reveals a depth gradient from gen-0 through gen-4, with progressive overlap at deeper generations consistent with the convergence that motivates the gen-2+ class collapse.
18	Panel (b) shows the 3-class view: gen-0 forms a separable cluster, while gen-1 and gen-2+ overlap substantially, explaining the classification difficulty at this boundary.
19	
20	\begin{figure*}[ht]
21	\centering
22	\includegraphics[width=\textwidth]{fig_appendix_umap.pdf}
23	\caption{UMAP 2D projection of the 7-feature space ($N$\,=\,7{,}500 stratified sample). (a) Colored by raw generation depth (0--4): a gradient structure emerges, with deeper depths converging. (b) Colored by 3-class label: gen-0 separates clearly; gen-1 and gen-2+ overlap, consistent with the high false-negative rate at the gen-1/gen-2+ boundary.}
24	\label{fig:umap}
25	\end{figure*}
26	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "76e07acb-32ac-4c30-bced-dac0d844e69e",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_feature_distributions.tex",
      "content": "\\subsection*{DDR Trend Lines}\n\nFigure~\\ref{fig:ddr-trends} shows the per-feature depth trend (mean across all samples at each depth) with individual generator traces overlaid.\nThe consistent downward trajectories for drifting features across all generators confirm that DDR is a universal property of recursive generation.\nShape features exhibit flat trajectories regardless of generator, with near-zero $R^2$ for the linear fit.\n\n\\begin{figure*}[ht]\n\\centering\n\\includegraphics[width=\\textwidth]{fig_appendix_ddr_trends.pdf}\n\\caption{Per-feature depth trends. Black line: pooled mean ($\\pm$1 std shading) across all generators. Colored traces: individual generators. Features are labeled by DDR category (drifting, intermediate, stationary). Spearman $\\rho$ and linear $R^2$ are annotated per panel.}\n\\label{fig:ddr-trends}\n\\end{figure*}\n\n\\subsection*{UMAP Embedding}\n\nFigure~\\ref{fig:umap} shows a 2D UMAP projection of the 7-feature space (7{,}500 stratified samples, StandardScaler normalization, $k$\\,=\\,30 neighbors, min\\_dist\\,=\\,0.3).\nPanel (a) reveals a depth gradient from gen-0 through gen-4, with progressive overlap at deeper generations consistent with the convergence that motivates the gen-2+ class collapse.\nPanel (b) shows the 3-class view: gen-0 forms a separable cluster, while gen-1 and gen-2+ overlap substantially, explaining the classification difficulty at this boundary.\n\n\\begin{figure*}[ht]\n\\centering\n\\includegraphics[width=\\textwidth]{fig_appendix_umap.pdf}\n\\caption{UMAP 2D projection of the 7-feature space ($N$\\,=\\,7{,}500 stratified sample). (a) Colored by raw generation depth (0--4): a gradient structure emerges, with deeper depths converging. (b) Colored by 3-class label: gen-0 separates clearly; gen-1 and gen-2+ overlap, consistent with the high false-negative rate at the gen-1/gen-2+ boundary.}\n\\label{fig:umap}\n\\end{figure*}\n",
      "numLines": 26,
      "startLine": 1,
      "totalLines": 26
    }
  }
}
```

</details>

---


### Assistant

_source line 65_

<details><summary>Logged reasoning block</summary>

```text
Now I have read all the affected files. Let me compile the full list of -ing participle phrases that need fixing, organized by file. I'll focus on the clear AI-style patterns (", VERBing..." at the end of clauses/sentences) and skip legitimate uses.

Let me go through each file systematically:

### abstract.tex
1. Line 3: "producing recursive chains whose outputs progressively diverge from human-written text" — this is a -ing phrase ending a sentence. Fix.
2. Line 7: "restricting current applicability to base models" — -ing phrase ending. Fix.


3. 
### introduction.tex
Looking at line 6, I need to check the full context: "Understanding how distributional features evolve across recursive generation depths is a fundamental question for characterizing recursive generation dynamics, yet existing methods..." — the "for characterizing" is a prepositional phrase with a gerund object, so that's legitimate. Skip.

### method.tex
1. Line 7: "revealing differential depth response" — this appears in the figure caption.
2. Lines 17, 24, 28, 42: All contain -ing forms that need fixing — "enabling finer-grained provenance characterization," "enabling evaluation of cross-generator and cross-scale generalization," "isolating the effect of the generation model from source text variation," and "confirming that both feature groups contribute to depth discrimination."
3. Lines 52-53: "capturing the average predictability of the text under the reference model" and "measuring the spread of per-token surprise" — these are feature definitions in an itemize list that follow a standard pattern, but I'll adjust them for consistency with the rest.
4. Lines 54-55: "capturing the most surprising token," "capturing the most predictable token," and "reflecting the model's increasing confidence on its own outputs" — three more -ing phrases to revise.
5. Lines 56, 59: "ensuring the classifier has access to the full marginal distribution shape" and "characterizing the shape of the distribution tail" both need fixing.
6. Lines 86, 96: "confirming that discriminative power resides in the features" and "ensuring a controlled comparison" — two more -ing endings to address.
7. Line 72 with "motivates combining both feature types" is a standard object complement construction, so I'll leave that one alone.

Now I'm reconsidering the feature list items from lines 52-59. These are academic definitions where the participle phrases modify the features in apposition, which is exactly the pattern the user wants changed. I should rewrite them using relative clauses like "which captures" instead of the -ing form to make them cleaner and more direct.

Moving to results.tex, I'm identifying several instances of -ing endings that need fixing: "confirming that depth signal persists," "making each recursive step more distinct," "confirming transfer across architectural families," and several others throughout the file. Most of these appear after commas in descriptive contexts, so I'll convert them to relative clauses or restructure them as complete clauses. Line 82 appears to be cut off mid-sentence, but I can see it's another "indicating that" construction that needs the same treatment.

Now checking discussion.tex and related_work.tex for the same pattern—I'm finding more -ing constructions like "suggesting" and "showing" that follow the same problematic structure and need to be rewritten as proper clauses.

Moving through limitations.tex and conclusion.tex, the issue persists: phrases like "enabling," "indicating," and "defining" are dangling participles that should be converted to finite verbs or restructured entirely.

Now I'm working through the appendix sections. In appendix_prompt_type.tex, appendix_qlora.tex, and appendix_cross_temp.tex, the same pattern appears—captions and sentences ending with -ing constructions that need fixing. The appendix_downstream.tex entry appears to be cut off, but it's clearly another instance of the same grammatical issue that needs attention. I'm continuing through the LaTeX files to identify and fix -ing phrase endings. In appendix_length.tex, I need to convert several instances where participles end sentences—like "indicating that depth does not systematically shorten or lengthen text" and "confirming that the 0.046 drop reflects genuine length deconfounding." Then moving into appendix_error_analysis.tex, there are more -ing constructions to address, such as "making the gen-1 to gen-2 transition the hardest to detect" and "indicating they retain gen-1-like lexical diversity."

Continuing through appendix_classifier.tex, appendix_domain.tex, and appendix_finer_depth.tex, I'm finding similar patterns—phrases like "demonstrating that depth signal is not an artifact of Wikipedia text properties," "compressing the feature distance between gen-0 and gen-1," and "establishing 3-class granularity as the practical ceiling" all need conversion away from -ing endings, while skipping cases where the main verb is finite rather than participial.

Now I'm looking at appendix_feature_distributions.tex where line 18 has "explaining the classification difficulty at this boundary"—another -ing phrase to fix.

For the method.tex feature list, I'm examining those entropy descriptions. The "capturing" and "measuring" phrases are functioning as appositives that clarify what each feature represents, so they're worth keeping but I should make sure they're consistent with the overall style adjustments I'm making elsewhere in the document.

Line 55's "reflecting" is definitely a sentence fragment that needs fixing—it's describing how the floor of token-level surprise drops as generation depth increases. Line 56's "ensuring the classifier has access to the full marginal distribution shape" is another -ing ending to address. And line 59 has "characterizing the shape of the distribution tail" which also needs to be rewritten.

I'm going to systematically work through these edits now, being careful to maintain the technical precision while removing the -ing participle phrases.

Actually, let me verify the "approximately preserving distributional shape" instances the user flagged. I'm checking where this exact phrase appears across the files—it looks like some instances already use "preserves" correctly, while others have -ing forms like "suggesting" that still need fixing. I've confirmed that both "shifting" and "preserving" are legitimate constructions here—"shifting" is a gerund complement describing the mechanism of recursive generation, and "preserving" is part of a standard adverbial clause introduced by "while". I'll skip both of these. Now I'm ready to start making edits across the files, being careful to match exact strings, and I should check figure captions too since they're part of the paper.

Given the volume of changes needed, I'll work through the files systematically, batching edits by file to ensure each modification has the correct context. I'm wrestling with how to rephrase this sentence without bloating the abstract — the key issue is that "chains diverge" doesn't work grammatically; it's the outputs that diverge. I could use a semicolon to separate the clauses, or treat "produces" as a coordinate verb, but I'm trying to keep it concise while maintaining clarity about what actually diverges from human-written text.

The two-sentence split seems like the cleanest approach: "LLM-generated text increasingly re-enters the web and seeds subsequent generation. The resulting recursive chains produce outputs that progressively diverge from human-written text." It's the same word count as the original but reads more naturally.

For the second issue, I'm deciding between using a relative clause with "which" or making "restricts" a coordinate verb — either way, I need to clarify that instruction tuning is what limits applicability to base models. I'm settling on the cleaner phrasing: "The depth signal degrades substantially under instruction tuning, which restricts current applicability to base models." Now I need to handle the conclusion.tex line about how the signal may further compress at larger scales — I should tighten that by using a semicolon to connect the two related constraints rather than repeating "and." I'm working through a series of edits across multiple files, starting with the abstract and conclusion sections. The introduction looks clean without any participle ending issues, so I can skip that. Now I'm moving into method.tex, which has the most revisions to handle.

I'm going through several specific fixes: converting present participles like "revealing" and "enabling" into relative clauses with "which" to maintain parallel structure with the main verbs. For instance, I'm changing "revealing differential depth response" to "which reveals differential depth response" so the coordinate verbs align properly. Similar adjustments are needed for the ordinal classification task description and the generalization evaluation sections. I'm working through the grammar here—"isolating" in the original modifies the entire action of using shared seeds, so I need to preserve that relationship. Using "which isolates" after the clause about controlling for input content captures this better, even if the reference is slightly loose. This phrasing keeps the sentence structure cleaner while maintaining the intended meaning.

Now for the validation sentence, I'm deciding between a few options. The "which confirm" version is the most straightforward—it ties the validation methods directly to what they accomplish without adding extra clauses. This feels like the clearest way to express that both analyses together confirm the contribution of the feature groups.

For the feature list items, I'm standardizing the phrasing across all four lines. Instead of mixing "capturing" and "measuring," I'm using "which" consistently to introduce what each metric does. This keeps the list parallel and readable while maintaining the original meaning. The slope captures how steeply the reference model's probability mass decays beyond high-probability tokens, characterizing the distribution tail's shape. I'm also noting that alternative classifiers and ordinal-specific methods produce comparable results, which confirms the discriminative power comes from the features themselves rather than the classifier choice. I'm working through the wording of that sentence—"to ensure" feels more natural than "which ensures" for this context. Now I've got a clear editing plan, so I'm ready to start making changes across the files. I'll batch the edits by file and work through them systematically, starting with abstract.tex, conclusion.tex, and discussion.

tex since those have fewer changes, then moving to the larger files like method.tex and results.tex, and finally the appendices.

For the abstract, I'm refining that sentence about recursive chains. The current version uses a participle phrase that feels a bit awkward, so I'm considering either splitting it into two sentences or coordinating with "and" to keep it as one. Given the word limit constraints, using "and" to join them works better: "LLM-generated text increasingly re-enters the web and seeds subsequent generation, and the resulting recursive chains produce outputs that progressively diverge from human-written text."

I'm also updating the phrasing around the base model limitation from a participle to a relative clause for clarity.

For the conclusion, I need to rework how I'm describing the scope boundaries. The current phrasing with "defining" is a bit loose, so I'm splitting it into two sentences to make it clearer that these factors—the degradation and potential compression at larger scales—are what establish the current scope boundaries.

In the discussion section, I'm breaking up a longer sentence about the classifier results. Instead of using a comma before "suggesting," I'm making it a separate sentence that more directly states what the results indicate about the gen-1/gen-2+ boundary being the bottleneck. I'm working through some sentence splits to improve clarity. The first one about the practical resolution ceiling is too long, so I'm breaking it after the XGBoost reference and making the suggestion about the bottleneck its own sentence. For the DDR section, I'm separating the point about preserving distributional shape from the conclusion about compression versus erosion. And in the related work, I'm simplifying how the citation flows—either converting the comma to "and show" or using a semicolon to connect the analysis with its findings more directly. I'm deciding between "and provides" versus "which provides" for better coordination—using "and" keeps the structure parallel with the earlier "reveals," so I'll go with that phrasing.

Now I'm working through how to restructure a sentence about surface features and diversity decline. The issue is that "showing" dangles awkwardly when the features themselves are what demonstrate the decline, not the application of them. I think splitting it into two sentences works best: apply the measures to inference chains, then have a separate statement that they show the monotonic decline pattern.

For the watermark decay sentence, I just need to swap "motivating" for "which motivates" to make the grammar clearer—the decay itself is what motivates the methods, not the citation.

Now looking at the next edits: I'm working through some LaTeX refinements. The first one is about coordinating verbs—instead of using a comma and gerund phrase, I can make "isolate" and "enable" parallel verbs connected by "and" for cleaner syntax. The second edit is tackling a long sentence where certain domain/generator combinations hit low performance levels, and I need to figure out how to restructure it so the suggestion about reference model calibration doesn't get buried in the complexity. I'm refining the wording around the cross-domain findings—switching from "suggesting" to "which suggests" for better flow, and applying the same phrasing adjustment to another sentence about degradation at higher temperatures to maintain consistency throughout the section. I'm working through the edits to results.tex. For the first change, I need to handle the footnote placement carefully—using "which confirms" after the footnote works better than "confirming" since it refers back to the overall F1 finding. Now I'm looking at the second edit about cross-model performance and how it affects distinctness across recursive steps. I'm working through the phrasing of this effect-size comparison—the contrast between minimal shift in shape features versus substantial drift in others really drives home why "approximately preserves" works better than claiming strict invariance. Using "which supports" keeps the logical flow tight by tying the evidence directly to the characterization.

For the next edit, I'm reconsidering how to handle the multiple references and their consistent findings. A semicolon gives me the breathing room to emphasize that this pattern across different models confirms DDR isn't just a quirk of one architecture—it's a genuine property of the recursive generation process itself.

Now looking at the sentence structure around line 82, the current phrasing is getting unwieldy. The correlation drop from -0.60 to -0.002 is the key evidence, and I should split this into two sentences to let that finding land clearly before explaining what it means about high-temperature sampling's effect on the model's ability to exploit positional information.

Moving on to the method.tex edits. I need to tighten up the language around enabling clauses and coordinate structures. The caption about bars showing Spearman correlations should use parallel verbs—"show" and "reveal" work better together than "show" and "revealing." Then there are a few places where I'm using enabling clauses that could be more direct with "which enables" instead of just the gerund form. I'm working through some grammar edits for academic writing. The issue is whether "which" should be singular or plural when referring back to "leave-one-feature-out analysis and cross-group ablation." Since the referent is really the whole validation process rather than the individual analyses, I think "which confirms" works better as a singular form. I could also restructure it to say "both analyses confirm" to be more explicit, but keeping it simple with just the grammar adjustment seems cleaner.

Now I'm moving through similar edits on lines 52-55, converting several "-ing" phrases to relative clauses with "which" for consistency and clarity. For instance, changing "capturing the average predictability" to "which captures the average predictability," and doing the same for "measuring the spread" and "capturing the most surprising token." On line 55, I'm also restructuring the second part to use a semicolon and "this reflects" instead of the "-ing" phrase "reflecting," which gives the sentence better parallel structure.

For line 56, I need to check if "ensuring" appears elsewhere in the file before deciding whether to change it. After searching, it doesn't seem to be used elsewhere, so I'll go ahead and replace "ensuring the classifier has access" with "which ensures the classifier has access" for consistency with the other edits. I'm also expanding the context to show the full phrase "summary (mean, std, max, min), which ensures..."

On line 59, I'm changing "characterizing the shape of the distribution tail" to "and characterizes the shape of the distribution tail" to maintain parallel structure with the rest of the sentence about the slope.

For line 86, I need to be careful with the LaTeX syntax—the file uses `\ref{app:classifier}` not the escaped version, so my old_string needs to match exactly what's in the tex file. I'm replacing "confirming that discriminative power" with "which confirms that discriminative power" to match the pattern of the other edits.

Line 96 is a simpler change from "ensuring a controlled comparison" to "to ensure a controlled comparison."

Now I'm looking at the scope of all these edits—13 changes to method.tex alone. Since each old_string is unique and non-overlapping, I can batch multiple Edit calls together for the same file without them interfering with each other.

I'll organize this into four batches to keep the context manageable: first batch covers abstract.tex, conclusion.tex, discussion.tex, and limitations.tex with 8 edits total; second batch handles related_work.tex and results.tex with 11 edits; third batch is the 13 edits to method.tex; and the final batch will tackle all the appendix files with around 20 edits. Let me start executing the first batch.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "a56e43eb-0ee9-4f35-baf9-98408b3c78a1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DRypTj9vWbVAx1sPK7ESXk",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6358,
      "cache_read_input_tokens": 62234,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6358
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

_source line 66_

I've read all files and identified ~50 -ing participle phrase endings to fix. Starting edits now, organized by file.

**Batch 1**: abstract.tex, conclusion.tex, discussion.tex, limitations.tex.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "e4a8af2e-fc53-48c7-b3f5-ed738b2c45be",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DRypTj9vWbVAx1sPK7ESXk",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6358,
      "cache_read_input_tokens": 62234,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6358
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

_source line 67_

<details open><summary>🔧 Tool call — Edit · `toolu_01YKjiY3eG4MHzpfW4jY2x5c`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/abstract.tex",
  "old_string": "seeds subsequent generation, producing recursive chains whose outputs progressively diverge from human-written text.",
  "new_string": "seeds subsequent generation, and the resulting recursive chains progressively diverge from human-written text."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "89b1f3d0-fac8-4071-a8d5-df2318481f99",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DRypTj9vWbVAx1sPK7ESXk",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6358,
      "cache_read_input_tokens": 62234,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6358
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

_source line 68 · 2026-05-17T19:56:58.491Z_

<details><summary>↩ Tool result · `toolu_01YKjiY3eG4MHzpfW4jY2x5c`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/abstract.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "01d3a786-c9ed-4cd5-a0f1-2a1694125385",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/abstract.tex",
    "oldString": "seeds subsequent generation, producing recursive chains whose outputs progressively diverge from human-written text.",
    "newString": "seeds subsequent generation, and the resulting recursive chains progressively diverge from human-written text.",
    "originalFile": "% Abstract — Depth Fingerprinting of Recursive LLM Generation Chains\n\\begin{abstract}\nLLM-generated text increasingly re-enters the web and seeds subsequent generation, producing recursive chains whose outputs progressively diverge from human-written text.\nWe ask whether this drift is structured enough to classify how many generation steps a text has undergone, framing this as \\emph{generation depth classification} (gen-0\\,/\\,gen-1\\,/\\,gen-2+ rather than binary real-vs-synthetic).\nStudying eight base (pretrained) models from five families (0.6B--8B parameters), we identify a \\emph{differential depth response} (DDR): central-tendency features (mean entropy, lexical diversity) drift monotonically with generation depth, while shape features (entropy max, vocabulary tail slope) remain near-stationary, consistent with a location shift in the token-level NLL distribution that approximately preserves distributional shape.\nA 7-feature ensemble achieves leak-free binary F1\\,=\\,0.694 under eight-generator leave-one-generator-out (LOGO) evaluation and 0.764 on cross-model chains (five-generator subset), using a single 410M-parameter reference model.\nThe depth signal degrades substantially under instruction tuning, restricting current applicability to base models.\n\\end{abstract}\n",
    "structuredPatch": [
      {
        "oldStart": 1,
        "oldLines": 6,
        "newStart": 1,
        "newLines": 6,
        "lines": [
          " % Abstract — Depth Fingerprinting of Recursive LLM Generation Chains",
          " \\begin{abstract}",
          "-LLM-generated text increasingly re-enters the web and seeds subsequent generation, producing recursive chains whose outputs progressively diverge from human-written text.",
          "+LLM-generated text increasingly re-enters the web and seeds subsequent generation, and the resulting recursive chains progressively diverge from human-written text.",
          " We ask whether this drift is structured enough to classify how many generation steps a text has undergone, framing this as \\emph{generation depth classification} (gen-0\\,/\\,gen-1\\,/\\,gen-2+ rather than binary real-vs-synthetic).",
          " Studying eight base (pretrained) models from five families (0.6B--8B parameters), we identify a \\emph{differential depth response} (DDR): central-tendency features (mean entropy, lexical diversity) drift monotonically with generation depth, while shape features (entropy max, vocabulary tail slope) remain near-stationary, consistent with a location shift in the token-level NLL distribution that approximately preserves distributional shape.",
          " A 7-feature ensemble achieves leak-free binary F1\\,=\\,0.694 under eight-generator leave-one-generator-out (LOGO) evaluation and 0.764 on cross-model chains (five-generator subset), using a single 410M-parameter reference model."
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

_source line 69_

<details open><summary>🔧 Tool call — Edit · `toolu_017aJT7BVe1LePfnggAwZdDq`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/abstract.tex",
  "old_string": ", restricting current applicability to base models.",
  "new_string": ", which restricts current applicability to base models."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "c5b029ae-f973-441a-a632-ebf57074ec35",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DRypTj9vWbVAx1sPK7ESXk",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6358,
      "cache_read_input_tokens": 62234,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6358
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

_source line 70 · 2026-05-17T19:56:59.435Z_

<details><summary>↩ Tool result · `toolu_017aJT7BVe1LePfnggAwZdDq`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/abstract.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "a1bc12ae-78ee-4ed2-a09d-ce3a2979d815",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/abstract.tex",
    "oldString": ", restricting current applicability to base models.",
    "newString": ", which restricts current applicability to base models.",
    "originalFile": "% Abstract — Depth Fingerprinting of Recursive LLM Generation Chains\n\\begin{abstract}\nLLM-generated text increasingly re-enters the web and seeds subsequent generation, and the resulting recursive chains progressively diverge from human-written text.\nWe ask whether this drift is structured enough to classify how many generation steps a text has undergone, framing this as \\emph{generation depth classification} (gen-0\\,/\\,gen-1\\,/\\,gen-2+ rather than binary real-vs-synthetic).\nStudying eight base (pretrained) models from five families (0.6B--8B parameters), we identify a \\emph{differential depth response} (DDR): central-tendency features (mean entropy, lexical diversity) drift monotonically with generation depth, while shape features (entropy max, vocabulary tail slope) remain near-stationary, consistent with a location shift in the token-level NLL distribution that approximately preserves distributional shape.\nA 7-feature ensemble achieves leak-free binary F1\\,=\\,0.694 under eight-generator leave-one-generator-out (LOGO) evaluation and 0.764 on cross-model chains (five-generator subset), using a single 410M-parameter reference model.\nThe depth signal degrades substantially under instruction tuning, restricting current applicability to base models.\n\\end{abstract}\n",
    "structuredPatch": [
      {
        "oldStart": 4,
        "oldLines": 5,
        "newStart": 4,
        "newLines": 5,
        "lines": [
          " We ask whether this drift is structured enough to classify how many generation steps a text has undergone, framing this as \\emph{generation depth classification} (gen-0\\,/\\,gen-1\\,/\\,gen-2+ rather than binary real-vs-synthetic).",
          " Studying eight base (pretrained) models from five families (0.6B--8B parameters), we identify a \\emph{differential depth response} (DDR): central-tendency features (mean entropy, lexical diversity) drift monotonically with generation depth, while shape features (entropy max, vocabulary tail slope) remain near-stationary, consistent with a location shift in the token-level NLL distribution that approximately preserves distributional shape.",
          " A 7-feature ensemble achieves leak-free binary F1\\,=\\,0.694 under eight-generator leave-one-generator-out (LOGO) evaluation and 0.764 on cross-model chains (five-generator subset), using a single 410M-parameter reference model.",
          "-The depth signal degrades substantially under instruction tuning, restricting current applicability to base models.",
          "+The depth signal degrades substantially under instruction tuning, which restricts current applicability to base models.",
          " \\end{abstract}"
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

_source line 71_

<details open><summary>🔧 Tool call — Edit · `toolu_01Pz927AKRyWZKH8QPgWbaDZ`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/conclusion.tex",
  "old_string": ", defining the current scope boundaries.",
  "new_string": "; these limitations define the current scope boundaries."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "743a0593-885d-4a95-9670-8b6fa3abb8b7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DRypTj9vWbVAx1sPK7ESXk",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6358,
      "cache_read_input_tokens": 62234,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6358
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

_source line 72 · 2026-05-17T19:57:00.752Z_

<details><summary>↩ Tool result · `toolu_01Pz927AKRyWZKH8QPgWbaDZ`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/conclusion.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "c11ceaa5-2553-4699-be24-1fd00598ce71",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/conclusion.tex",
    "oldString": ", defining the current scope boundaries.",
    "newString": "; these limitations define the current scope boundaries.",
    "originalFile": "\\section{Conclusion}\n\\label{sec:conclusion}\n\nWe introduced generation depth classification and documented a differential depth response across eight base-model generators from five families: recursive generation is consistent with a systematic location shift in the token-level NLL distribution that approximately preserves distributional shape.\nA lightweight 7-feature ensemble detects this drift with leak-free binary F1\\,=\\,0.694 under eight-generator LOGO evaluation (0.764 on cross-model chains; five-generator subset).\nThe signal degrades substantially under instruction tuning and may further compress at larger scales (our largest generator is 8B), defining the current scope boundaries.\nAll code, data, and trained models will be released upon publication.\n",
    "structuredPatch": [
      {
        "oldStart": 3,
        "oldLines": 5,
        "newStart": 3,
        "newLines": 5,
        "lines": [
          " ",
          " We introduced generation depth classification and documented a differential depth response across eight base-model generators from five families: recursive generation is consistent with a systematic location shift in the token-level NLL distribution that approximately preserves distributional shape.",
          " A lightweight 7-feature ensemble detects this drift with leak-free binary F1\\,=\\,0.694 under eight-generator LOGO evaluation (0.764 on cross-model chains; five-generator subset).",
          "-The signal degrades substantially under instruction tuning and may further compress at larger scales (our largest generator is 8B), defining the current scope boundaries.",
          "+The signal degrades substantially under instruction tuning and may further compress at larger scales (our largest generator is 8B); these limitations define the current scope boundaries.",
          " All code, data, and trained models will be released upon publication."
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

_source line 73_

<details open><summary>🔧 Tool call — Edit · `toolu_01Q4bi6UpZ2kxdxUfTWSr4sg`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/discussion.tex",
  "old_string": "yield no improvement over standard XGBoost (Appendix~\\ref{app:classifier}), suggesting that the gen-1/gen-2+ boundary rather than ordinal structure is the bottleneck.",
  "new_string": "yield no improvement over standard XGBoost (Appendix~\\ref{app:classifier}). These results suggest that the gen-1/gen-2+ boundary rather than ordinal structure is the bottleneck."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "21d7da00-1ce2-44c1-a47d-49c2617213e6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DRypTj9vWbVAx1sPK7ESXk",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6358,
      "cache_read_input_tokens": 62234,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6358
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

_source line 74 · 2026-05-17T19:57:02.137Z_

<details><summary>↩ Tool result · `toolu_01Q4bi6UpZ2kxdxUfTWSr4sg`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/discussion.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "350d986a-41af-4b19-b96e-c2ea60c290af",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/discussion.tex",
    "oldString": "yield no improvement over standard XGBoost (Appendix~\\ref{app:classifier}), suggesting that the gen-1/gen-2+ boundary rather than ordinal structure is the bottleneck.",
    "newString": "yield no improvement over standard XGBoost (Appendix~\\ref{app:classifier}). These results suggest that the gen-1/gen-2+ boundary rather than ordinal structure is the bottleneck.",
    "originalFile": "\\section{Discussion}\n\\label{sec:discussion}\n\nThe near-stationarity of shape features is consistent with the softmax architecture and fixed sampling parameters constraining distributional shape while allowing location to drift.\nSampling ablation supports this as a tendency rather than a guarantee ($t \\in [0.5, 0.7]$: ${\\leq}0.3$\\,pp degradation; $t = 1.0$: $-6$\\,pp; Appendix~\\ref{app:sampling-sensitivity}), and prompt-type dependence further modulates the effect (elaboration F1\\,=\\,0.730 vs.\\ continuation 0.781; Appendix~\\ref{app:prompt-type}).\n\nInstruction-tuned models show substantially weaker fingerprints in preliminary experiments (OLMo-Instruct LOGO F1\\,=\\,0.338 vs.\\ 0.763 base, 6-generator LOGO): alignment-imposed length regulation and format constraints compress the distributional variation that DDR exploits.\nThis restricts current applicability to base models and constitutes the primary scope limitation.\nAt the document level within base models, gen-1 per-class F1\\,=\\,0.63 is insufficient for automated filtering but sufficient for corpus-level flagging; the gen-1\\,/\\,gen-2+ boundary concentrates 86\\% of binary errors as false negatives, with larger generators exacerbating this (Mistral-7B error rate 45\\% vs.\\ Pythia-1B 18\\%; Appendix~\\ref{app:error-analysis}).\nCross-temperature transfer degrades substantially ($t{=}0.7 \\to t{=}1.0$: Qwen3-1.7B F1 drops from 0.789 to 0.418; Appendix~\\ref{app:cross-temp}).\n\nThree classes represent the practical resolution ceiling: 5-class F1 drops to ${\\approx}$0.50 (Appendix~\\ref{app:finer-depth}), and ordinal-specific methods (CORAL, Frank-Hall) yield no improvement over standard XGBoost (Appendix~\\ref{app:classifier}), suggesting that the gen-1/gen-2+ boundary rather than ordinal structure is the bottleneck.\nDDR is distinct from model collapse \\cite{curse_of_recursion,strong_model_collapse}: inference-chain drift occurs with fixed parameters, is fully reversible, and approximately preserves distributional shape, suggesting compression within existing capacity rather than erosion of it.\n",
    "structuredPatch": [
      {
        "oldStart": 9,
        "oldLines": 5,
        "newStart": 9,
        "newLines": 5,
        "lines": [
          " At the document level within base models, gen-1 per-class F1\\,=\\,0.63 is insufficient for automated filtering but sufficient for corpus-level flagging; the gen-1\\,/\\,gen-2+ boundary concentrates 86\\% of binary errors as false negatives, with larger generators exacerbating this (Mistral-7B error rate 45\\% vs.\\ Pythia-1B 18\\%; Appendix~\\ref{app:error-analysis}).",
          " Cross-temperature transfer degrades substantially ($t{=}0.7 \\to t{=}1.0$: Qwen3-1.7B F1 drops from 0.789 to 0.418; Appendix~\\ref{app:cross-temp}).",
          " ",
          "-Three classes represent the practical resolution ceiling: 5-class F1 drops to ${\\approx}$0.50 (Appendix~\\ref{app:finer-depth}), and ordinal-specific methods (CORAL, Frank-Hall) yield no improvement over standard XGBoost (Appendix~\\ref{app:classifier}), suggesting that the gen-1/gen-2+ boundary rather than ordinal structure is the bottleneck.",
          "+Three classes represent the practical resolution ceiling: 5-class F1 drops to ${\\approx}$0.50 (Appendix~\\ref{app:finer-depth}), and ordinal-specific methods (CORAL, Frank-Hall) yield no improvement over standard XGBoost (Appendix~\\ref{app:classifier}). These results suggest that the gen-1/gen-2+ boundary rather than ordinal structure is the bottleneck.",
          " DDR is distinct from model collapse \\cite{curse_of_recursion,strong_model_collapse}: inference-chain drift occurs with fixed parameters, is fully reversible, and approximately preserves distributional shape, suggesting compression within existing capacity rather than erosion of it."
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

_source line 75_

<details open><summary>🔧 Tool call — Edit · `toolu_01C7m6CqkUTiZnWxRWd8WFQ6`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/discussion.tex",
  "old_string": "approximately preserves distributional shape, suggesting compression within existing capacity rather than erosion of it.",
  "new_string": "approximately preserves distributional shape. This pattern suggests compression within existing capacity rather than erosion of it."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "7e9aa87a-7e0d-4a72-805d-d485542e0b14",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DRypTj9vWbVAx1sPK7ESXk",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6358,
      "cache_read_input_tokens": 62234,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6358
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

_source line 76 · 2026-05-17T19:57:03.617Z_

<details><summary>↩ Tool result · `toolu_01C7m6CqkUTiZnWxRWd8WFQ6`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/discussion.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "1bf41fd9-cb5d-49b2-bcd3-cd23269a9655",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/discussion.tex",
    "oldString": "approximately preserves distributional shape, suggesting compression within existing capacity rather than erosion of it.",
    "newString": "approximately preserves distributional shape. This pattern suggests compression within existing capacity rather than erosion of it.",
    "originalFile": "\\section{Discussion}\n\\label{sec:discussion}\n\nThe near-stationarity of shape features is consistent with the softmax architecture and fixed sampling parameters constraining distributional shape while allowing location to drift.\nSampling ablation supports this as a tendency rather than a guarantee ($t \\in [0.5, 0.7]$: ${\\leq}0.3$\\,pp degradation; $t = 1.0$: $-6$\\,pp; Appendix~\\ref{app:sampling-sensitivity}), and prompt-type dependence further modulates the effect (elaboration F1\\,=\\,0.730 vs.\\ continuation 0.781; Appendix~\\ref{app:prompt-type}).\n\nInstruction-tuned models show substantially weaker fingerprints in preliminary experiments (OLMo-Instruct LOGO F1\\,=\\,0.338 vs.\\ 0.763 base, 6-generator LOGO): alignment-imposed length regulation and format constraints compress the distributional variation that DDR exploits.\nThis restricts current applicability to base models and constitutes the primary scope limitation.\nAt the document level within base models, gen-1 per-class F1\\,=\\,0.63 is insufficient for automated filtering but sufficient for corpus-level flagging; the gen-1\\,/\\,gen-2+ boundary concentrates 86\\% of binary errors as false negatives, with larger generators exacerbating this (Mistral-7B error rate 45\\% vs.\\ Pythia-1B 18\\%; Appendix~\\ref{app:error-analysis}).\nCross-temperature transfer degrades substantially ($t{=}0.7 \\to t{=}1.0$: Qwen3-1.7B F1 drops from 0.789 to 0.418; Appendix~\\ref{app:cross-temp}).\n\nThree classes represent the practical resolution ceiling: 5-class F1 drops to ${\\approx}$0.50 (Appendix~\\ref{app:finer-depth}), and ordinal-specific methods (CORAL, Frank-Hall) yield no improvement over standard XGBoost (Appendix~\\ref{app:classifier}). These results suggest that the gen-1/gen-2+ boundary rather than ordinal structure is the bottleneck.\nDDR is distinct from model collapse \\cite{curse_of_recursion,strong_model_collapse}: inference-chain drift occurs with fixed parameters, is fully reversible, and approximately preserves distributional shape, suggesting compression within existing capacity rather than erosion of it.\n",
    "structuredPatch": [
      {
        "oldStart": 10,
        "oldLines": 4,
        "newStart": 10,
        "newLines": 4,
        "lines": [
          " Cross-temperature transfer degrades substantially ($t{=}0.7 \\to t{=}1.0$: Qwen3-1.7B F1 drops from 0.789 to 0.418; Appendix~\\ref{app:cross-temp}).",
          " ",
          " Three classes represent the practical resolution ceiling: 5-class F1 drops to ${\\approx}$0.50 (Appendix~\\ref{app:finer-depth}), and ordinal-specific methods (CORAL, Frank-Hall) yield no improvement over standard XGBoost (Appendix~\\ref{app:classifier}). These results suggest that the gen-1/gen-2+ boundary rather than ordinal structure is the bottleneck.",
          "-DDR is distinct from model collapse \\cite{curse_of_recursion,strong_model_collapse}: inference-chain drift occurs with fixed parameters, is fully reversible, and approximately preserves distributional shape, suggesting compression within existing capacity rather than erosion of it.",
          "+DDR is distinct from model collapse \\cite{curse_of_recursion,strong_model_collapse}: inference-chain drift occurs with fixed parameters, is fully reversible, and approximately preserves distributional shape. This pattern suggests compression within existing capacity rather than erosion of it."
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

_source line 77_

<details open><summary>🔧 Tool call — Edit · `toolu_01KeVH9WZCdi2VnE7uoEkCyK`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/limitations.tex",
  "old_string": "from instruction-tuning effects, enabling controlled study of recursive distributional drift.",
  "new_string": "from instruction-tuning effects and enables controlled study of recursive distributional drift."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "1814b959-76bd-42aa-9de4-5d2cfa7a1ead",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DRypTj9vWbVAx1sPK7ESXk",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6358,
      "cache_read_input_tokens": 62234,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6358
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

_source line 78 · 2026-05-17T19:57:05.034Z_

<details><summary>↩ Tool result · `toolu_01KeVH9WZCdi2VnE7uoEkCyK`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/limitations.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "b5dbf995-50c0-4509-a7fa-411959fe78ba",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/limitations.tex",
    "oldString": "from instruction-tuning effects, enabling controlled study of recursive distributional drift.",
    "newString": "from instruction-tuning effects and enables controlled study of recursive distributional drift.",
    "originalFile": "\\section*{Limitations}\n\\label{sec:limitations}\n\nAll eight generators are base (pretrained) models.\nThis is a deliberate design choice: base models isolate the generation mechanism from instruction-tuning effects, enabling controlled study of recursive distributional drift.\nHowever, web text is predominantly produced by instruction-tuned and RLHF-aligned models.\nPreliminary instruct experiments confirm that depth signal degrades substantially under instruction tuning: OLMo-2-1B-Instruct drops to LOGO F1\\,=\\,0.338 (vs.\\ 0.763 base) and Qwen3-0.6B with chat template to 0.667 (vs.\\ 0.816 base); these comparisons use earlier LOGO subsets (5--6 generators) predating the full 8-generator expansion in Table~\\ref{tab:logo-results}.\nLength-matched analysis yields near-zero correlations ($|\\rho| < 0.02$) and binary classification near chance (F1\\,$\\approx$\\,0.5) for Qwen models, leaving interpretation ambiguous.\nExtending depth fingerprinting to instruct models requires addressing these confounds (length regulation, format constraints, safety-driven distribution shaping) that instruction tuning introduces.\n\nOur experiments include generators up to 8.2B parameters (Qwen3-8B).\nDepth signal persists at this scale (Qwen3-8B 3-class F1\\,=\\,0.714), but cross-scale transfer incurs a moderate gap vs.\\ $\\leq$2.8B generators (F1\\,=\\,0.77--0.81).\nFrontier models (70B+) remain untested; their higher fluency may further compress feature margins.\n\nDifferential depth response strength is prompt-type dependent: continuation chains show strongest drift (within-type F1\\,=\\,0.781) compared to elaboration (0.730), rewriting (0.737), and paraphrastic chains (binary F1\\,=\\,0.671 vs.\\ 0.749 for continuation).\nDDR is most reliably detected in continuation-style generation; near-paraphrastic settings approach the method's detection floor.\nCross-prompt-type transfer (LOPTO F1\\,=\\,0.753) confirms shared signal, yet additional prompt types (e.g., summarization, instruction following) and cross-generator $\\times$ cross-prompt interactions remain untested.\n\nOur primary evaluation uses single-generator chains; cross-model chains (\\S\\ref{sec:results-classification}) confirm depth signal under generator heterogeneity (3-class F1\\,=\\,0.809, binary F1\\,=\\,0.764), though the eight generators represent a controlled laboratory setting rather than the full diversity of real-world contamination.\nSimulated human editing (\\S\\ref{sec:discussion}) suggests graceful degradation, but the gap between simulated token replacement and real-world post-processing remains untested.\n\nThe reference model is fixed to Pythia-410M throughout, although cross-family reference experiments (\\S\\ref{sec:results-differential}) confirm the phenomenon is not reference-specific (spread 0.013 across three references).\nAll seed texts in the main evaluation are English Wikipedia excerpts.\nCross-domain evaluation (Appendix~\\ref{app:domain}) shows that depth signal persists across News, Academic, and Code domains (binary F1 $>$ 0.73 under LOGO at $t{=}1.0$), though a domain $\\times$ temperature interaction exists: certain domain/generator combinations at lower temperature approach chance level (e.g., Academic domain binary F1\\,=\\,0.628 at $t{=}0.7$), suggesting that reference model calibration is critical for cross-domain deployment.\nThe reference model dependency (Pythia-410M, English-centric pretraining) limits non-English applicability and adds inference overhead relative to surface-feature-only approaches.\nGeneralization to other languages remains untested.\n\nOur default analysis uses fixed decoding parameters (temperature 0.7, nucleus $p{=}0.9$). A sampling ablation (Appendix~\\ref{app:sampling-sensitivity}) shows robustness to moderate variation ($t \\in [0.5, 0.7]$, ${\\leq}0.3$\\,pp) but substantial degradation at $t{=}1.0$ ($-6$\\,pp), indicating that depth fingerprinting assumes standard decoding regimes.\n\nWe use 3-class granularity (gen-0\\,/\\,gen-1\\,/\\,gen-2+). A 5-class evaluation (Appendix~\\ref{app:finer-depth}) yields LOGO F1\\,$\\approx$\\,0.50, with depths 2--4 mutually indistinguishable, validating the 3-class design as the practical resolution limit.\n",
    "structuredPatch": [
      {
        "oldStart": 2,
        "oldLines": 7,
        "newStart": 2,
        "newLines": 7,
        "lines": [
          " \\label{sec:limitations}",
          " ",
          " All eight generators are base (pretrained) models.",
          "-This is a deliberate design choice: base models isolate the generation mechanism from instruction-tuning effects, enabling controlled study of recursive distributional drift.",
          "+This is a deliberate design choice: base models isolate the generation mechanism from instruction-tuning effects and enables controlled study of recursive distributional drift.",
          " However, web text is predominantly produced by instruction-tuned and RLHF-aligned models.",
          " Preliminary instruct experiments confirm that depth signal degrades substantially under instruction tuning: OLMo-2-1B-Instruct drops to LOGO F1\\,=\\,0.338 (vs.\\ 0.763 base) and Qwen3-0.6B with chat template to 0.667 (vs.\\ 0.816 base); these comparisons use earlier LOGO subsets (5--6 generators) predating the full 8-generator expansion in Table~\\ref{tab:logo-results}.",
          " Length-matched analysis yields near-zero correlations ($|\\rho| < 0.02$) and binary classification near chance (F1\\,$\\approx$\\,0.5) for Qwen models, leaving interpretation ambiguous."
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

_source line 79_

<details open><summary>🔧 Tool call — Edit · `toolu_01LfMozTAgsiCNV1o7Z3NsEi`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/limitations.tex",
  "old_string": "at $t{=}0.7$), suggesting that reference model calibration is critical for cross-domain deployment.",
  "new_string": "at $t{=}0.7$), which suggests that reference model calibration is critical for cross-domain deployment."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "7e92e723-6573-471e-9ef2-9478fe892064",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DRypTj9vWbVAx1sPK7ESXk",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6358,
      "cache_read_input_tokens": 62234,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6358
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

_source line 80 · 2026-05-17T19:57:05.948Z_

<details><summary>↩ Tool result · `toolu_01LfMozTAgsiCNV1o7Z3NsEi`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/limitations.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "c7094454-bb1b-43d1-9f94-3250eb0679e8",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/limitations.tex",
    "oldString": "at $t{=}0.7$), suggesting that reference model calibration is critical for cross-domain deployment.",
    "newString": "at $t{=}0.7$), which suggests that reference model calibration is critical for cross-domain deployment.",
    "originalFile": "\\section*{Limitations}\n\\label{sec:limitations}\n\nAll eight generators are base (pretrained) models.\nThis is a deliberate design choice: base models isolate the generation mechanism from instruction-tuning effects and enables controlled study of recursive distributional drift.\nHowever, web text is predominantly produced by instruction-tuned and RLHF-aligned models.\nPreliminary instruct experiments confirm that depth signal degrades substantially under instruction tuning: OLMo-2-1B-Instruct drops to LOGO F1\\,=\\,0.338 (vs.\\ 0.763 base) and Qwen3-0.6B with chat template to 0.667 (vs.\\ 0.816 base); these comparisons use earlier LOGO subsets (5--6 generators) predating the full 8-generator expansion in Table~\\ref{tab:logo-results}.\nLength-matched analysis yields near-zero correlations ($|\\rho| < 0.02$) and binary classification near chance (F1\\,$\\approx$\\,0.5) for Qwen models, leaving interpretation ambiguous.\nExtending depth fingerprinting to instruct models requires addressing these confounds (length regulation, format constraints, safety-driven distribution shaping) that instruction tuning introduces.\n\nOur experiments include generators up to 8.2B parameters (Qwen3-8B).\nDepth signal persists at this scale (Qwen3-8B 3-class F1\\,=\\,0.714), but cross-scale transfer incurs a moderate gap vs.\\ $\\leq$2.8B generators (F1\\,=\\,0.77--0.81).\nFrontier models (70B+) remain untested; their higher fluency may further compress feature margins.\n\nDifferential depth response strength is prompt-type dependent: continuation chains show strongest drift (within-type F1\\,=\\,0.781) compared to elaboration (0.730), rewriting (0.737), and paraphrastic chains (binary F1\\,=\\,0.671 vs.\\ 0.749 for continuation).\nDDR is most reliably detected in continuation-style generation; near-paraphrastic settings approach the method's detection floor.\nCross-prompt-type transfer (LOPTO F1\\,=\\,0.753) confirms shared signal, yet additional prompt types (e.g., summarization, instruction following) and cross-generator $\\times$ cross-prompt interactions remain untested.\n\nOur primary evaluation uses single-generator chains; cross-model chains (\\S\\ref{sec:results-classification}) confirm depth signal under generator heterogeneity (3-class F1\\,=\\,0.809, binary F1\\,=\\,0.764), though the eight generators represent a controlled laboratory setting rather than the full diversity of real-world contamination.\nSimulated human editing (\\S\\ref{sec:discussion}) suggests graceful degradation, but the gap between simulated token replacement and real-world post-processing remains untested.\n\nThe reference model is fixed to Pythia-410M throughout, although cross-family reference experiments (\\S\\ref{sec:results-differential}) confirm the phenomenon is not reference-specific (spread 0.013 across three references).\nAll seed texts in the main evaluation are English Wikipedia excerpts.\nCross-domain evaluation (Appendix~\\ref{app:domain}) shows that depth signal persists across News, Academic, and Code domains (binary F1 $>$ 0.73 under LOGO at $t{=}1.0$), though a domain $\\times$ temperature interaction exists: certain domain/generator combinations at lower temperature approach chance level (e.g., Academic domain binary F1\\,=\\,0.628 at $t{=}0.7$), suggesting that reference model calibration is critical for cross-domain deployment.\nThe reference model dependency (Pythia-410M, English-centric pretraining) limits non-English applicability and adds inference overhead relative to surface-feature-only approaches.\nGeneralization to other languages remains untested.\n\nOur default analysis uses fixed decoding parameters (temperature 0.7, nucleus $p{=}0.9$). A sampling ablation (Appendix~\\ref{app:sampling-sensitivity}) shows robustness to moderate variation ($t \\in [0.5, 0.7]$, ${\\leq}0.3$\\,pp) but substantial degradation at $t{=}1.0$ ($-6$\\,pp), indicating that depth fingerprinting assumes standard decoding regimes.\n\nWe use 3-class granularity (gen-0\\,/\\,gen-1\\,/\\,gen-2+). A 5-class evaluation (Appendix~\\ref{app:finer-depth}) yields LOGO F1\\,$\\approx$\\,0.50, with depths 2--4 mutually indistinguishable, validating the 3-class design as the practical resolution limit.\n",
    "structuredPatch": [
      {
        "oldStart": 21,
        "oldLines": 7,
        "newStart": 21,
        "newLines": 7,
        "lines": [
          " ",
          " The reference model is fixed to Pythia-410M throughout, although cross-family reference experiments (\\S\\ref{sec:results-differential}) confirm the phenomenon is not reference-specific (spread 0.013 across three references).",
          " All seed texts in the main evaluation are English Wikipedia excerpts.",
          "-Cross-domain evaluation (Appendix~\\ref{app:domain}) shows that depth signal persists across News, Academic, and Code domains (binary F1 $>$ 0.73 under LOGO at $t{=}1.0$), though a domain $\\times$ temperature interaction exists: certain domain/generator combinations at lower temperature approach chance level (e.g., Academic domain binary F1\\,=\\,0.628 at $t{=}0.7$), suggesting that reference model calibration is critical for cross-domain deployment.",
          "+Cross-domain evaluation (Appendix~\\ref{app:domain}) shows that depth signal persists across News, Academic, and Code domains (binary F1 $>$ 0.73 under LOGO at $t{=}1.0$), though a domain $\\times$ temperature interaction exists: certain domain/generator combinations at lower temperature approach chance level (e.g., Academic domain binary F1\\,=\\,0.628 at $t{=}0.7$), which suggests that reference model calibration is critical for cross-domain deployment.",
          " The reference model dependency (Pythia-410M, English-centric pretraining) limits non-English applicability and adds inference overhead relative to surface-feature-only approaches.",
          " Generalization to other languages remains untested.",
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


### Tool call

_source line 81_

<details open><summary>🔧 Tool call — Edit · `toolu_013mkE6FXnyR64QTqWEbhNpo`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/limitations.tex",
  "old_string": "($-6$\\,pp), indicating that depth fingerprinting assumes standard decoding regimes.",
  "new_string": "($-6$\\,pp), which indicates that depth fingerprinting assumes standard decoding regimes."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "36dd8b44-dfd7-40b3-a013-299e7c62edfe",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DRypTj9vWbVAx1sPK7ESXk",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6358,
      "cache_read_input_tokens": 62234,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6358
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

_source line 82 · 2026-05-17T19:57:07.074Z_

<details><summary>↩ Tool result · `toolu_013mkE6FXnyR64QTqWEbhNpo`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/limitations.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "af60fc35-5189-450f-8a5c-8f8046a661ac",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/limitations.tex",
    "oldString": "($-6$\\,pp), indicating that depth fingerprinting assumes standard decoding regimes.",
    "newString": "($-6$\\,pp), which indicates that depth fingerprinting assumes standard decoding regimes.",
    "originalFile": "\\section*{Limitations}\n\\label{sec:limitations}\n\nAll eight generators are base (pretrained) models.\nThis is a deliberate design choice: base models isolate the generation mechanism from instruction-tuning effects and enables controlled study of recursive distributional drift.\nHowever, web text is predominantly produced by instruction-tuned and RLHF-aligned models.\nPreliminary instruct experiments confirm that depth signal degrades substantially under instruction tuning: OLMo-2-1B-Instruct drops to LOGO F1\\,=\\,0.338 (vs.\\ 0.763 base) and Qwen3-0.6B with chat template to 0.667 (vs.\\ 0.816 base); these comparisons use earlier LOGO subsets (5--6 generators) predating the full 8-generator expansion in Table~\\ref{tab:logo-results}.\nLength-matched analysis yields near-zero correlations ($|\\rho| < 0.02$) and binary classification near chance (F1\\,$\\approx$\\,0.5) for Qwen models, leaving interpretation ambiguous.\nExtending depth fingerprinting to instruct models requires addressing these confounds (length regulation, format constraints, safety-driven distribution shaping) that instruction tuning introduces.\n\nOur experiments include generators up to 8.2B parameters (Qwen3-8B).\nDepth signal persists at this scale (Qwen3-8B 3-class F1\\,=\\,0.714), but cross-scale transfer incurs a moderate gap vs.\\ $\\leq$2.8B generators (F1\\,=\\,0.77--0.81).\nFrontier models (70B+) remain untested; their higher fluency may further compress feature margins.\n\nDifferential depth response strength is prompt-type dependent: continuation chains show strongest drift (within-type F1\\,=\\,0.781) compared to elaboration (0.730), rewriting (0.737), and paraphrastic chains (binary F1\\,=\\,0.671 vs.\\ 0.749 for continuation).\nDDR is most reliably detected in continuation-style generation; near-paraphrastic settings approach the method's detection floor.\nCross-prompt-type transfer (LOPTO F1\\,=\\,0.753) confirms shared signal, yet additional prompt types (e.g., summarization, instruction following) and cross-generator $\\times$ cross-prompt interactions remain untested.\n\nOur primary evaluation uses single-generator chains; cross-model chains (\\S\\ref{sec:results-classification}) confirm depth signal under generator heterogeneity (3-class F1\\,=\\,0.809, binary F1\\,=\\,0.764), though the eight generators represent a controlled laboratory setting rather than the full diversity of real-world contamination.\nSimulated human editing (\\S\\ref{sec:discussion}) suggests graceful degradation, but the gap between simulated token replacement and real-world post-processing remains untested.\n\nThe reference model is fixed to Pythia-410M throughout, although cross-family reference experiments (\\S\\ref{sec:results-differential}) confirm the phenomenon is not reference-specific (spread 0.013 across three references).\nAll seed texts in the main evaluation are English Wikipedia excerpts.\nCross-domain evaluation (Appendix~\\ref{app:domain}) shows that depth signal persists across News, Academic, and Code domains (binary F1 $>$ 0.73 under LOGO at $t{=}1.0$), though a domain $\\times$ temperature interaction exists: certain domain/generator combinations at lower temperature approach chance level (e.g., Academic domain binary F1\\,=\\,0.628 at $t{=}0.7$), which suggests that reference model calibration is critical for cross-domain deployment.\nThe reference model dependency (Pythia-410M, English-centric pretraining) limits non-English applicability and adds inference overhead relative to surface-feature-only approaches.\nGeneralization to other languages remains untested.\n\nOur default analysis uses fixed decoding parameters (temperature 0.7, nucleus $p{=}0.9$). A sampling ablation (Appendix~\\ref{app:sampling-sensitivity}) shows robustness to moderate variation ($t \\in [0.5, 0.7]$, ${\\leq}0.3$\\,pp) but substantial degradation at $t{=}1.0$ ($-6$\\,pp), indicating that depth fingerprinting assumes standard decoding regimes.\n\nWe use 3-class granularity (gen-0\\,/\\,gen-1\\,/\\,gen-2+). A 5-class evaluation (Appendix~\\ref{app:finer-depth}) yields LOGO F1\\,$\\approx$\\,0.50, with depths 2--4 mutually indistinguishable, validating the 3-class design as the practical resolution limit.\n",
    "structuredPatch": [
      {
        "oldStart": 25,
        "oldLines": 6,
        "newStart": 25,
        "newLines": 6,
        "lines": [
          " The reference model dependency (Pythia-410M, English-centric pretraining) limits non-English applicability and adds inference overhead relative to surface-feature-only approaches.",
          " Generalization to other languages remains untested.",
          " ",
          "-Our default analysis uses fixed decoding parameters (temperature 0.7, nucleus $p{=}0.9$). A sampling ablation (Appendix~\\ref{app:sampling-sensitivity}) shows robustness to moderate variation ($t \\in [0.5, 0.7]$, ${\\leq}0.3$\\,pp) but substantial degradation at $t{=}1.0$ ($-6$\\,pp), indicating that depth fingerprinting assumes standard decoding regimes.",
          "+Our default analysis uses fixed decoding parameters (temperature 0.7, nucleus $p{=}0.9$). A sampling ablation (Appendix~\\ref{app:sampling-sensitivity}) shows robustness to moderate variation ($t \\in [0.5, 0.7]$, ${\\leq}0.3$\\,pp) but substantial degradation at $t{=}1.0$ ($-6$\\,pp), which indicates that depth fingerprinting assumes standard decoding regimes.",
          " ",
          " We use 3-class granularity (gen-0\\,/\\,gen-1\\,/\\,gen-2+). A 5-class evaluation (Appendix~\\ref{app:finer-depth}) yields LOGO F1\\,$\\approx$\\,0.50, with depths 2--4 mutually indistinguishable, validating the 3-class design as the practical resolution limit."
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

_source line 83_

**Batch 2**: related_work.tex, results.tex.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "a06b2cd5-e5ec-44aa-8981-c786f2a51f22",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Fdq885ZGJeioznoH8Xjqs3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14907,
      "cache_read_input_tokens": 68592,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14907
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


### Tool call

_source line 84_

<details open><summary>🔧 Tool call — Edit · `toolu_01HFukKn1vBMLZQ6XdrHY6Xz`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/related_work.tex",
  "old_string": "analyze paraphrasing and translation chains, showing progressive information loss.",
  "new_string": "analyze paraphrasing and translation chains and show progressive information loss."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "6785034f-c892-4cc3-a1f2-3b6560ea1709",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Fdq885ZGJeioznoH8Xjqs3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14907,
      "cache_read_input_tokens": 68592,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14907
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

_source line 85 · 2026-05-17T19:57:11.338Z_

<details><summary>↩ Tool result · `toolu_01HFukKn1vBMLZQ6XdrHY6Xz`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/related_work.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "be11f51f-9a42-4747-9dfb-f073b313f8f8",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/related_work.tex",
    "oldString": "analyze paraphrasing and translation chains, showing progressive information loss.",
    "newString": "analyze paraphrasing and translation chains and show progressive information loss.",
    "originalFile": "\\section{Related Work}\n\\label{sec:related}\n\n\\subsection{AI-Generated Text Detection}\n\\label{sec:related-detection}\n\nMethods for distinguishing human-written from machine-generated text have evolved from statistical tests \\cite{gltr,grover,release_strategies} to zero-shot reference-model approaches \\cite{detectgpt,fast_detectgpt,binoculars,dna_gpt} and learned classifiers \\cite{ghostbuster,feat_aug_transformer,reliable_detection,ld_score}.\nRecent work pursues diverse signals including intrinsic dimensionality \\cite{intrinsic_dimension}, surprisal diversity \\cite{diveye}, and distributional gap measures \\cite{generator_barrier}; see \\citet{wu_survey_2025} and \\citet{jawahar_survey} for surveys.\nA persistent limitation is that these methods produce binary (real vs.\\ synthetic) decisions.\nRecent multi-class extensions (role recognition in human-LLM collaboration \\cite{beyond_binary}, multi-generator attribution \\cite{semeval2024_task8}) discriminate among different \\emph{sources} rather than recursive generation \\emph{depth}.\nEven when detection scores correlate with depth, they exhibit high cross-generator variance as ordinal predictors (binary F1 from 0.52 to 0.71; Table~\\ref{tab:baselines}), because each captures a single distributional property that generalizes inconsistently \\cite{paraphrase_evades,detection_possibilities}.\nAdversarial training approaches (e.g., RADAR \\cite{radar}) improve robustness to paraphrasing but remain binary detectors without depth awareness.\nOur contribution is not a new detection method but the task formulation (generation depth classification, framed within the broader ordinal classification literature \\cite{gutierrez_ordinal_survey,coral_ordinal}) and the finding that combining drifting and stationary features yields consistent cross-generator performance.\nThis is orthogonal to source attribution \\cite{uchendu_attribution,munir_looking_glass}, which identifies \\emph{which} model generated text; our LOGO evaluation decouples generator identity from depth.\n\n\\subsection{Model Collapse and Iterative Generation}\n\\label{sec:related-collapse}\n\nSelf-consuming generative models progressively lose distributional coverage \\cite{self_consuming_mad}, and model collapse is inevitable without fresh human data \\cite{curse_of_recursion}, though careful data mixing can mitigate this \\cite{model_collapse_avoidable,strong_model_collapse}.\nThese studies focus on \\emph{training-loop} degradation; our setting studies \\emph{inference chains}, where a fixed model generates text conditioned on its own prior output without retraining.\nThe distinction extends beyond setting: model collapse erodes distributional tail coverage irreversibly as training progresses \\cite{curse_of_recursion,strong_model_collapse}, whereas the drift we observe is reversible under fixed parameters and approximately preserves distributional shape (\\S\\ref{sec:results-differential}).\nThe drifting/stationary feature decomposition central to our analysis has no analogue in model collapse studies, which track aggregate divergence without separating location from shape components.\nIterative self-refinement \\cite{self_refine} represents another form of recursive LLM processing, but targets output improvement through feedback loops rather than open-ended continuation; the distributional drift we study arises specifically from unconstrained recursive generation.\n\nTwo concurrent works are most directly relevant.\n\\citet{broken_telephone} analyze paraphrasing and translation chains, showing progressive information loss.\n\\citet{markovian_chains} demonstrate that semantic-preservation constraints induce attractor dynamics bounding distinguishable depth to approximately three classes; their analysis focuses on characterizing convergence behavior through model-based perplexity tracking.\nWe differ in three respects: (i) we study \\emph{non-paraphrastic continuation} chains, where the absence of semantic anchoring permits richer depth signal; (ii) we use handcrafted features rather than model-internal representations, enabling the DDR decomposition into drifting vs.\\ stationary components; and (iii) we focus on \\emph{estimating} depth from text rather than characterizing the convergence dynamics of the generation process.\n\nThat both works independently converge on approximately three distinguishable classes reflects different mechanisms reaching the same practical ceiling.\n\\citet{markovian_chains} derive this bound from Markovian attractor dynamics: semantic-preservation constraints create fixed points where successive outputs become indistinguishable under model-internal perplexity.\nWe observe the same bound empirically through feature-space compression: inter-class KS statistics drop sharply after depth 2 (gen-1$\\rightarrow$gen-2: KS\\,=\\,0.28 vs.\\ gen-2$\\rightarrow$gen-3: KS\\,=\\,0.09 for entropy mean), collapsing discriminative margins.\nThe approaches are complementary: their theoretical framework explains \\emph{why} convergence occurs (attractor dynamics in semantic space), while our DDR decomposition reveals \\emph{what} converges (location properties) versus what remains stable (distributional shape), providing an empirical signature that can be exploited for detection without access to model internals.\n\n\\subsection{Vocabulary Diversity and Stylometry}\n\\label{sec:related-diversity}\n\nDeclining lexical diversity in LLM-generated text is documented in both training \\cite{curious_decline} and deployment \\cite{writing_diversity} settings.\nOur surface features (TTR and hapax ratio) are classical stylometric measures \\cite{stamatatos_survey,koppel_authorship} that we apply to inference chains, showing monotonic diversity decline across depths without model retraining.\nWe push beyond generator identity \\cite{uchendu_attribution} to the \\emph{depth} dimension, and show that diversity declines monotonically even under top-$p$ sampling \\cite{nucleus_sampling}.\n\n\\subsection{Data Quality and Provenance}\n\\label{sec:related-provenance}\n\nScalable data curation relies on quality signals \\cite{dsir,qurating,ccnet}; generation depth is a complementary provenance signal characterizing \\emph{how many steps removed} text is from a human source.\nProactive watermarking \\cite{watermark_llm,synthid_text,aaronson_watermark} embeds identifiable patterns, but watermark strength decays across multi-step chains \\cite{chainwash}, motivating passive post-hoc methods like ours.\nAt the feature level, our NLL analysis connects to \\citet{min_k_percent}, who use the probability tail for membership inference; we analyze the full NLL distribution for generation depth classification.\n",
    "structuredPatch": [
      {
        "oldStart": 23,
        "oldLines": 7,
        "newStart": 23,
        "newLines": 7,
        "lines": [
          " Iterative self-refinement \\cite{self_refine} represents another form of recursive LLM processing, but targets output improvement through feedback loops rather than open-ended continuation; the distributional drift we study arises specifically from unconstrained recursive generation.",
          " ",
          " Two concurrent works are most directly relevant.",
          "-\\citet{broken_telephone} analyze paraphrasing and translation chains, showing progressive information loss.",
          "+\\citet{broken_telephone} analyze paraphrasing and translation chains and show progressive information loss.",
          " \\citet{markovian_chains} demonstrate that semantic-preservation constraints induce attractor dynamics bounding distinguishable depth to approximately three classes; their analysis focuses on characterizing convergence behavior through model-based perplexity tracking.",
          " We differ in three respects: (i) we study \\emph{non-paraphrastic continuation} chains, where the absence of semantic anchoring permits richer depth signal; (ii) we use handcrafted features rather than model-internal representations, enabling the DDR decomposition into drifting vs.\\ stationary components; and (iii) we focus on \\emph{estimating} depth from text rather than characterizing the convergence dynamics of the generation process.",
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


### Tool call

_source line 86_

<details open><summary>🔧 Tool call — Edit · `toolu_01KhTghpBLUUV2yC8kF7Pu9D`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/related_work.tex",
  "old_string": "model-internal representations, enabling the DDR decomposition into drifting vs.\\ stationary components;",
  "new_string": "model-internal representations, which enables the DDR decomposition into drifting vs.\\ stationary components;"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "fb67e209-3880-4672-aecf-ea520abb05ea",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Fdq885ZGJeioznoH8Xjqs3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14907,
      "cache_read_input_tokens": 68592,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14907
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

_source line 87 · 2026-05-17T19:57:12.749Z_

<details><summary>↩ Tool result · `toolu_01KhTghpBLUUV2yC8kF7Pu9D`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/related_work.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "557e1c6f-53f6-4a89-b9d3-ab14ab7d53e8",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/related_work.tex",
    "oldString": "model-internal representations, enabling the DDR decomposition into drifting vs.\\ stationary components;",
    "newString": "model-internal representations, which enables the DDR decomposition into drifting vs.\\ stationary components;",
    "originalFile": "\\section{Related Work}\n\\label{sec:related}\n\n\\subsection{AI-Generated Text Detection}\n\\label{sec:related-detection}\n\nMethods for distinguishing human-written from machine-generated text have evolved from statistical tests \\cite{gltr,grover,release_strategies} to zero-shot reference-model approaches \\cite{detectgpt,fast_detectgpt,binoculars,dna_gpt} and learned classifiers \\cite{ghostbuster,feat_aug_transformer,reliable_detection,ld_score}.\nRecent work pursues diverse signals including intrinsic dimensionality \\cite{intrinsic_dimension}, surprisal diversity \\cite{diveye}, and distributional gap measures \\cite{generator_barrier}; see \\citet{wu_survey_2025} and \\citet{jawahar_survey} for surveys.\nA persistent limitation is that these methods produce binary (real vs.\\ synthetic) decisions.\nRecent multi-class extensions (role recognition in human-LLM collaboration \\cite{beyond_binary}, multi-generator attribution \\cite{semeval2024_task8}) discriminate among different \\emph{sources} rather than recursive generation \\emph{depth}.\nEven when detection scores correlate with depth, they exhibit high cross-generator variance as ordinal predictors (binary F1 from 0.52 to 0.71; Table~\\ref{tab:baselines}), because each captures a single distributional property that generalizes inconsistently \\cite{paraphrase_evades,detection_possibilities}.\nAdversarial training approaches (e.g., RADAR \\cite{radar}) improve robustness to paraphrasing but remain binary detectors without depth awareness.\nOur contribution is not a new detection method but the task formulation (generation depth classification, framed within the broader ordinal classification literature \\cite{gutierrez_ordinal_survey,coral_ordinal}) and the finding that combining drifting and stationary features yields consistent cross-generator performance.\nThis is orthogonal to source attribution \\cite{uchendu_attribution,munir_looking_glass}, which identifies \\emph{which} model generated text; our LOGO evaluation decouples generator identity from depth.\n\n\\subsection{Model Collapse and Iterative Generation}\n\\label{sec:related-collapse}\n\nSelf-consuming generative models progressively lose distributional coverage \\cite{self_consuming_mad}, and model collapse is inevitable without fresh human data \\cite{curse_of_recursion}, though careful data mixing can mitigate this \\cite{model_collapse_avoidable,strong_model_collapse}.\nThese studies focus on \\emph{training-loop} degradation; our setting studies \\emph{inference chains}, where a fixed model generates text conditioned on its own prior output without retraining.\nThe distinction extends beyond setting: model collapse erodes distributional tail coverage irreversibly as training progresses \\cite{curse_of_recursion,strong_model_collapse}, whereas the drift we observe is reversible under fixed parameters and approximately preserves distributional shape (\\S\\ref{sec:results-differential}).\nThe drifting/stationary feature decomposition central to our analysis has no analogue in model collapse studies, which track aggregate divergence without separating location from shape components.\nIterative self-refinement \\cite{self_refine} represents another form of recursive LLM processing, but targets output improvement through feedback loops rather than open-ended continuation; the distributional drift we study arises specifically from unconstrained recursive generation.\n\nTwo concurrent works are most directly relevant.\n\\citet{broken_telephone} analyze paraphrasing and translation chains and show progressive information loss.\n\\citet{markovian_chains} demonstrate that semantic-preservation constraints induce attractor dynamics bounding distinguishable depth to approximately three classes; their analysis focuses on characterizing convergence behavior through model-based perplexity tracking.\nWe differ in three respects: (i) we study \\emph{non-paraphrastic continuation} chains, where the absence of semantic anchoring permits richer depth signal; (ii) we use handcrafted features rather than model-internal representations, enabling the DDR decomposition into drifting vs.\\ stationary components; and (iii) we focus on \\emph{estimating} depth from text rather than characterizing the convergence dynamics of the generation process.\n\nThat both works independently converge on approximately three distinguishable classes reflects different mechanisms reaching the same practical ceiling.\n\\citet{markovian_chains} derive this bound from Markovian attractor dynamics: semantic-preservation constraints create fixed points where successive outputs become indistinguishable under model-internal perplexity.\nWe observe the same bound empirically through feature-space compression: inter-class KS statistics drop sharply after depth 2 (gen-1$\\rightarrow$gen-2: KS\\,=\\,0.28 vs.\\ gen-2$\\rightarrow$gen-3: KS\\,=\\,0.09 for entropy mean), collapsing discriminative margins.\nThe approaches are complementary: their theoretical framework explains \\emph{why} convergence occurs (attractor dynamics in semantic space), while our DDR decomposition reveals \\emph{what} converges (location properties) versus what remains stable (distributional shape), providing an empirical signature that can be exploited for detection without access to model internals.\n\n\\subsection{Vocabulary Diversity and Stylometry}\n\\label{sec:related-diversity}\n\nDeclining lexical diversity in LLM-generated text is documented in both training \\cite{curious_decline} and deployment \\cite{writing_diversity} settings.\nOur surface features (TTR and hapax ratio) are classical stylometric measures \\cite{stamatatos_survey,koppel_authorship} that we apply to inference chains, showing monotonic diversity decline across depths without model retraining.\nWe push beyond generator identity \\cite{uchendu_attribution} to the \\emph{depth} dimension, and show that diversity declines monotonically even under top-$p$ sampling \\cite{nucleus_sampling}.\n\n\\subsection{Data Quality and Provenance}\n\\label{sec:related-provenance}\n\nScalable data curation relies on quality signals \\cite{dsir,qurating,ccnet}; generation depth is a complementary provenance signal characterizing \\emph{how many steps removed} text is from a human source.\nProactive watermarking \\cite{watermark_llm,synthid_text,aaronson_watermark} embeds identifiable patterns, but watermark strength decays across multi-step chains \\cite{chainwash}, motivating passive post-hoc methods like ours.\nAt the feature level, our NLL analysis connects to \\citet{min_k_percent}, who use the probability tail for membership inference; we analyze the full NLL distribution for generation depth classification.\n",
    "structuredPatch": [
      {
        "oldStart": 25,
        "oldLines": 7,
        "newStart": 25,
        "newLines": 7,
        "lines": [
          " Two concurrent works are most directly relevant.",
          " \\citet{broken_telephone} analyze paraphrasing and translation chains and show progressive information loss.",
          " \\citet{markovian_chains} demonstrate that semantic-preservation constraints induce attractor dynamics bounding distinguishable depth to approximately three classes; their analysis focuses on characterizing convergence behavior through model-based perplexity tracking.",
          "-We differ in three respects: (i) we study \\emph{non-paraphrastic continuation} chains, where the absence of semantic anchoring permits richer depth signal; (ii) we use handcrafted features rather than model-internal representations, enabling the DDR decomposition into drifting vs.\\ stationary components; and (iii) we focus on \\emph{estimating} depth from text rather than characterizing the convergence dynamics of the generation process.",
          "+We differ in three respects: (i) we study \\emph{non-paraphrastic continuation} chains, where the absence of semantic anchoring permits richer depth signal; (ii) we use handcrafted features rather than model-internal representations, which enables the DDR decomposition into drifting vs.\\ stationary components; and (iii) we focus on \\emph{estimating} depth from text rather than characterizing the convergence dynamics of the generation process.",
          " ",
          " That both works independently converge on approximately three distinguishable classes reflects different mechanisms reaching the same practical ceiling.",
          " \\citet{markovian_chains} derive this bound from Markovian attractor dynamics: semantic-preservation constraints create fixed points where successive outputs become indistinguishable under model-internal perplexity."
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

_source line 88_

<details open><summary>🔧 Tool call — Edit · `toolu_01HaksFZS39AkbanVBftTqUG`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/related_work.tex",
  "old_string": "what remains stable (distributional shape), providing an empirical signature that can be exploited for detection without access to model internals.",
  "new_string": "what remains stable (distributional shape) and provides an empirical signature that can be exploited for detection without access to model internals."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "e9f46770-3ea7-4e9b-aa5f-69980b917975",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Fdq885ZGJeioznoH8Xjqs3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14907,
      "cache_read_input_tokens": 68592,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14907
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

_source line 89 · 2026-05-17T19:57:15.064Z_

<details><summary>↩ Tool result · `toolu_01HaksFZS39AkbanVBftTqUG`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/related_work.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "6a461708-126e-49d6-a57c-dea278c7d573",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/related_work.tex",
    "oldString": "what remains stable (distributional shape), providing an empirical signature that can be exploited for detection without access to model internals.",
    "newString": "what remains stable (distributional shape) and provides an empirical signature that can be exploited for detection without access to model internals.",
    "originalFile": "\\section{Related Work}\n\\label{sec:related}\n\n\\subsection{AI-Generated Text Detection}\n\\label{sec:related-detection}\n\nMethods for distinguishing human-written from machine-generated text have evolved from statistical tests \\cite{gltr,grover,release_strategies} to zero-shot reference-model approaches \\cite{detectgpt,fast_detectgpt,binoculars,dna_gpt} and learned classifiers \\cite{ghostbuster,feat_aug_transformer,reliable_detection,ld_score}.\nRecent work pursues diverse signals including intrinsic dimensionality \\cite{intrinsic_dimension}, surprisal diversity \\cite{diveye}, and distributional gap measures \\cite{generator_barrier}; see \\citet{wu_survey_2025} and \\citet{jawahar_survey} for surveys.\nA persistent limitation is that these methods produce binary (real vs.\\ synthetic) decisions.\nRecent multi-class extensions (role recognition in human-LLM collaboration \\cite{beyond_binary}, multi-generator attribution \\cite{semeval2024_task8}) discriminate among different \\emph{sources} rather than recursive generation \\emph{depth}.\nEven when detection scores correlate with depth, they exhibit high cross-generator variance as ordinal predictors (binary F1 from 0.52 to 0.71; Table~\\ref{tab:baselines}), because each captures a single distributional property that generalizes inconsistently \\cite{paraphrase_evades,detection_possibilities}.\nAdversarial training approaches (e.g., RADAR \\cite{radar}) improve robustness to paraphrasing but remain binary detectors without depth awareness.\nOur contribution is not a new detection method but the task formulation (generation depth classification, framed within the broader ordinal classification literature \\cite{gutierrez_ordinal_survey,coral_ordinal}) and the finding that combining drifting and stationary features yields consistent cross-generator performance.\nThis is orthogonal to source attribution \\cite{uchendu_attribution,munir_looking_glass}, which identifies \\emph{which} model generated text; our LOGO evaluation decouples generator identity from depth.\n\n\\subsection{Model Collapse and Iterative Generation}\n\\label{sec:related-collapse}\n\nSelf-consuming generative models progressively lose distributional coverage \\cite{self_consuming_mad}, and model collapse is inevitable without fresh human data \\cite{curse_of_recursion}, though careful data mixing can mitigate this \\cite{model_collapse_avoidable,strong_model_collapse}.\nThese studies focus on \\emph{training-loop} degradation; our setting studies \\emph{inference chains}, where a fixed model generates text conditioned on its own prior output without retraining.\nThe distinction extends beyond setting: model collapse erodes distributional tail coverage irreversibly as training progresses \\cite{curse_of_recursion,strong_model_collapse}, whereas the drift we observe is reversible under fixed parameters and approximately preserves distributional shape (\\S\\ref{sec:results-differential}).\nThe drifting/stationary feature decomposition central to our analysis has no analogue in model collapse studies, which track aggregate divergence without separating location from shape components.\nIterative self-refinement \\cite{self_refine} represents another form of recursive LLM processing, but targets output improvement through feedback loops rather than open-ended continuation; the distributional drift we study arises specifically from unconstrained recursive generation.\n\nTwo concurrent works are most directly relevant.\n\\citet{broken_telephone} analyze paraphrasing and translation chains and show progressive information loss.\n\\citet{markovian_chains} demonstrate that semantic-preservation constraints induce attractor dynamics bounding distinguishable depth to approximately three classes; their analysis focuses on characterizing convergence behavior through model-based perplexity tracking.\nWe differ in three respects: (i) we study \\emph{non-paraphrastic continuation} chains, where the absence of semantic anchoring permits richer depth signal; (ii) we use handcrafted features rather than model-internal representations, which enables the DDR decomposition into drifting vs.\\ stationary components; and (iii) we focus on \\emph{estimating} depth from text rather than characterizing the convergence dynamics of the generation process.\n\nThat both works independently converge on approximately three distinguishable classes reflects different mechanisms reaching the same practical ceiling.\n\\citet{markovian_chains} derive this bound from Markovian attractor dynamics: semantic-preservation constraints create fixed points where successive outputs become indistinguishable under model-internal perplexity.\nWe observe the same bound empirically through feature-space compression: inter-class KS statistics drop sharply after depth 2 (gen-1$\\rightarrow$gen-2: KS\\,=\\,0.28 vs.\\ gen-2$\\rightarrow$gen-3: KS\\,=\\,0.09 for entropy mean), collapsing discriminative margins.\nThe approaches are complementary: their theoretical framework explains \\emph{why} convergence occurs (attractor dynamics in semantic space), while our DDR decomposition reveals \\emph{what} converges (location properties) versus what remains stable (distributional shape), providing an empirical signature that can be exploited for detection without access to model internals.\n\n\\subsection{Vocabulary Diversity and Stylometry}\n\\label{sec:related-diversity}\n\nDeclining lexical diversity in LLM-generated text is documented in both training \\cite{curious_decline} and deployment \\cite{writing_diversity} settings.\nOur surface features (TTR and hapax ratio) are classical stylometric measures \\cite{stamatatos_survey,koppel_authorship} that we apply to inference chains, showing monotonic diversity decline across depths without model retraining.\nWe push beyond generator identity \\cite{uchendu_attribution} to the \\emph{depth} dimension, and show that diversity declines monotonically even under top-$p$ sampling \\cite{nucleus_sampling}.\n\n\\subsection{Data Quality and Provenance}\n\\label{sec:related-provenance}\n\nScalable data curation relies on quality signals \\cite{dsir,qurating,ccnet}; generation depth is a complementary provenance signal characterizing \\emph{how many steps removed} text is from a human source.\nProactive watermarking \\cite{watermark_llm,synthid_text,aaronson_watermark} embeds identifiable patterns, but watermark strength decays across multi-step chains \\cite{chainwash}, motivating passive post-hoc methods like ours.\nAt the feature level, our NLL analysis connects to \\citet{min_k_percent}, who use the probability tail for membership inference; we analyze the full NLL distribution for generation depth classification.\n",
    "structuredPatch": [
      {
        "oldStart": 30,
        "oldLines": 7,
        "newStart": 30,
        "newLines": 7,
        "lines": [
          " That both works independently converge on approximately three distinguishable classes reflects different mechanisms reaching the same practical ceiling.",
          " \\citet{markovian_chains} derive this bound from Markovian attractor dynamics: semantic-preservation constraints create fixed points where successive outputs become indistinguishable under model-internal perplexity.",
          " We observe the same bound empirically through feature-space compression: inter-class KS statistics drop sharply after depth 2 (gen-1$\\rightarrow$gen-2: KS\\,=\\,0.28 vs.\\ gen-2$\\rightarrow$gen-3: KS\\,=\\,0.09 for entropy mean), collapsing discriminative margins.",
          "-The approaches are complementary: their theoretical framework explains \\emph{why} convergence occurs (attractor dynamics in semantic space), while our DDR decomposition reveals \\emph{what} converges (location properties) versus what remains stable (distributional shape), providing an empirical signature that can be exploited for detection without access to model internals.",
          "+The approaches are complementary: their theoretical framework explains \\emph{why} convergence occurs (attractor dynamics in semantic space), while our DDR decomposition reveals \\emph{what} converges (location properties) versus what remains stable (distributional shape) and provides an empirical signature that can be exploited for detection without access to model internals.",
          " ",
          " \\subsection{Vocabulary Diversity and Stylometry}",
          " \\label{sec:related-diversity}"
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

_source line 90_

<details open><summary>🔧 Tool call — Edit · `toolu_01AKgaYST4YDjeJBZ52t3hwX`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/related_work.tex",
  "old_string": "that we apply to inference chains, showing monotonic diversity decline across depths without model retraining.",
  "new_string": "that we apply to inference chains; these features show monotonic diversity decline across depths without model retraining."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "38ead814-9c17-460c-8562-4e5e72f80806",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Fdq885ZGJeioznoH8Xjqs3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14907,
      "cache_read_input_tokens": 68592,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14907
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

_source line 91 · 2026-05-17T19:57:16.973Z_

<details><summary>↩ Tool result · `toolu_01AKgaYST4YDjeJBZ52t3hwX`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/related_work.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "ddc12fcb-c9fe-4cd4-975f-ca0357d6a0f0",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/related_work.tex",
    "oldString": "that we apply to inference chains, showing monotonic diversity decline across depths without model retraining.",
    "newString": "that we apply to inference chains; these features show monotonic diversity decline across depths without model retraining.",
    "originalFile": "\\section{Related Work}\n\\label{sec:related}\n\n\\subsection{AI-Generated Text Detection}\n\\label{sec:related-detection}\n\nMethods for distinguishing human-written from machine-generated text have evolved from statistical tests \\cite{gltr,grover,release_strategies} to zero-shot reference-model approaches \\cite{detectgpt,fast_detectgpt,binoculars,dna_gpt} and learned classifiers \\cite{ghostbuster,feat_aug_transformer,reliable_detection,ld_score}.\nRecent work pursues diverse signals including intrinsic dimensionality \\cite{intrinsic_dimension}, surprisal diversity \\cite{diveye}, and distributional gap measures \\cite{generator_barrier}; see \\citet{wu_survey_2025} and \\citet{jawahar_survey} for surveys.\nA persistent limitation is that these methods produce binary (real vs.\\ synthetic) decisions.\nRecent multi-class extensions (role recognition in human-LLM collaboration \\cite{beyond_binary}, multi-generator attribution \\cite{semeval2024_task8}) discriminate among different \\emph{sources} rather than recursive generation \\emph{depth}.\nEven when detection scores correlate with depth, they exhibit high cross-generator variance as ordinal predictors (binary F1 from 0.52 to 0.71; Table~\\ref{tab:baselines}), because each captures a single distributional property that generalizes inconsistently \\cite{paraphrase_evades,detection_possibilities}.\nAdversarial training approaches (e.g., RADAR \\cite{radar}) improve robustness to paraphrasing but remain binary detectors without depth awareness.\nOur contribution is not a new detection method but the task formulation (generation depth classification, framed within the broader ordinal classification literature \\cite{gutierrez_ordinal_survey,coral_ordinal}) and the finding that combining drifting and stationary features yields consistent cross-generator performance.\nThis is orthogonal to source attribution \\cite{uchendu_attribution,munir_looking_glass}, which identifies \\emph{which} model generated text; our LOGO evaluation decouples generator identity from depth.\n\n\\subsection{Model Collapse and Iterative Generation}\n\\label{sec:related-collapse}\n\nSelf-consuming generative models progressively lose distributional coverage \\cite{self_consuming_mad}, and model collapse is inevitable without fresh human data \\cite{curse_of_recursion}, though careful data mixing can mitigate this \\cite{model_collapse_avoidable,strong_model_collapse}.\nThese studies focus on \\emph{training-loop} degradation; our setting studies \\emph{inference chains}, where a fixed model generates text conditioned on its own prior output without retraining.\nThe distinction extends beyond setting: model collapse erodes distributional tail coverage irreversibly as training progresses \\cite{curse_of_recursion,strong_model_collapse}, whereas the drift we observe is reversible under fixed parameters and approximately preserves distributional shape (\\S\\ref{sec:results-differential}).\nThe drifting/stationary feature decomposition central to our analysis has no analogue in model collapse studies, which track aggregate divergence without separating location from shape components.\nIterative self-refinement \\cite{self_refine} represents another form of recursive LLM processing, but targets output improvement through feedback loops rather than open-ended continuation; the distributional drift we study arises specifically from unconstrained recursive generation.\n\nTwo concurrent works are most directly relevant.\n\\citet{broken_telephone} analyze paraphrasing and translation chains and show progressive information loss.\n\\citet{markovian_chains} demonstrate that semantic-preservation constraints induce attractor dynamics bounding distinguishable depth to approximately three classes; their analysis focuses on characterizing convergence behavior through model-based perplexity tracking.\nWe differ in three respects: (i) we study \\emph{non-paraphrastic continuation} chains, where the absence of semantic anchoring permits richer depth signal; (ii) we use handcrafted features rather than model-internal representations, which enables the DDR decomposition into drifting vs.\\ stationary components; and (iii) we focus on \\emph{estimating} depth from text rather than characterizing the convergence dynamics of the generation process.\n\nThat both works independently converge on approximately three distinguishable classes reflects different mechanisms reaching the same practical ceiling.\n\\citet{markovian_chains} derive this bound from Markovian attractor dynamics: semantic-preservation constraints create fixed points where successive outputs become indistinguishable under model-internal perplexity.\nWe observe the same bound empirically through feature-space compression: inter-class KS statistics drop sharply after depth 2 (gen-1$\\rightarrow$gen-2: KS\\,=\\,0.28 vs.\\ gen-2$\\rightarrow$gen-3: KS\\,=\\,0.09 for entropy mean), collapsing discriminative margins.\nThe approaches are complementary: their theoretical framework explains \\emph{why} convergence occurs (attractor dynamics in semantic space), while our DDR decomposition reveals \\emph{what} converges (location properties) versus what remains stable (distributional shape) and provides an empirical signature that can be exploited for detection without access to model internals.\n\n\\subsection{Vocabulary Diversity and Stylometry}\n\\label{sec:related-diversity}\n\nDeclining lexical diversity in LLM-generated text is documented in both training \\cite{curious_decline} and deployment \\cite{writing_diversity} settings.\nOur surface features (TTR and hapax ratio) are classical stylometric measures \\cite{stamatatos_survey,koppel_authorship} that we apply to inference chains, showing monotonic diversity decline across depths without model retraining.\nWe push beyond generator identity \\cite{uchendu_attribution} to the \\emph{depth} dimension, and show that diversity declines monotonically even under top-$p$ sampling \\cite{nucleus_sampling}.\n\n\\subsection{Data Quality and Provenance}\n\\label{sec:related-provenance}\n\nScalable data curation relies on quality signals \\cite{dsir,qurating,ccnet}; generation depth is a complementary provenance signal characterizing \\emph{how many steps removed} text is from a human source.\nProactive watermarking \\cite{watermark_llm,synthid_text,aaronson_watermark} embeds identifiable patterns, but watermark strength decays across multi-step chains \\cite{chainwash}, motivating passive post-hoc methods like ours.\nAt the feature level, our NLL analysis connects to \\citet{min_k_percent}, who use the probability tail for membership inference; we analyze the full NLL distribution for generation depth classification.\n",
    "structuredPatch": [
      {
        "oldStart": 36,
        "oldLines": 7,
        "newStart": 36,
        "newLines": 7,
        "lines": [
          " \\label{sec:related-diversity}",
          " ",
          " Declining lexical diversity in LLM-generated text is documented in both training \\cite{curious_decline} and deployment \\cite{writing_diversity} settings.",
          "-Our surface features (TTR and hapax ratio) are classical stylometric measures \\cite{stamatatos_survey,koppel_authorship} that we apply to inference chains, showing monotonic diversity decline across depths without model retraining.",
          "+Our surface features (TTR and hapax ratio) are classical stylometric measures \\cite{stamatatos_survey,koppel_authorship} that we apply to inference chains; these features show monotonic diversity decline across depths without model retraining.",
          " We push beyond generator identity \\cite{uchendu_attribution} to the \\emph{depth} dimension, and show that diversity declines monotonically even under top-$p$ sampling \\cite{nucleus_sampling}.",
          " ",
          " \\subsection{Data Quality and Provenance}"
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

_source line 92_

<details open><summary>🔧 Tool call — Edit · `toolu_01JfC3wpURYgygEhoQmRdwrF`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/related_work.tex",
  "old_string": "decays across multi-step chains \\cite{chainwash}, motivating passive post-hoc methods like ours.",
  "new_string": "decays across multi-step chains \\cite{chainwash}, which motivates passive post-hoc methods like ours."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "e50ed698-ce00-4b1e-877c-a3b484ca3573",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Fdq885ZGJeioznoH8Xjqs3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14907,
      "cache_read_input_tokens": 68592,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14907
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

_source line 93 · 2026-05-17T19:57:18.855Z_

<details><summary>↩ Tool result · `toolu_01JfC3wpURYgygEhoQmRdwrF`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/related_work.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "cfd760c6-2227-45e7-9427-02c96a8dd518",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/related_work.tex",
    "oldString": "decays across multi-step chains \\cite{chainwash}, motivating passive post-hoc methods like ours.",
    "newString": "decays across multi-step chains \\cite{chainwash}, which motivates passive post-hoc methods like ours.",
    "originalFile": "\\section{Related Work}\n\\label{sec:related}\n\n\\subsection{AI-Generated Text Detection}\n\\label{sec:related-detection}\n\nMethods for distinguishing human-written from machine-generated text have evolved from statistical tests \\cite{gltr,grover,release_strategies} to zero-shot reference-model approaches \\cite{detectgpt,fast_detectgpt,binoculars,dna_gpt} and learned classifiers \\cite{ghostbuster,feat_aug_transformer,reliable_detection,ld_score}.\nRecent work pursues diverse signals including intrinsic dimensionality \\cite{intrinsic_dimension}, surprisal diversity \\cite{diveye}, and distributional gap measures \\cite{generator_barrier}; see \\citet{wu_survey_2025} and \\citet{jawahar_survey} for surveys.\nA persistent limitation is that these methods produce binary (real vs.\\ synthetic) decisions.\nRecent multi-class extensions (role recognition in human-LLM collaboration \\cite{beyond_binary}, multi-generator attribution \\cite{semeval2024_task8}) discriminate among different \\emph{sources} rather than recursive generation \\emph{depth}.\nEven when detection scores correlate with depth, they exhibit high cross-generator variance as ordinal predictors (binary F1 from 0.52 to 0.71; Table~\\ref{tab:baselines}), because each captures a single distributional property that generalizes inconsistently \\cite{paraphrase_evades,detection_possibilities}.\nAdversarial training approaches (e.g., RADAR \\cite{radar}) improve robustness to paraphrasing but remain binary detectors without depth awareness.\nOur contribution is not a new detection method but the task formulation (generation depth classification, framed within the broader ordinal classification literature \\cite{gutierrez_ordinal_survey,coral_ordinal}) and the finding that combining drifting and stationary features yields consistent cross-generator performance.\nThis is orthogonal to source attribution \\cite{uchendu_attribution,munir_looking_glass}, which identifies \\emph{which} model generated text; our LOGO evaluation decouples generator identity from depth.\n\n\\subsection{Model Collapse and Iterative Generation}\n\\label{sec:related-collapse}\n\nSelf-consuming generative models progressively lose distributional coverage \\cite{self_consuming_mad}, and model collapse is inevitable without fresh human data \\cite{curse_of_recursion}, though careful data mixing can mitigate this \\cite{model_collapse_avoidable,strong_model_collapse}.\nThese studies focus on \\emph{training-loop} degradation; our setting studies \\emph{inference chains}, where a fixed model generates text conditioned on its own prior output without retraining.\nThe distinction extends beyond setting: model collapse erodes distributional tail coverage irreversibly as training progresses \\cite{curse_of_recursion,strong_model_collapse}, whereas the drift we observe is reversible under fixed parameters and approximately preserves distributional shape (\\S\\ref{sec:results-differential}).\nThe drifting/stationary feature decomposition central to our analysis has no analogue in model collapse studies, which track aggregate divergence without separating location from shape components.\nIterative self-refinement \\cite{self_refine} represents another form of recursive LLM processing, but targets output improvement through feedback loops rather than open-ended continuation; the distributional drift we study arises specifically from unconstrained recursive generation.\n\nTwo concurrent works are most directly relevant.\n\\citet{broken_telephone} analyze paraphrasing and translation chains and show progressive information loss.\n\\citet{markovian_chains} demonstrate that semantic-preservation constraints induce attractor dynamics bounding distinguishable depth to approximately three classes; their analysis focuses on characterizing convergence behavior through model-based perplexity tracking.\nWe differ in three respects: (i) we study \\emph{non-paraphrastic continuation} chains, where the absence of semantic anchoring permits richer depth signal; (ii) we use handcrafted features rather than model-internal representations, which enables the DDR decomposition into drifting vs.\\ stationary components; and (iii) we focus on \\emph{estimating} depth from text rather than characterizing the convergence dynamics of the generation process.\n\nThat both works independently converge on approximately three distinguishable classes reflects different mechanisms reaching the same practical ceiling.\n\\citet{markovian_chains} derive this bound from Markovian attractor dynamics: semantic-preservation constraints create fixed points where successive outputs become indistinguishable under model-internal perplexity.\nWe observe the same bound empirically through feature-space compression: inter-class KS statistics drop sharply after depth 2 (gen-1$\\rightarrow$gen-2: KS\\,=\\,0.28 vs.\\ gen-2$\\rightarrow$gen-3: KS\\,=\\,0.09 for entropy mean), collapsing discriminative margins.\nThe approaches are complementary: their theoretical framework explains \\emph{why} convergence occurs (attractor dynamics in semantic space), while our DDR decomposition reveals \\emph{what} converges (location properties) versus what remains stable (distributional shape) and provides an empirical signature that can be exploited for detection without access to model internals.\n\n\\subsection{Vocabulary Diversity and Stylometry}\n\\label{sec:related-diversity}\n\nDeclining lexical diversity in LLM-generated text is documented in both training \\cite{curious_decline} and deployment \\cite{writing_diversity} settings.\nOur surface features (TTR and hapax ratio) are classical stylometric measures \\cite{stamatatos_survey,koppel_authorship} that we apply to inference chains; these features show monotonic diversity decline across depths without model retraining.\nWe push beyond generator identity \\cite{uchendu_attribution} to the \\emph{depth} dimension, and show that diversity declines monotonically even under top-$p$ sampling \\cite{nucleus_sampling}.\n\n\\subsection{Data Quality and Provenance}\n\\label{sec:related-provenance}\n\nScalable data curation relies on quality signals \\cite{dsir,qurating,ccnet}; generation depth is a complementary provenance signal characterizing \\emph{how many steps removed} text is from a human source.\nProactive watermarking \\cite{watermark_llm,synthid_text,aaronson_watermark} embeds identifiable patterns, but watermark strength decays across multi-step chains \\cite{chainwash}, motivating passive post-hoc methods like ours.\nAt the feature level, our NLL analysis connects to \\citet{min_k_percent}, who use the probability tail for membership inference; we analyze the full NLL distribution for generation depth classification.\n",
    "structuredPatch": [
      {
        "oldStart": 43,
        "oldLines": 5,
        "newStart": 43,
        "newLines": 5,
        "lines": [
          " \\label{sec:related-provenance}",
          " ",
          " Scalable data curation relies on quality signals \\cite{dsir,qurating,ccnet}; generation depth is a complementary provenance signal characterizing \\emph{how many steps removed} text is from a human source.",
          "-Proactive watermarking \\cite{watermark_llm,synthid_text,aaronson_watermark} embeds identifiable patterns, but watermark strength decays across multi-step chains \\cite{chainwash}, motivating passive post-hoc methods like ours.",
          "+Proactive watermarking \\cite{watermark_llm,synthid_text,aaronson_watermark} embeds identifiable patterns, but watermark strength decays across multi-step chains \\cite{chainwash}, which motivates passive post-hoc methods like ours.",
          " At the feature level, our NLL analysis connects to \\citet{min_k_percent}, who use the probability tail for membership inference; we analyze the full NLL distribution for generation depth classification."
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

_source line 94_

<details open><summary>🔧 Tool call — Edit · `toolu_01Chc9oCDPdxKgQSqzc2VZpr`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex",
  "old_string": "under 5-fold CV,\\footnote{Cross-model chains use the original five-generator subset (Pythia, OLMo, Qwen); Llama and Mistral were added later for single-generator evaluation.} confirming that depth signal persists when text passes through heterogeneous generators.",
  "new_string": "under 5-fold CV,\\footnote{Cross-model chains use the original five-generator subset (Pythia, OLMo, Qwen); Llama and Mistral were added later for single-generator evaluation.} which confirms that depth signal persists when text passes through heterogeneous generators."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "60957ad2-8245-4a41-abd1-3466334a8a8f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Fdq885ZGJeioznoH8Xjqs3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14907,
      "cache_read_input_tokens": 68592,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14907
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

_source line 95 · 2026-05-17T19:57:22.675Z_

<details><summary>↩ Tool result · `toolu_01Chc9oCDPdxKgQSqzc2VZpr`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "426060f5-e4f8-403c-9feb-1b71fa57734c",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex",
    "oldString": "under 5-fold CV,\\footnote{Cross-model chains use the original five-generator subset (Pythia, OLMo, Qwen); Llama and Mistral were added later for single-generator evaluation.} confirming that depth signal persists when text passes through heterogeneous generators.",
    "newString": "under 5-fold CV,\\footnote{Cross-model chains use the original five-generator subset (Pythia, OLMo, Qwen); Llama and Mistral were added later for single-generator evaluation.} which confirms that depth signal persists when text passes through heterogeneous generators.",
    "originalFile": "\\section{Results}\n\\label{sec:results}\n\n\\subsection{Depth Classification Performance}\n\\label{sec:results-classification}\n\nThe 7-feature ensemble achieves 3-class LOGO F1\\,=\\,0.762 (95\\% CI [0.758, 0.766]; $N$\\,=\\,37{,}058) across eight generators from five families (Table~\\ref{tab:logo-results}).\nBecause gen-0 seeds are shared across generators (\\S\\ref{sec:generation}), gen-0 classification is near-perfect (per-class F1\\,$\\approx$\\,0.94) and the 3-class metric is inflated by this overlap.\nWe therefore adopt leak-free binary F1 (gen-1 vs.\\ gen-2+)\\,=\\,0.694, CI [0.688, 0.700], as the primary metric throughout; it excludes gen-0 entirely and is unaffected by seed sharing.\nPer-generator binary F1 ranges from 0.633 (Mistral-7B) to 0.724 (Pythia-2.8B); the primary difficulty is distinguishing gen-1 from gen-2+ (Appendix~\\ref{app:confusion}).\nLarger generators show moderate degradation (Qwen3-8B: 0.692, Mistral-7B: 0.633) relative to the 0.694 average.\nThe Pythia-1B/2.8B crossover between three-class and binary scores (0.806 vs.\\ 0.798 and 0.718 vs.\\ 0.724, respectively) reflects differences in gen-0 classification accuracy rather than in depth discrimination per se.\n\n\\paragraph{Cross-model generalization.}\nCross-model chains (randomly selected generator per step) yield 3-class F1\\,=\\,0.809 and binary F1\\,=\\,0.764 under 5-fold CV,\\footnote{Cross-model chains use the original five-generator subset (Pythia, OLMo, Qwen); Llama and Mistral were added later for single-generator evaluation.} confirming that depth signal persists when text passes through heterogeneous generators.\nThe higher cross-model performance relative to single-generator LOGO (3-class: 0.809 vs.\\ 0.762) suggests that generator heterogeneity amplifies distributional shifts between depths, making each recursive step more distinct.\nUnder class balancing, macro F1 reaches 0.831 (per-class breakdown in Appendix~\\ref{app:cross-model-detail}).\n\nLeave-one-family-out (LOFO) evaluation yields average binary F1\\,=\\,0.686, confirming transfer across architectural families.\nA scale effect emerges: Pythia generators achieve the highest binary F1 (0.718--0.724), while larger models show degradation (Mistral-7B: 0.633), consistent with higher-capacity models compressing the feature margins DDR exploits.\nThe signal generalizes across text domains with variation (Appendix~\\ref{app:domain}).\n\n\\paragraph{Length confound control.}\nLength-matched subsampling yields binary F1\\,=\\,0.724 (vs.\\ 0.770 unmatched); a random-subsample control confirms the drop reflects deconfounding, not sample-size reduction (Appendix~\\ref{app:length}).\n\n\n\\begin{table}[t]\n\\centering\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llcccc}\n\\toprule\n\\textbf{Model} & \\textbf{Family} & \\textbf{Params} & \\textbf{3-cl F1} & \\textbf{Bin F1} & \\textbf{95\\% CI} \\\\\n\\midrule\nPythia-2.8B     & Pythia  & 2.8B & 0.798 & \\textbf{0.724} & [.707, .742] \\\\\nPythia-1B       & Pythia  & 1.0B & \\textbf{0.806} & 0.718 & [.700, .735] \\\\\nQwen3-1.7B     & Qwen    & 1.7B & 0.772 & 0.709 & [.693, .726] \\\\\nLlama-3.2-3B   & Llama   & 3.2B & 0.775 & 0.697 & [.680, .713] \\\\\nOLMo-2-1B      & OLMo    & 1.5B & 0.781 & 0.695 & [.679, .711] \\\\\nQwen3-8B       & Qwen    & 8.2B & 0.714 & 0.692 & [.674, .708] \\\\\nQwen3-0.6B     & Qwen    & 0.6B & 0.780 & 0.691 & [.673, .709] \\\\\nMistral-7B     & Mistral & 7.0B & 0.682 & 0.633 & [.617, .648] \\\\\n\\midrule\n\\multicolumn{3}{l}{\\textbf{Average (8-gen LOGO)}} & \\textbf{0.762} & \\textbf{0.694} & [.688, .700] \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{8-generator LOGO macro-F1 for the 7-feature ensemble (bootstrap 95\\% CIs, $n$\\,=\\,1000). Binary F1 (gen-1 vs.\\ gen-2+) is the primary metric. Note: 3-class F1 may carry upward bias from gen-0 seed sharing across generators; binary F1 is leak-free. Cross-model chains (Table~\\ref{tab:cross-ref}) use sample-level CV without this issue.}\n\\label{tab:logo-results}\n\\end{table}\n\n\\subsection{Differential Depth Response}\n\\label{sec:results-differential}\n\nFeatures exhibit \\emph{differential depth response} (DDR): central-tendency and diversity measures drift monotonically with depth, while shape measures remain near-stationary, consistent with recursive generation inducing a location shift in the NLL distribution while approximately preserving its functional form (shape-feature CV shift $<$3\\% vs.\\ $>$15\\% for drifting features).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig1_differential_response.pdf}\n\\caption{Differential depth response: Spearman correlations between individual features and generation depth. Central-tendency and diversity features (hapax ratio, TTR, entropy mean) show substantial monotonic drift; entropy std ($|\\rho|{=}0.17$) occupies an intermediate position; shape features (entropy max, tail decay) remain near-stationary ($|\\rho| < 0.10$).}\n\\label{fig:feature-drift}\n\\end{figure}\n\nPooled class-balanced Spearman correlations with depth confirm the split (Figure~\\ref{fig:feature-drift}):\ndrifting features show substantial monotonic trends (hapax ratio $\\rho = -0.63$, TTR $\\rho = -0.61$, entropy mean $\\rho = -0.60$),\nwhile shape features remain near-stationary (tail decay $|\\rho| = 0.04$).\nThe six-fold magnitude gap between drifting ($|\\rho| > 0.60$) and shape features ($|\\rho| < 0.10$) serves as the operative criterion for the DDR split, with entropy std occupying an intermediate position ($|\\rho| = 0.17$); shifting these descriptive thresholds by $\\pm 0.10$ does not alter feature grouping.\n\n\\paragraph{Distributional shift quantification.}\nTwo-sample KS tests between gen-1 and gen-2+ distributions confirm the split: drifting-feature KS statistics (0.516--0.537) are ${\\sim}10\\times$ larger than shape-feature statistics (0.043--0.052; all $p \\approx 0$ after Bonferroni correction).\nLevene tests reject equal variance for all features ($p < 10^{-10}$), but effect sizes differ markedly: shape-feature CV shift $<$3\\% vs.\\ $>$15\\% for drifting features, supporting ``approximately preserves'' as a practical characterization rather than a strict invariance claim.\n\n\\paragraph{Feature complementarity.}\nUnder 10-fold stratified CV, the full 7-feature set (F1\\,=\\,0.773) outperforms surface-only (F1\\,=\\,0.688) and reference-only (F1\\,=\\,0.713; McNemar $p \\approx 0$; Table~\\ref{tab:ablation} in Appendix~\\ref{app:ablation-table}).\nReference-only yields higher binary F1 (0.833 vs.\\ 0.695) since surface features introduce noise at the gen-1/gen-2+ boundary, but surface features are essential for 3-class gen-0 discrimination (Full 0.773 vs.\\ Reference-only 0.713).\nPermutation importance: hapax ratio (0.35), entropy mean (0.23), TTR (0.18); leave-one-feature-out confirms 6 of 7 features contribute positively (Appendix~\\ref{app:lofo}).\n\n\\paragraph{Cross-family reference models.}\nAlternative references (OLMo-2-1B, Qwen3-0.6B) achieve comparable LOGO F1 (spread 0.013; Table~\\ref{tab:cross-ref} in Appendix~\\ref{app:cross-ref}), with consistently negative entropy drift, confirming DDR is a property of recursive generation.\n\n\\paragraph{Temperature sensitivity.}\nThe method operates reliably within $t \\in [0.5, 0.9]$: F1 varies by at most 1\\,pp from the default $t{=}0.7$ across this range (Appendix~\\ref{app:sampling-sensitivity}).\nAt $t{=}1.0$, performance degrades by ${\\sim}6$\\,pp as the primary depth signal collapses: entropy mean's Spearman correlation with depth drops from $\\rho = -0.60$ to $\\rho = -0.002$, indicating that high-temperature sampling injects sufficient token-level randomness to mask the systematic location shift that DDR exploits.\n\n\n\\subsection{Comparison with Detection Baselines}\n\\label{sec:results-baselines}\n\nWe repurpose four detection scores as ordinal depth predictors using the same XGBoost framework and LOGO splits (Table~\\ref{tab:baselines}, Figure~\\ref{fig:baseline-ci}).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig3_baseline_comparison.pdf}\n\\caption{LOGO binary F1 with 95\\% bootstrap CIs. Per-generator variance is higher for single detectors than for the ensemble.}\n\\label{fig:baseline-ci}\n\\end{figure}\n\n\\begin{table}[t]\n\\centering\n\\footnotesize\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Method} & \\textbf{Feat.} & \\textbf{3-cl F1} & \\textbf{Bin F1} & \\textbf{ms/text} \\\\\n\\midrule\n4-det.\\ + surface     & 6 & \\textbf{0.795} & \\textbf{0.708} & 22.8 \\\\\n4-detector ens.\\      & 4 & 0.785 & 0.700 & 22.8 \\\\\n7-feature (ours)      & 7 & 0.774 & 0.705 & \\textbf{9.7} \\\\\nAvg-LogProb           & 1 & 0.707 & 0.673 & --- \\\\\nFastDetectGPT         & 1 & 0.660 & 0.569 & --- \\\\\nLD-Score              & 1 & 0.630 & 0.675 & --- \\\\\nBinoculars            & 1 & 0.411 & 0.539 & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Depth classification (8-gen LOGO, pooled evaluation: predictions from all held-out folds are concatenated before computing F1, yielding slightly higher scores than the per-generator macro average in Table~\\ref{tab:logo-results}). All methods use identical XGBoost configuration ($n_\\text{estimators}{=}200$, $\\max_\\text{depth}{=}6$). Binary: gen-1 vs.\\ gen-2+. Inference cost: 7-feature requires one 410M reference model (905\\,MB); 4-det ensembles require two models totaling 1.4B parameters (2{,}868\\,MB).}\n\\label{tab:baselines}\n\\end{table}\n\nThe 7-feature ensemble exceeds all individual baselines in 3-class F1 ($\\Delta$\\,=\\,6.7--14.4\\,pp vs.\\ Avg-LogProb through LD-Score).\nMulti-detector ensembles achieve higher 3-class F1 (0.795 vs.\\ 0.774, +2.1\\,pp) and marginally higher binary F1 (0.708 vs.\\ 0.705, +0.3\\,pp), but require 2.4$\\times$ longer inference and 3.2$\\times$ more GPU memory.\n\n\nPreliminary downstream evaluation (fine-tuning OLMo-2-0425-1B on depth-stratified data; Appendix~\\ref{app:downstream}) finds that depth composition does not determine training utility at fixed sample count, though the evidence is limited (three seeds, single perplexity metric).\n",
    "structuredPatch": [
      {
        "oldStart": 12,
        "oldLines": 7,
        "newStart": 12,
        "newLines": 7,
        "lines": [
          " The Pythia-1B/2.8B crossover between three-class and binary scores (0.806 vs.\\ 0.798 and 0.718 vs.\\ 0.724, respectively) reflects differences in gen-0 classification accuracy rather than in depth discrimination per se.",
          " ",
          " \\paragraph{Cross-model generalization.}",
          "-Cross-model chains (randomly selected generator per step) yield 3-class F1\\,=\\,0.809 and binary F1\\,=\\,0.764 under 5-fold CV,\\footnote{Cross-model chains use the original five-generator subset (Pythia, OLMo, Qwen); Llama and Mistral were added later for single-generator evaluation.} confirming that depth signal persists when text passes through heterogeneous generators.",
          "+Cross-model chains (randomly selected generator per step) yield 3-class F1\\,=\\,0.809 and binary F1\\,=\\,0.764 under 5-fold CV,\\footnote{Cross-model chains use the original five-generator subset (Pythia, OLMo, Qwen); Llama and Mistral were added later for single-generator evaluation.} which confirms that depth signal persists when text passes through heterogeneous generators.",
          " The higher cross-model performance relative to single-generator LOGO (3-class: 0.809 vs.\\ 0.762) suggests that generator heterogeneity amplifies distributional shifts between depths, making each recursive step more distinct.",
          " Under class balancing, macro F1 reaches 0.831 (per-class breakdown in Appendix~\\ref{app:cross-model-detail}).",
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


### Tool call

_source line 96_

<details open><summary>🔧 Tool call — Edit · `toolu_0127fHyBzCpJrN7rnoSgmuux`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex",
  "old_string": "amplifies distributional shifts between depths, making each recursive step more distinct.",
  "new_string": "amplifies distributional shifts between depths and makes each recursive step more distinct."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "93b1e99b-1c28-425c-a659-e97f38e81feb",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Fdq885ZGJeioznoH8Xjqs3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14907,
      "cache_read_input_tokens": 68592,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14907
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

_source line 97 · 2026-05-17T19:57:24.092Z_

<details><summary>↩ Tool result · `toolu_0127fHyBzCpJrN7rnoSgmuux`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "3d763e3b-68f2-4463-a461-5cf9eb5d3e4c",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex",
    "oldString": "amplifies distributional shifts between depths, making each recursive step more distinct.",
    "newString": "amplifies distributional shifts between depths and makes each recursive step more distinct.",
    "originalFile": "\\section{Results}\n\\label{sec:results}\n\n\\subsection{Depth Classification Performance}\n\\label{sec:results-classification}\n\nThe 7-feature ensemble achieves 3-class LOGO F1\\,=\\,0.762 (95\\% CI [0.758, 0.766]; $N$\\,=\\,37{,}058) across eight generators from five families (Table~\\ref{tab:logo-results}).\nBecause gen-0 seeds are shared across generators (\\S\\ref{sec:generation}), gen-0 classification is near-perfect (per-class F1\\,$\\approx$\\,0.94) and the 3-class metric is inflated by this overlap.\nWe therefore adopt leak-free binary F1 (gen-1 vs.\\ gen-2+)\\,=\\,0.694, CI [0.688, 0.700], as the primary metric throughout; it excludes gen-0 entirely and is unaffected by seed sharing.\nPer-generator binary F1 ranges from 0.633 (Mistral-7B) to 0.724 (Pythia-2.8B); the primary difficulty is distinguishing gen-1 from gen-2+ (Appendix~\\ref{app:confusion}).\nLarger generators show moderate degradation (Qwen3-8B: 0.692, Mistral-7B: 0.633) relative to the 0.694 average.\nThe Pythia-1B/2.8B crossover between three-class and binary scores (0.806 vs.\\ 0.798 and 0.718 vs.\\ 0.724, respectively) reflects differences in gen-0 classification accuracy rather than in depth discrimination per se.\n\n\\paragraph{Cross-model generalization.}\nCross-model chains (randomly selected generator per step) yield 3-class F1\\,=\\,0.809 and binary F1\\,=\\,0.764 under 5-fold CV,\\footnote{Cross-model chains use the original five-generator subset (Pythia, OLMo, Qwen); Llama and Mistral were added later for single-generator evaluation.} which confirms that depth signal persists when text passes through heterogeneous generators.\nThe higher cross-model performance relative to single-generator LOGO (3-class: 0.809 vs.\\ 0.762) suggests that generator heterogeneity amplifies distributional shifts between depths, making each recursive step more distinct.\nUnder class balancing, macro F1 reaches 0.831 (per-class breakdown in Appendix~\\ref{app:cross-model-detail}).\n\nLeave-one-family-out (LOFO) evaluation yields average binary F1\\,=\\,0.686, confirming transfer across architectural families.\nA scale effect emerges: Pythia generators achieve the highest binary F1 (0.718--0.724), while larger models show degradation (Mistral-7B: 0.633), consistent with higher-capacity models compressing the feature margins DDR exploits.\nThe signal generalizes across text domains with variation (Appendix~\\ref{app:domain}).\n\n\\paragraph{Length confound control.}\nLength-matched subsampling yields binary F1\\,=\\,0.724 (vs.\\ 0.770 unmatched); a random-subsample control confirms the drop reflects deconfounding, not sample-size reduction (Appendix~\\ref{app:length}).\n\n\n\\begin{table}[t]\n\\centering\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llcccc}\n\\toprule\n\\textbf{Model} & \\textbf{Family} & \\textbf{Params} & \\textbf{3-cl F1} & \\textbf{Bin F1} & \\textbf{95\\% CI} \\\\\n\\midrule\nPythia-2.8B     & Pythia  & 2.8B & 0.798 & \\textbf{0.724} & [.707, .742] \\\\\nPythia-1B       & Pythia  & 1.0B & \\textbf{0.806} & 0.718 & [.700, .735] \\\\\nQwen3-1.7B     & Qwen    & 1.7B & 0.772 & 0.709 & [.693, .726] \\\\\nLlama-3.2-3B   & Llama   & 3.2B & 0.775 & 0.697 & [.680, .713] \\\\\nOLMo-2-1B      & OLMo    & 1.5B & 0.781 & 0.695 & [.679, .711] \\\\\nQwen3-8B       & Qwen    & 8.2B & 0.714 & 0.692 & [.674, .708] \\\\\nQwen3-0.6B     & Qwen    & 0.6B & 0.780 & 0.691 & [.673, .709] \\\\\nMistral-7B     & Mistral & 7.0B & 0.682 & 0.633 & [.617, .648] \\\\\n\\midrule\n\\multicolumn{3}{l}{\\textbf{Average (8-gen LOGO)}} & \\textbf{0.762} & \\textbf{0.694} & [.688, .700] \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{8-generator LOGO macro-F1 for the 7-feature ensemble (bootstrap 95\\% CIs, $n$\\,=\\,1000). Binary F1 (gen-1 vs.\\ gen-2+) is the primary metric. Note: 3-class F1 may carry upward bias from gen-0 seed sharing across generators; binary F1 is leak-free. Cross-model chains (Table~\\ref{tab:cross-ref}) use sample-level CV without this issue.}\n\\label{tab:logo-results}\n\\end{table}\n\n\\subsection{Differential Depth Response}\n\\label{sec:results-differential}\n\nFeatures exhibit \\emph{differential depth response} (DDR): central-tendency and diversity measures drift monotonically with depth, while shape measures remain near-stationary, consistent with recursive generation inducing a location shift in the NLL distribution while approximately preserving its functional form (shape-feature CV shift $<$3\\% vs.\\ $>$15\\% for drifting features).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig1_differential_response.pdf}\n\\caption{Differential depth response: Spearman correlations between individual features and generation depth. Central-tendency and diversity features (hapax ratio, TTR, entropy mean) show substantial monotonic drift; entropy std ($|\\rho|{=}0.17$) occupies an intermediate position; shape features (entropy max, tail decay) remain near-stationary ($|\\rho| < 0.10$).}\n\\label{fig:feature-drift}\n\\end{figure}\n\nPooled class-balanced Spearman correlations with depth confirm the split (Figure~\\ref{fig:feature-drift}):\ndrifting features show substantial monotonic trends (hapax ratio $\\rho = -0.63$, TTR $\\rho = -0.61$, entropy mean $\\rho = -0.60$),\nwhile shape features remain near-stationary (tail decay $|\\rho| = 0.04$).\nThe six-fold magnitude gap between drifting ($|\\rho| > 0.60$) and shape features ($|\\rho| < 0.10$) serves as the operative criterion for the DDR split, with entropy std occupying an intermediate position ($|\\rho| = 0.17$); shifting these descriptive thresholds by $\\pm 0.10$ does not alter feature grouping.\n\n\\paragraph{Distributional shift quantification.}\nTwo-sample KS tests between gen-1 and gen-2+ distributions confirm the split: drifting-feature KS statistics (0.516--0.537) are ${\\sim}10\\times$ larger than shape-feature statistics (0.043--0.052; all $p \\approx 0$ after Bonferroni correction).\nLevene tests reject equal variance for all features ($p < 10^{-10}$), but effect sizes differ markedly: shape-feature CV shift $<$3\\% vs.\\ $>$15\\% for drifting features, supporting ``approximately preserves'' as a practical characterization rather than a strict invariance claim.\n\n\\paragraph{Feature complementarity.}\nUnder 10-fold stratified CV, the full 7-feature set (F1\\,=\\,0.773) outperforms surface-only (F1\\,=\\,0.688) and reference-only (F1\\,=\\,0.713; McNemar $p \\approx 0$; Table~\\ref{tab:ablation} in Appendix~\\ref{app:ablation-table}).\nReference-only yields higher binary F1 (0.833 vs.\\ 0.695) since surface features introduce noise at the gen-1/gen-2+ boundary, but surface features are essential for 3-class gen-0 discrimination (Full 0.773 vs.\\ Reference-only 0.713).\nPermutation importance: hapax ratio (0.35), entropy mean (0.23), TTR (0.18); leave-one-feature-out confirms 6 of 7 features contribute positively (Appendix~\\ref{app:lofo}).\n\n\\paragraph{Cross-family reference models.}\nAlternative references (OLMo-2-1B, Qwen3-0.6B) achieve comparable LOGO F1 (spread 0.013; Table~\\ref{tab:cross-ref} in Appendix~\\ref{app:cross-ref}), with consistently negative entropy drift, confirming DDR is a property of recursive generation.\n\n\\paragraph{Temperature sensitivity.}\nThe method operates reliably within $t \\in [0.5, 0.9]$: F1 varies by at most 1\\,pp from the default $t{=}0.7$ across this range (Appendix~\\ref{app:sampling-sensitivity}).\nAt $t{=}1.0$, performance degrades by ${\\sim}6$\\,pp as the primary depth signal collapses: entropy mean's Spearman correlation with depth drops from $\\rho = -0.60$ to $\\rho = -0.002$, indicating that high-temperature sampling injects sufficient token-level randomness to mask the systematic location shift that DDR exploits.\n\n\n\\subsection{Comparison with Detection Baselines}\n\\label{sec:results-baselines}\n\nWe repurpose four detection scores as ordinal depth predictors using the same XGBoost framework and LOGO splits (Table~\\ref{tab:baselines}, Figure~\\ref{fig:baseline-ci}).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig3_baseline_comparison.pdf}\n\\caption{LOGO binary F1 with 95\\% bootstrap CIs. Per-generator variance is higher for single detectors than for the ensemble.}\n\\label{fig:baseline-ci}\n\\end{figure}\n\n\\begin{table}[t]\n\\centering\n\\footnotesize\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Method} & \\textbf{Feat.} & \\textbf{3-cl F1} & \\textbf{Bin F1} & \\textbf{ms/text} \\\\\n\\midrule\n4-det.\\ + surface     & 6 & \\textbf{0.795} & \\textbf{0.708} & 22.8 \\\\\n4-detector ens.\\      & 4 & 0.785 & 0.700 & 22.8 \\\\\n7-feature (ours)      & 7 & 0.774 & 0.705 & \\textbf{9.7} \\\\\nAvg-LogProb           & 1 & 0.707 & 0.673 & --- \\\\\nFastDetectGPT         & 1 & 0.660 & 0.569 & --- \\\\\nLD-Score              & 1 & 0.630 & 0.675 & --- \\\\\nBinoculars            & 1 & 0.411 & 0.539 & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Depth classification (8-gen LOGO, pooled evaluation: predictions from all held-out folds are concatenated before computing F1, yielding slightly higher scores than the per-generator macro average in Table~\\ref{tab:logo-results}). All methods use identical XGBoost configuration ($n_\\text{estimators}{=}200$, $\\max_\\text{depth}{=}6$). Binary: gen-1 vs.\\ gen-2+. Inference cost: 7-feature requires one 410M reference model (905\\,MB); 4-det ensembles require two models totaling 1.4B parameters (2{,}868\\,MB).}\n\\label{tab:baselines}\n\\end{table}\n\nThe 7-feature ensemble exceeds all individual baselines in 3-class F1 ($\\Delta$\\,=\\,6.7--14.4\\,pp vs.\\ Avg-LogProb through LD-Score).\nMulti-detector ensembles achieve higher 3-class F1 (0.795 vs.\\ 0.774, +2.1\\,pp) and marginally higher binary F1 (0.708 vs.\\ 0.705, +0.3\\,pp), but require 2.4$\\times$ longer inference and 3.2$\\times$ more GPU memory.\n\n\nPreliminary downstream evaluation (fine-tuning OLMo-2-0425-1B on depth-stratified data; Appendix~\\ref{app:downstream}) finds that depth composition does not determine training utility at fixed sample count, though the evidence is limited (three seeds, single perplexity metric).\n",
    "structuredPatch": [
      {
        "oldStart": 13,
        "oldLines": 7,
        "newStart": 13,
        "newLines": 7,
        "lines": [
          " ",
          " \\paragraph{Cross-model generalization.}",
          " Cross-model chains (randomly selected generator per step) yield 3-class F1\\,=\\,0.809 and binary F1\\,=\\,0.764 under 5-fold CV,\\footnote{Cross-model chains use the original five-generator subset (Pythia, OLMo, Qwen); Llama and Mistral were added later for single-generator evaluation.} which confirms that depth signal persists when text passes through heterogeneous generators.",
          "-The higher cross-model performance relative to single-generator LOGO (3-class: 0.809 vs.\\ 0.762) suggests that generator heterogeneity amplifies distributional shifts between depths, making each recursive step more distinct.",
          "+The higher cross-model performance relative to single-generator LOGO (3-class: 0.809 vs.\\ 0.762) suggests that generator heterogeneity amplifies distributional shifts between depths and makes each recursive step more distinct.",
          " Under class balancing, macro F1 reaches 0.831 (per-class breakdown in Appendix~\\ref{app:cross-model-detail}).",
          " ",
          " Leave-one-family-out (LOFO) evaluation yields average binary F1\\,=\\,0.686, confirming transfer across architectural families."
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

_source line 98_

<details open><summary>🔧 Tool call — Edit · `toolu_01U7mueN5enfvjhwjBxTaRMY`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex",
  "old_string": "yields average binary F1\\,=\\,0.686, confirming transfer across architectural families.",
  "new_string": "yields average binary F1\\,=\\,0.686, which confirms transfer across architectural families."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "5206a17b-b3cc-456f-80f3-2886b33a5640",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Fdq885ZGJeioznoH8Xjqs3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14907,
      "cache_read_input_tokens": 68592,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14907
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

_source line 99 · 2026-05-17T19:57:25.969Z_

<details><summary>↩ Tool result · `toolu_01U7mueN5enfvjhwjBxTaRMY`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "0f74631e-e8e9-49eb-988e-81afe5aefb38",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex",
    "oldString": "yields average binary F1\\,=\\,0.686, confirming transfer across architectural families.",
    "newString": "yields average binary F1\\,=\\,0.686, which confirms transfer across architectural families.",
    "originalFile": "\\section{Results}\n\\label{sec:results}\n\n\\subsection{Depth Classification Performance}\n\\label{sec:results-classification}\n\nThe 7-feature ensemble achieves 3-class LOGO F1\\,=\\,0.762 (95\\% CI [0.758, 0.766]; $N$\\,=\\,37{,}058) across eight generators from five families (Table~\\ref{tab:logo-results}).\nBecause gen-0 seeds are shared across generators (\\S\\ref{sec:generation}), gen-0 classification is near-perfect (per-class F1\\,$\\approx$\\,0.94) and the 3-class metric is inflated by this overlap.\nWe therefore adopt leak-free binary F1 (gen-1 vs.\\ gen-2+)\\,=\\,0.694, CI [0.688, 0.700], as the primary metric throughout; it excludes gen-0 entirely and is unaffected by seed sharing.\nPer-generator binary F1 ranges from 0.633 (Mistral-7B) to 0.724 (Pythia-2.8B); the primary difficulty is distinguishing gen-1 from gen-2+ (Appendix~\\ref{app:confusion}).\nLarger generators show moderate degradation (Qwen3-8B: 0.692, Mistral-7B: 0.633) relative to the 0.694 average.\nThe Pythia-1B/2.8B crossover between three-class and binary scores (0.806 vs.\\ 0.798 and 0.718 vs.\\ 0.724, respectively) reflects differences in gen-0 classification accuracy rather than in depth discrimination per se.\n\n\\paragraph{Cross-model generalization.}\nCross-model chains (randomly selected generator per step) yield 3-class F1\\,=\\,0.809 and binary F1\\,=\\,0.764 under 5-fold CV,\\footnote{Cross-model chains use the original five-generator subset (Pythia, OLMo, Qwen); Llama and Mistral were added later for single-generator evaluation.} which confirms that depth signal persists when text passes through heterogeneous generators.\nThe higher cross-model performance relative to single-generator LOGO (3-class: 0.809 vs.\\ 0.762) suggests that generator heterogeneity amplifies distributional shifts between depths and makes each recursive step more distinct.\nUnder class balancing, macro F1 reaches 0.831 (per-class breakdown in Appendix~\\ref{app:cross-model-detail}).\n\nLeave-one-family-out (LOFO) evaluation yields average binary F1\\,=\\,0.686, confirming transfer across architectural families.\nA scale effect emerges: Pythia generators achieve the highest binary F1 (0.718--0.724), while larger models show degradation (Mistral-7B: 0.633), consistent with higher-capacity models compressing the feature margins DDR exploits.\nThe signal generalizes across text domains with variation (Appendix~\\ref{app:domain}).\n\n\\paragraph{Length confound control.}\nLength-matched subsampling yields binary F1\\,=\\,0.724 (vs.\\ 0.770 unmatched); a random-subsample control confirms the drop reflects deconfounding, not sample-size reduction (Appendix~\\ref{app:length}).\n\n\n\\begin{table}[t]\n\\centering\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llcccc}\n\\toprule\n\\textbf{Model} & \\textbf{Family} & \\textbf{Params} & \\textbf{3-cl F1} & \\textbf{Bin F1} & \\textbf{95\\% CI} \\\\\n\\midrule\nPythia-2.8B     & Pythia  & 2.8B & 0.798 & \\textbf{0.724} & [.707, .742] \\\\\nPythia-1B       & Pythia  & 1.0B & \\textbf{0.806} & 0.718 & [.700, .735] \\\\\nQwen3-1.7B     & Qwen    & 1.7B & 0.772 & 0.709 & [.693, .726] \\\\\nLlama-3.2-3B   & Llama   & 3.2B & 0.775 & 0.697 & [.680, .713] \\\\\nOLMo-2-1B      & OLMo    & 1.5B & 0.781 & 0.695 & [.679, .711] \\\\\nQwen3-8B       & Qwen    & 8.2B & 0.714 & 0.692 & [.674, .708] \\\\\nQwen3-0.6B     & Qwen    & 0.6B & 0.780 & 0.691 & [.673, .709] \\\\\nMistral-7B     & Mistral & 7.0B & 0.682 & 0.633 & [.617, .648] \\\\\n\\midrule\n\\multicolumn{3}{l}{\\textbf{Average (8-gen LOGO)}} & \\textbf{0.762} & \\textbf{0.694} & [.688, .700] \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{8-generator LOGO macro-F1 for the 7-feature ensemble (bootstrap 95\\% CIs, $n$\\,=\\,1000). Binary F1 (gen-1 vs.\\ gen-2+) is the primary metric. Note: 3-class F1 may carry upward bias from gen-0 seed sharing across generators; binary F1 is leak-free. Cross-model chains (Table~\\ref{tab:cross-ref}) use sample-level CV without this issue.}\n\\label{tab:logo-results}\n\\end{table}\n\n\\subsection{Differential Depth Response}\n\\label{sec:results-differential}\n\nFeatures exhibit \\emph{differential depth response} (DDR): central-tendency and diversity measures drift monotonically with depth, while shape measures remain near-stationary, consistent with recursive generation inducing a location shift in the NLL distribution while approximately preserving its functional form (shape-feature CV shift $<$3\\% vs.\\ $>$15\\% for drifting features).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig1_differential_response.pdf}\n\\caption{Differential depth response: Spearman correlations between individual features and generation depth. Central-tendency and diversity features (hapax ratio, TTR, entropy mean) show substantial monotonic drift; entropy std ($|\\rho|{=}0.17$) occupies an intermediate position; shape features (entropy max, tail decay) remain near-stationary ($|\\rho| < 0.10$).}\n\\label{fig:feature-drift}\n\\end{figure}\n\nPooled class-balanced Spearman correlations with depth confirm the split (Figure~\\ref{fig:feature-drift}):\ndrifting features show substantial monotonic trends (hapax ratio $\\rho = -0.63$, TTR $\\rho = -0.61$, entropy mean $\\rho = -0.60$),\nwhile shape features remain near-stationary (tail decay $|\\rho| = 0.04$).\nThe six-fold magnitude gap between drifting ($|\\rho| > 0.60$) and shape features ($|\\rho| < 0.10$) serves as the operative criterion for the DDR split, with entropy std occupying an intermediate position ($|\\rho| = 0.17$); shifting these descriptive thresholds by $\\pm 0.10$ does not alter feature grouping.\n\n\\paragraph{Distributional shift quantification.}\nTwo-sample KS tests between gen-1 and gen-2+ distributions confirm the split: drifting-feature KS statistics (0.516--0.537) are ${\\sim}10\\times$ larger than shape-feature statistics (0.043--0.052; all $p \\approx 0$ after Bonferroni correction).\nLevene tests reject equal variance for all features ($p < 10^{-10}$), but effect sizes differ markedly: shape-feature CV shift $<$3\\% vs.\\ $>$15\\% for drifting features, supporting ``approximately preserves'' as a practical characterization rather than a strict invariance claim.\n\n\\paragraph{Feature complementarity.}\nUnder 10-fold stratified CV, the full 7-feature set (F1\\,=\\,0.773) outperforms surface-only (F1\\,=\\,0.688) and reference-only (F1\\,=\\,0.713; McNemar $p \\approx 0$; Table~\\ref{tab:ablation} in Appendix~\\ref{app:ablation-table}).\nReference-only yields higher binary F1 (0.833 vs.\\ 0.695) since surface features introduce noise at the gen-1/gen-2+ boundary, but surface features are essential for 3-class gen-0 discrimination (Full 0.773 vs.\\ Reference-only 0.713).\nPermutation importance: hapax ratio (0.35), entropy mean (0.23), TTR (0.18); leave-one-feature-out confirms 6 of 7 features contribute positively (Appendix~\\ref{app:lofo}).\n\n\\paragraph{Cross-family reference models.}\nAlternative references (OLMo-2-1B, Qwen3-0.6B) achieve comparable LOGO F1 (spread 0.013; Table~\\ref{tab:cross-ref} in Appendix~\\ref{app:cross-ref}), with consistently negative entropy drift, confirming DDR is a property of recursive generation.\n\n\\paragraph{Temperature sensitivity.}\nThe method operates reliably within $t \\in [0.5, 0.9]$: F1 varies by at most 1\\,pp from the default $t{=}0.7$ across this range (Appendix~\\ref{app:sampling-sensitivity}).\nAt $t{=}1.0$, performance degrades by ${\\sim}6$\\,pp as the primary depth signal collapses: entropy mean's Spearman correlation with depth drops from $\\rho = -0.60$ to $\\rho = -0.002$, indicating that high-temperature sampling injects sufficient token-level randomness to mask the systematic location shift that DDR exploits.\n\n\n\\subsection{Comparison with Detection Baselines}\n\\label{sec:results-baselines}\n\nWe repurpose four detection scores as ordinal depth predictors using the same XGBoost framework and LOGO splits (Table~\\ref{tab:baselines}, Figure~\\ref{fig:baseline-ci}).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig3_baseline_comparison.pdf}\n\\caption{LOGO binary F1 with 95\\% bootstrap CIs. Per-generator variance is higher for single detectors than for the ensemble.}\n\\label{fig:baseline-ci}\n\\end{figure}\n\n\\begin{table}[t]\n\\centering\n\\footnotesize\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Method} & \\textbf{Feat.} & \\textbf{3-cl F1} & \\textbf{Bin F1} & \\textbf{ms/text} \\\\\n\\midrule\n4-det.\\ + surface     & 6 & \\textbf{0.795} & \\textbf{0.708} & 22.8 \\\\\n4-detector ens.\\      & 4 & 0.785 & 0.700 & 22.8 \\\\\n7-feature (ours)      & 7 & 0.774 & 0.705 & \\textbf{9.7} \\\\\nAvg-LogProb           & 1 & 0.707 & 0.673 & --- \\\\\nFastDetectGPT         & 1 & 0.660 & 0.569 & --- \\\\\nLD-Score              & 1 & 0.630 & 0.675 & --- \\\\\nBinoculars            & 1 & 0.411 & 0.539 & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Depth classification (8-gen LOGO, pooled evaluation: predictions from all held-out folds are concatenated before computing F1, yielding slightly higher scores than the per-generator macro average in Table~\\ref{tab:logo-results}). All methods use identical XGBoost configuration ($n_\\text{estimators}{=}200$, $\\max_\\text{depth}{=}6$). Binary: gen-1 vs.\\ gen-2+. Inference cost: 7-feature requires one 410M reference model (905\\,MB); 4-det ensembles require two models totaling 1.4B parameters (2{,}868\\,MB).}\n\\label{tab:baselines}\n\\end{table}\n\nThe 7-feature ensemble exceeds all individual baselines in 3-class F1 ($\\Delta$\\,=\\,6.7--14.4\\,pp vs.\\ Avg-LogProb through LD-Score).\nMulti-detector ensembles achieve higher 3-class F1 (0.795 vs.\\ 0.774, +2.1\\,pp) and marginally higher binary F1 (0.708 vs.\\ 0.705, +0.3\\,pp), but require 2.4$\\times$ longer inference and 3.2$\\times$ more GPU memory.\n\n\nPreliminary downstream evaluation (fine-tuning OLMo-2-0425-1B on depth-stratified data; Appendix~\\ref{app:downstream}) finds that depth composition does not determine training utility at fixed sample count, though the evidence is limited (three seeds, single perplexity metric).\n",
    "structuredPatch": [
      {
        "oldStart": 16,
        "oldLines": 7,
        "newStart": 16,
        "newLines": 7,
        "lines": [
          " The higher cross-model performance relative to single-generator LOGO (3-class: 0.809 vs.\\ 0.762) suggests that generator heterogeneity amplifies distributional shifts between depths and makes each recursive step more distinct.",
          " Under class balancing, macro F1 reaches 0.831 (per-class breakdown in Appendix~\\ref{app:cross-model-detail}).",
          " ",
          "-Leave-one-family-out (LOFO) evaluation yields average binary F1\\,=\\,0.686, confirming transfer across architectural families.",
          "+Leave-one-family-out (LOFO) evaluation yields average binary F1\\,=\\,0.686, which confirms transfer across architectural families.",
          " A scale effect emerges: Pythia generators achieve the highest binary F1 (0.718--0.724), while larger models show degradation (Mistral-7B: 0.633), consistent with higher-capacity models compressing the feature margins DDR exploits.",
          " The signal generalizes across text domains with variation (Appendix~\\ref{app:domain}).",
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


### Tool call

_source line 100_

<details open><summary>🔧 Tool call — Edit · `toolu_01GcmtjyyJGu3Nhmp6qhvA6g`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex",
  "old_string": "for drifting features, supporting ``approximately preserves'' as a practical characterization rather than a strict invariance claim.",
  "new_string": "for drifting features, which supports ``approximately preserves'' as a practical characterization rather than a strict invariance claim."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "141eae5e-f8e0-47be-90ad-d57db38ab168",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Fdq885ZGJeioznoH8Xjqs3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14907,
      "cache_read_input_tokens": 68592,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14907
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

_source line 101 · 2026-05-17T19:57:27.855Z_

<details><summary>↩ Tool result · `toolu_01GcmtjyyJGu3Nhmp6qhvA6g`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "fe656cfa-0e43-447e-8ba6-59bc6b55b4ed",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex",
    "oldString": "for drifting features, supporting ``approximately preserves'' as a practical characterization rather than a strict invariance claim.",
    "newString": "for drifting features, which supports ``approximately preserves'' as a practical characterization rather than a strict invariance claim.",
    "originalFile": "\\section{Results}\n\\label{sec:results}\n\n\\subsection{Depth Classification Performance}\n\\label{sec:results-classification}\n\nThe 7-feature ensemble achieves 3-class LOGO F1\\,=\\,0.762 (95\\% CI [0.758, 0.766]; $N$\\,=\\,37{,}058) across eight generators from five families (Table~\\ref{tab:logo-results}).\nBecause gen-0 seeds are shared across generators (\\S\\ref{sec:generation}), gen-0 classification is near-perfect (per-class F1\\,$\\approx$\\,0.94) and the 3-class metric is inflated by this overlap.\nWe therefore adopt leak-free binary F1 (gen-1 vs.\\ gen-2+)\\,=\\,0.694, CI [0.688, 0.700], as the primary metric throughout; it excludes gen-0 entirely and is unaffected by seed sharing.\nPer-generator binary F1 ranges from 0.633 (Mistral-7B) to 0.724 (Pythia-2.8B); the primary difficulty is distinguishing gen-1 from gen-2+ (Appendix~\\ref{app:confusion}).\nLarger generators show moderate degradation (Qwen3-8B: 0.692, Mistral-7B: 0.633) relative to the 0.694 average.\nThe Pythia-1B/2.8B crossover between three-class and binary scores (0.806 vs.\\ 0.798 and 0.718 vs.\\ 0.724, respectively) reflects differences in gen-0 classification accuracy rather than in depth discrimination per se.\n\n\\paragraph{Cross-model generalization.}\nCross-model chains (randomly selected generator per step) yield 3-class F1\\,=\\,0.809 and binary F1\\,=\\,0.764 under 5-fold CV,\\footnote{Cross-model chains use the original five-generator subset (Pythia, OLMo, Qwen); Llama and Mistral were added later for single-generator evaluation.} which confirms that depth signal persists when text passes through heterogeneous generators.\nThe higher cross-model performance relative to single-generator LOGO (3-class: 0.809 vs.\\ 0.762) suggests that generator heterogeneity amplifies distributional shifts between depths and makes each recursive step more distinct.\nUnder class balancing, macro F1 reaches 0.831 (per-class breakdown in Appendix~\\ref{app:cross-model-detail}).\n\nLeave-one-family-out (LOFO) evaluation yields average binary F1\\,=\\,0.686, which confirms transfer across architectural families.\nA scale effect emerges: Pythia generators achieve the highest binary F1 (0.718--0.724), while larger models show degradation (Mistral-7B: 0.633), consistent with higher-capacity models compressing the feature margins DDR exploits.\nThe signal generalizes across text domains with variation (Appendix~\\ref{app:domain}).\n\n\\paragraph{Length confound control.}\nLength-matched subsampling yields binary F1\\,=\\,0.724 (vs.\\ 0.770 unmatched); a random-subsample control confirms the drop reflects deconfounding, not sample-size reduction (Appendix~\\ref{app:length}).\n\n\n\\begin{table}[t]\n\\centering\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llcccc}\n\\toprule\n\\textbf{Model} & \\textbf{Family} & \\textbf{Params} & \\textbf{3-cl F1} & \\textbf{Bin F1} & \\textbf{95\\% CI} \\\\\n\\midrule\nPythia-2.8B     & Pythia  & 2.8B & 0.798 & \\textbf{0.724} & [.707, .742] \\\\\nPythia-1B       & Pythia  & 1.0B & \\textbf{0.806} & 0.718 & [.700, .735] \\\\\nQwen3-1.7B     & Qwen    & 1.7B & 0.772 & 0.709 & [.693, .726] \\\\\nLlama-3.2-3B   & Llama   & 3.2B & 0.775 & 0.697 & [.680, .713] \\\\\nOLMo-2-1B      & OLMo    & 1.5B & 0.781 & 0.695 & [.679, .711] \\\\\nQwen3-8B       & Qwen    & 8.2B & 0.714 & 0.692 & [.674, .708] \\\\\nQwen3-0.6B     & Qwen    & 0.6B & 0.780 & 0.691 & [.673, .709] \\\\\nMistral-7B     & Mistral & 7.0B & 0.682 & 0.633 & [.617, .648] \\\\\n\\midrule\n\\multicolumn{3}{l}{\\textbf{Average (8-gen LOGO)}} & \\textbf{0.762} & \\textbf{0.694} & [.688, .700] \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{8-generator LOGO macro-F1 for the 7-feature ensemble (bootstrap 95\\% CIs, $n$\\,=\\,1000). Binary F1 (gen-1 vs.\\ gen-2+) is the primary metric. Note: 3-class F1 may carry upward bias from gen-0 seed sharing across generators; binary F1 is leak-free. Cross-model chains (Table~\\ref{tab:cross-ref}) use sample-level CV without this issue.}\n\\label{tab:logo-results}\n\\end{table}\n\n\\subsection{Differential Depth Response}\n\\label{sec:results-differential}\n\nFeatures exhibit \\emph{differential depth response} (DDR): central-tendency and diversity measures drift monotonically with depth, while shape measures remain near-stationary, consistent with recursive generation inducing a location shift in the NLL distribution while approximately preserving its functional form (shape-feature CV shift $<$3\\% vs.\\ $>$15\\% for drifting features).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig1_differential_response.pdf}\n\\caption{Differential depth response: Spearman correlations between individual features and generation depth. Central-tendency and diversity features (hapax ratio, TTR, entropy mean) show substantial monotonic drift; entropy std ($|\\rho|{=}0.17$) occupies an intermediate position; shape features (entropy max, tail decay) remain near-stationary ($|\\rho| < 0.10$).}\n\\label{fig:feature-drift}\n\\end{figure}\n\nPooled class-balanced Spearman correlations with depth confirm the split (Figure~\\ref{fig:feature-drift}):\ndrifting features show substantial monotonic trends (hapax ratio $\\rho = -0.63$, TTR $\\rho = -0.61$, entropy mean $\\rho = -0.60$),\nwhile shape features remain near-stationary (tail decay $|\\rho| = 0.04$).\nThe six-fold magnitude gap between drifting ($|\\rho| > 0.60$) and shape features ($|\\rho| < 0.10$) serves as the operative criterion for the DDR split, with entropy std occupying an intermediate position ($|\\rho| = 0.17$); shifting these descriptive thresholds by $\\pm 0.10$ does not alter feature grouping.\n\n\\paragraph{Distributional shift quantification.}\nTwo-sample KS tests between gen-1 and gen-2+ distributions confirm the split: drifting-feature KS statistics (0.516--0.537) are ${\\sim}10\\times$ larger than shape-feature statistics (0.043--0.052; all $p \\approx 0$ after Bonferroni correction).\nLevene tests reject equal variance for all features ($p < 10^{-10}$), but effect sizes differ markedly: shape-feature CV shift $<$3\\% vs.\\ $>$15\\% for drifting features, supporting ``approximately preserves'' as a practical characterization rather than a strict invariance claim.\n\n\\paragraph{Feature complementarity.}\nUnder 10-fold stratified CV, the full 7-feature set (F1\\,=\\,0.773) outperforms surface-only (F1\\,=\\,0.688) and reference-only (F1\\,=\\,0.713; McNemar $p \\approx 0$; Table~\\ref{tab:ablation} in Appendix~\\ref{app:ablation-table}).\nReference-only yields higher binary F1 (0.833 vs.\\ 0.695) since surface features introduce noise at the gen-1/gen-2+ boundary, but surface features are essential for 3-class gen-0 discrimination (Full 0.773 vs.\\ Reference-only 0.713).\nPermutation importance: hapax ratio (0.35), entropy mean (0.23), TTR (0.18); leave-one-feature-out confirms 6 of 7 features contribute positively (Appendix~\\ref{app:lofo}).\n\n\\paragraph{Cross-family reference models.}\nAlternative references (OLMo-2-1B, Qwen3-0.6B) achieve comparable LOGO F1 (spread 0.013; Table~\\ref{tab:cross-ref} in Appendix~\\ref{app:cross-ref}), with consistently negative entropy drift, confirming DDR is a property of recursive generation.\n\n\\paragraph{Temperature sensitivity.}\nThe method operates reliably within $t \\in [0.5, 0.9]$: F1 varies by at most 1\\,pp from the default $t{=}0.7$ across this range (Appendix~\\ref{app:sampling-sensitivity}).\nAt $t{=}1.0$, performance degrades by ${\\sim}6$\\,pp as the primary depth signal collapses: entropy mean's Spearman correlation with depth drops from $\\rho = -0.60$ to $\\rho = -0.002$, indicating that high-temperature sampling injects sufficient token-level randomness to mask the systematic location shift that DDR exploits.\n\n\n\\subsection{Comparison with Detection Baselines}\n\\label{sec:results-baselines}\n\nWe repurpose four detection scores as ordinal depth predictors using the same XGBoost framework and LOGO splits (Table~\\ref{tab:baselines}, Figure~\\ref{fig:baseline-ci}).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig3_baseline_comparison.pdf}\n\\caption{LOGO binary F1 with 95\\% bootstrap CIs. Per-generator variance is higher for single detectors than for the ensemble.}\n\\label{fig:baseline-ci}\n\\end{figure}\n\n\\begin{table}[t]\n\\centering\n\\footnotesize\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Method} & \\textbf{Feat.} & \\textbf{3-cl F1} & \\textbf{Bin F1} & \\textbf{ms/text} \\\\\n\\midrule\n4-det.\\ + surface     & 6 & \\textbf{0.795} & \\textbf{0.708} & 22.8 \\\\\n4-detector ens.\\      & 4 & 0.785 & 0.700 & 22.8 \\\\\n7-feature (ours)      & 7 & 0.774 & 0.705 & \\textbf{9.7} \\\\\nAvg-LogProb           & 1 & 0.707 & 0.673 & --- \\\\\nFastDetectGPT         & 1 & 0.660 & 0.569 & --- \\\\\nLD-Score              & 1 & 0.630 & 0.675 & --- \\\\\nBinoculars            & 1 & 0.411 & 0.539 & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Depth classification (8-gen LOGO, pooled evaluation: predictions from all held-out folds are concatenated before computing F1, yielding slightly higher scores than the per-generator macro average in Table~\\ref{tab:logo-results}). All methods use identical XGBoost configuration ($n_\\text{estimators}{=}200$, $\\max_\\text{depth}{=}6$). Binary: gen-1 vs.\\ gen-2+. Inference cost: 7-feature requires one 410M reference model (905\\,MB); 4-det ensembles require two models totaling 1.4B parameters (2{,}868\\,MB).}\n\\label{tab:baselines}\n\\end{table}\n\nThe 7-feature ensemble exceeds all individual baselines in 3-class F1 ($\\Delta$\\,=\\,6.7--14.4\\,pp vs.\\ Avg-LogProb through LD-Score).\nMulti-detector ensembles achieve higher 3-class F1 (0.795 vs.\\ 0.774, +2.1\\,pp) and marginally higher binary F1 (0.708 vs.\\ 0.705, +0.3\\,pp), but require 2.4$\\times$ longer inference and 3.2$\\times$ more GPU memory.\n\n\nPreliminary downstream evaluation (fine-tuning OLMo-2-0425-1B on depth-stratified data; Appendix~\\ref{app:downstream}) finds that depth composition does not determine training utility at fixed sample count, though the evidence is limited (three seeds, single perplexity metric).\n",
    "structuredPatch": [
      {
        "oldStart": 67,
        "oldLines": 7,
        "newStart": 67,
        "newLines": 7,
        "lines": [
          " ",
          " \\paragraph{Distributional shift quantification.}",
          " Two-sample KS tests between gen-1 and gen-2+ distributions confirm the split: drifting-feature KS statistics (0.516--0.537) are ${\\sim}10\\times$ larger than shape-feature statistics (0.043--0.052; all $p \\approx 0$ after Bonferroni correction).",
          "-Levene tests reject equal variance for all features ($p < 10^{-10}$), but effect sizes differ markedly: shape-feature CV shift $<$3\\% vs.\\ $>$15\\% for drifting features, supporting ``approximately preserves'' as a practical characterization rather than a strict invariance claim.",
          "+Levene tests reject equal variance for all features ($p < 10^{-10}$), but effect sizes differ markedly: shape-feature CV shift $<$3\\% vs.\\ $>$15\\% for drifting features, which supports ``approximately preserves'' as a practical characterization rather than a strict invariance claim.",
          " ",
          " \\paragraph{Feature complementarity.}",
          " Under 10-fold stratified CV, the full 7-feature set (F1\\,=\\,0.773) outperforms surface-only (F1\\,=\\,0.688) and reference-only (F1\\,=\\,0.713; McNemar $p \\approx 0$; Table~\\ref{tab:ablation} in Appendix~\\ref{app:ablation-table})."
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

_source line 102_

<details open><summary>🔧 Tool call — Edit · `toolu_01BVmKbvMi67XtAKAq1ccvX4`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex",
  "old_string": "with consistently negative entropy drift, confirming DDR is a property of recursive generation.",
  "new_string": "with consistently negative entropy drift; this confirms DDR is a property of recursive generation."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "6e838800-4d25-4d59-8aa1-13f56bc0f9a0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Fdq885ZGJeioznoH8Xjqs3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14907,
      "cache_read_input_tokens": 68592,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14907
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

_source line 103 · 2026-05-17T19:57:28.841Z_

<details><summary>↩ Tool result · `toolu_01BVmKbvMi67XtAKAq1ccvX4`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "329dea6e-9ea1-43ce-94e5-d8886696b666",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex",
    "oldString": "with consistently negative entropy drift, confirming DDR is a property of recursive generation.",
    "newString": "with consistently negative entropy drift; this confirms DDR is a property of recursive generation.",
    "originalFile": "\\section{Results}\n\\label{sec:results}\n\n\\subsection{Depth Classification Performance}\n\\label{sec:results-classification}\n\nThe 7-feature ensemble achieves 3-class LOGO F1\\,=\\,0.762 (95\\% CI [0.758, 0.766]; $N$\\,=\\,37{,}058) across eight generators from five families (Table~\\ref{tab:logo-results}).\nBecause gen-0 seeds are shared across generators (\\S\\ref{sec:generation}), gen-0 classification is near-perfect (per-class F1\\,$\\approx$\\,0.94) and the 3-class metric is inflated by this overlap.\nWe therefore adopt leak-free binary F1 (gen-1 vs.\\ gen-2+)\\,=\\,0.694, CI [0.688, 0.700], as the primary metric throughout; it excludes gen-0 entirely and is unaffected by seed sharing.\nPer-generator binary F1 ranges from 0.633 (Mistral-7B) to 0.724 (Pythia-2.8B); the primary difficulty is distinguishing gen-1 from gen-2+ (Appendix~\\ref{app:confusion}).\nLarger generators show moderate degradation (Qwen3-8B: 0.692, Mistral-7B: 0.633) relative to the 0.694 average.\nThe Pythia-1B/2.8B crossover between three-class and binary scores (0.806 vs.\\ 0.798 and 0.718 vs.\\ 0.724, respectively) reflects differences in gen-0 classification accuracy rather than in depth discrimination per se.\n\n\\paragraph{Cross-model generalization.}\nCross-model chains (randomly selected generator per step) yield 3-class F1\\,=\\,0.809 and binary F1\\,=\\,0.764 under 5-fold CV,\\footnote{Cross-model chains use the original five-generator subset (Pythia, OLMo, Qwen); Llama and Mistral were added later for single-generator evaluation.} which confirms that depth signal persists when text passes through heterogeneous generators.\nThe higher cross-model performance relative to single-generator LOGO (3-class: 0.809 vs.\\ 0.762) suggests that generator heterogeneity amplifies distributional shifts between depths and makes each recursive step more distinct.\nUnder class balancing, macro F1 reaches 0.831 (per-class breakdown in Appendix~\\ref{app:cross-model-detail}).\n\nLeave-one-family-out (LOFO) evaluation yields average binary F1\\,=\\,0.686, which confirms transfer across architectural families.\nA scale effect emerges: Pythia generators achieve the highest binary F1 (0.718--0.724), while larger models show degradation (Mistral-7B: 0.633), consistent with higher-capacity models compressing the feature margins DDR exploits.\nThe signal generalizes across text domains with variation (Appendix~\\ref{app:domain}).\n\n\\paragraph{Length confound control.}\nLength-matched subsampling yields binary F1\\,=\\,0.724 (vs.\\ 0.770 unmatched); a random-subsample control confirms the drop reflects deconfounding, not sample-size reduction (Appendix~\\ref{app:length}).\n\n\n\\begin{table}[t]\n\\centering\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llcccc}\n\\toprule\n\\textbf{Model} & \\textbf{Family} & \\textbf{Params} & \\textbf{3-cl F1} & \\textbf{Bin F1} & \\textbf{95\\% CI} \\\\\n\\midrule\nPythia-2.8B     & Pythia  & 2.8B & 0.798 & \\textbf{0.724} & [.707, .742] \\\\\nPythia-1B       & Pythia  & 1.0B & \\textbf{0.806} & 0.718 & [.700, .735] \\\\\nQwen3-1.7B     & Qwen    & 1.7B & 0.772 & 0.709 & [.693, .726] \\\\\nLlama-3.2-3B   & Llama   & 3.2B & 0.775 & 0.697 & [.680, .713] \\\\\nOLMo-2-1B      & OLMo    & 1.5B & 0.781 & 0.695 & [.679, .711] \\\\\nQwen3-8B       & Qwen    & 8.2B & 0.714 & 0.692 & [.674, .708] \\\\\nQwen3-0.6B     & Qwen    & 0.6B & 0.780 & 0.691 & [.673, .709] \\\\\nMistral-7B     & Mistral & 7.0B & 0.682 & 0.633 & [.617, .648] \\\\\n\\midrule\n\\multicolumn{3}{l}{\\textbf{Average (8-gen LOGO)}} & \\textbf{0.762} & \\textbf{0.694} & [.688, .700] \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{8-generator LOGO macro-F1 for the 7-feature ensemble (bootstrap 95\\% CIs, $n$\\,=\\,1000). Binary F1 (gen-1 vs.\\ gen-2+) is the primary metric. Note: 3-class F1 may carry upward bias from gen-0 seed sharing across generators; binary F1 is leak-free. Cross-model chains (Table~\\ref{tab:cross-ref}) use sample-level CV without this issue.}\n\\label{tab:logo-results}\n\\end{table}\n\n\\subsection{Differential Depth Response}\n\\label{sec:results-differential}\n\nFeatures exhibit \\emph{differential depth response} (DDR): central-tendency and diversity measures drift monotonically with depth, while shape measures remain near-stationary, consistent with recursive generation inducing a location shift in the NLL distribution while approximately preserving its functional form (shape-feature CV shift $<$3\\% vs.\\ $>$15\\% for drifting features).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig1_differential_response.pdf}\n\\caption{Differential depth response: Spearman correlations between individual features and generation depth. Central-tendency and diversity features (hapax ratio, TTR, entropy mean) show substantial monotonic drift; entropy std ($|\\rho|{=}0.17$) occupies an intermediate position; shape features (entropy max, tail decay) remain near-stationary ($|\\rho| < 0.10$).}\n\\label{fig:feature-drift}\n\\end{figure}\n\nPooled class-balanced Spearman correlations with depth confirm the split (Figure~\\ref{fig:feature-drift}):\ndrifting features show substantial monotonic trends (hapax ratio $\\rho = -0.63$, TTR $\\rho = -0.61$, entropy mean $\\rho = -0.60$),\nwhile shape features remain near-stationary (tail decay $|\\rho| = 0.04$).\nThe six-fold magnitude gap between drifting ($|\\rho| > 0.60$) and shape features ($|\\rho| < 0.10$) serves as the operative criterion for the DDR split, with entropy std occupying an intermediate position ($|\\rho| = 0.17$); shifting these descriptive thresholds by $\\pm 0.10$ does not alter feature grouping.\n\n\\paragraph{Distributional shift quantification.}\nTwo-sample KS tests between gen-1 and gen-2+ distributions confirm the split: drifting-feature KS statistics (0.516--0.537) are ${\\sim}10\\times$ larger than shape-feature statistics (0.043--0.052; all $p \\approx 0$ after Bonferroni correction).\nLevene tests reject equal variance for all features ($p < 10^{-10}$), but effect sizes differ markedly: shape-feature CV shift $<$3\\% vs.\\ $>$15\\% for drifting features, which supports ``approximately preserves'' as a practical characterization rather than a strict invariance claim.\n\n\\paragraph{Feature complementarity.}\nUnder 10-fold stratified CV, the full 7-feature set (F1\\,=\\,0.773) outperforms surface-only (F1\\,=\\,0.688) and reference-only (F1\\,=\\,0.713; McNemar $p \\approx 0$; Table~\\ref{tab:ablation} in Appendix~\\ref{app:ablation-table}).\nReference-only yields higher binary F1 (0.833 vs.\\ 0.695) since surface features introduce noise at the gen-1/gen-2+ boundary, but surface features are essential for 3-class gen-0 discrimination (Full 0.773 vs.\\ Reference-only 0.713).\nPermutation importance: hapax ratio (0.35), entropy mean (0.23), TTR (0.18); leave-one-feature-out confirms 6 of 7 features contribute positively (Appendix~\\ref{app:lofo}).\n\n\\paragraph{Cross-family reference models.}\nAlternative references (OLMo-2-1B, Qwen3-0.6B) achieve comparable LOGO F1 (spread 0.013; Table~\\ref{tab:cross-ref} in Appendix~\\ref{app:cross-ref}), with consistently negative entropy drift, confirming DDR is a property of recursive generation.\n\n\\paragraph{Temperature sensitivity.}\nThe method operates reliably within $t \\in [0.5, 0.9]$: F1 varies by at most 1\\,pp from the default $t{=}0.7$ across this range (Appendix~\\ref{app:sampling-sensitivity}).\nAt $t{=}1.0$, performance degrades by ${\\sim}6$\\,pp as the primary depth signal collapses: entropy mean's Spearman correlation with depth drops from $\\rho = -0.60$ to $\\rho = -0.002$, indicating that high-temperature sampling injects sufficient token-level randomness to mask the systematic location shift that DDR exploits.\n\n\n\\subsection{Comparison with Detection Baselines}\n\\label{sec:results-baselines}\n\nWe repurpose four detection scores as ordinal depth predictors using the same XGBoost framework and LOGO splits (Table~\\ref{tab:baselines}, Figure~\\ref{fig:baseline-ci}).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig3_baseline_comparison.pdf}\n\\caption{LOGO binary F1 with 95\\% bootstrap CIs. Per-generator variance is higher for single detectors than for the ensemble.}\n\\label{fig:baseline-ci}\n\\end{figure}\n\n\\begin{table}[t]\n\\centering\n\\footnotesize\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Method} & \\textbf{Feat.} & \\textbf{3-cl F1} & \\textbf{Bin F1} & \\textbf{ms/text} \\\\\n\\midrule\n4-det.\\ + surface     & 6 & \\textbf{0.795} & \\textbf{0.708} & 22.8 \\\\\n4-detector ens.\\      & 4 & 0.785 & 0.700 & 22.8 \\\\\n7-feature (ours)      & 7 & 0.774 & 0.705 & \\textbf{9.7} \\\\\nAvg-LogProb           & 1 & 0.707 & 0.673 & --- \\\\\nFastDetectGPT         & 1 & 0.660 & 0.569 & --- \\\\\nLD-Score              & 1 & 0.630 & 0.675 & --- \\\\\nBinoculars            & 1 & 0.411 & 0.539 & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Depth classification (8-gen LOGO, pooled evaluation: predictions from all held-out folds are concatenated before computing F1, yielding slightly higher scores than the per-generator macro average in Table~\\ref{tab:logo-results}). All methods use identical XGBoost configuration ($n_\\text{estimators}{=}200$, $\\max_\\text{depth}{=}6$). Binary: gen-1 vs.\\ gen-2+. Inference cost: 7-feature requires one 410M reference model (905\\,MB); 4-det ensembles require two models totaling 1.4B parameters (2{,}868\\,MB).}\n\\label{tab:baselines}\n\\end{table}\n\nThe 7-feature ensemble exceeds all individual baselines in 3-class F1 ($\\Delta$\\,=\\,6.7--14.4\\,pp vs.\\ Avg-LogProb through LD-Score).\nMulti-detector ensembles achieve higher 3-class F1 (0.795 vs.\\ 0.774, +2.1\\,pp) and marginally higher binary F1 (0.708 vs.\\ 0.705, +0.3\\,pp), but require 2.4$\\times$ longer inference and 3.2$\\times$ more GPU memory.\n\n\nPreliminary downstream evaluation (fine-tuning OLMo-2-0425-1B on depth-stratified data; Appendix~\\ref{app:downstream}) finds that depth composition does not determine training utility at fixed sample count, though the evidence is limited (three seeds, single perplexity metric).\n",
    "structuredPatch": [
      {
        "oldStart": 75,
        "oldLines": 7,
        "newStart": 75,
        "newLines": 7,
        "lines": [
          " Permutation importance: hapax ratio (0.35), entropy mean (0.23), TTR (0.18); leave-one-feature-out confirms 6 of 7 features contribute positively (Appendix~\\ref{app:lofo}).",
          " ",
          " \\paragraph{Cross-family reference models.}",
          "-Alternative references (OLMo-2-1B, Qwen3-0.6B) achieve comparable LOGO F1 (spread 0.013; Table~\\ref{tab:cross-ref} in Appendix~\\ref{app:cross-ref}), with consistently negative entropy drift, confirming DDR is a property of recursive generation.",
          "+Alternative references (OLMo-2-1B, Qwen3-0.6B) achieve comparable LOGO F1 (spread 0.013; Table~\\ref{tab:cross-ref} in Appendix~\\ref{app:cross-ref}), with consistently negative entropy drift; this confirms DDR is a property of recursive generation.",
          " ",
          " \\paragraph{Temperature sensitivity.}",
          " The method operates reliably within $t \\in [0.5, 0.9]$: F1 varies by at most 1\\,pp from the default $t{=}0.7$ across this range (Appendix~\\ref{app:sampling-sensitivity})."
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

_source line 104_

<details open><summary>🔧 Tool call — Edit · `toolu_011JXPy5MuKrdbxZ1WSCxb7r`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex",
  "old_string": "to $\\rho = -0.002$, indicating that high-temperature sampling injects sufficient token-level randomness to mask the systematic location shift that DDR exploits.",
  "new_string": "to $\\rho = -0.002$. This collapse indicates that high-temperature sampling injects sufficient token-level randomness to mask the systematic location shift that DDR exploits."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "5bfefdf2-f62b-4a07-90b4-d9981a2643a8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Fdq885ZGJeioznoH8Xjqs3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14907,
      "cache_read_input_tokens": 68592,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14907
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

_source line 105 · 2026-05-17T19:57:30.241Z_

<details><summary>↩ Tool result · `toolu_011JXPy5MuKrdbxZ1WSCxb7r`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "fa779456-2d72-42d4-872d-997c9938ddcc",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex",
    "oldString": "to $\\rho = -0.002$, indicating that high-temperature sampling injects sufficient token-level randomness to mask the systematic location shift that DDR exploits.",
    "newString": "to $\\rho = -0.002$. This collapse indicates that high-temperature sampling injects sufficient token-level randomness to mask the systematic location shift that DDR exploits.",
    "originalFile": "\\section{Results}\n\\label{sec:results}\n\n\\subsection{Depth Classification Performance}\n\\label{sec:results-classification}\n\nThe 7-feature ensemble achieves 3-class LOGO F1\\,=\\,0.762 (95\\% CI [0.758, 0.766]; $N$\\,=\\,37{,}058) across eight generators from five families (Table~\\ref{tab:logo-results}).\nBecause gen-0 seeds are shared across generators (\\S\\ref{sec:generation}), gen-0 classification is near-perfect (per-class F1\\,$\\approx$\\,0.94) and the 3-class metric is inflated by this overlap.\nWe therefore adopt leak-free binary F1 (gen-1 vs.\\ gen-2+)\\,=\\,0.694, CI [0.688, 0.700], as the primary metric throughout; it excludes gen-0 entirely and is unaffected by seed sharing.\nPer-generator binary F1 ranges from 0.633 (Mistral-7B) to 0.724 (Pythia-2.8B); the primary difficulty is distinguishing gen-1 from gen-2+ (Appendix~\\ref{app:confusion}).\nLarger generators show moderate degradation (Qwen3-8B: 0.692, Mistral-7B: 0.633) relative to the 0.694 average.\nThe Pythia-1B/2.8B crossover between three-class and binary scores (0.806 vs.\\ 0.798 and 0.718 vs.\\ 0.724, respectively) reflects differences in gen-0 classification accuracy rather than in depth discrimination per se.\n\n\\paragraph{Cross-model generalization.}\nCross-model chains (randomly selected generator per step) yield 3-class F1\\,=\\,0.809 and binary F1\\,=\\,0.764 under 5-fold CV,\\footnote{Cross-model chains use the original five-generator subset (Pythia, OLMo, Qwen); Llama and Mistral were added later for single-generator evaluation.} which confirms that depth signal persists when text passes through heterogeneous generators.\nThe higher cross-model performance relative to single-generator LOGO (3-class: 0.809 vs.\\ 0.762) suggests that generator heterogeneity amplifies distributional shifts between depths and makes each recursive step more distinct.\nUnder class balancing, macro F1 reaches 0.831 (per-class breakdown in Appendix~\\ref{app:cross-model-detail}).\n\nLeave-one-family-out (LOFO) evaluation yields average binary F1\\,=\\,0.686, which confirms transfer across architectural families.\nA scale effect emerges: Pythia generators achieve the highest binary F1 (0.718--0.724), while larger models show degradation (Mistral-7B: 0.633), consistent with higher-capacity models compressing the feature margins DDR exploits.\nThe signal generalizes across text domains with variation (Appendix~\\ref{app:domain}).\n\n\\paragraph{Length confound control.}\nLength-matched subsampling yields binary F1\\,=\\,0.724 (vs.\\ 0.770 unmatched); a random-subsample control confirms the drop reflects deconfounding, not sample-size reduction (Appendix~\\ref{app:length}).\n\n\n\\begin{table}[t]\n\\centering\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llcccc}\n\\toprule\n\\textbf{Model} & \\textbf{Family} & \\textbf{Params} & \\textbf{3-cl F1} & \\textbf{Bin F1} & \\textbf{95\\% CI} \\\\\n\\midrule\nPythia-2.8B     & Pythia  & 2.8B & 0.798 & \\textbf{0.724} & [.707, .742] \\\\\nPythia-1B       & Pythia  & 1.0B & \\textbf{0.806} & 0.718 & [.700, .735] \\\\\nQwen3-1.7B     & Qwen    & 1.7B & 0.772 & 0.709 & [.693, .726] \\\\\nLlama-3.2-3B   & Llama   & 3.2B & 0.775 & 0.697 & [.680, .713] \\\\\nOLMo-2-1B      & OLMo    & 1.5B & 0.781 & 0.695 & [.679, .711] \\\\\nQwen3-8B       & Qwen    & 8.2B & 0.714 & 0.692 & [.674, .708] \\\\\nQwen3-0.6B     & Qwen    & 0.6B & 0.780 & 0.691 & [.673, .709] \\\\\nMistral-7B     & Mistral & 7.0B & 0.682 & 0.633 & [.617, .648] \\\\\n\\midrule\n\\multicolumn{3}{l}{\\textbf{Average (8-gen LOGO)}} & \\textbf{0.762} & \\textbf{0.694} & [.688, .700] \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{8-generator LOGO macro-F1 for the 7-feature ensemble (bootstrap 95\\% CIs, $n$\\,=\\,1000). Binary F1 (gen-1 vs.\\ gen-2+) is the primary metric. Note: 3-class F1 may carry upward bias from gen-0 seed sharing across generators; binary F1 is leak-free. Cross-model chains (Table~\\ref{tab:cross-ref}) use sample-level CV without this issue.}\n\\label{tab:logo-results}\n\\end{table}\n\n\\subsection{Differential Depth Response}\n\\label{sec:results-differential}\n\nFeatures exhibit \\emph{differential depth response} (DDR): central-tendency and diversity measures drift monotonically with depth, while shape measures remain near-stationary, consistent with recursive generation inducing a location shift in the NLL distribution while approximately preserving its functional form (shape-feature CV shift $<$3\\% vs.\\ $>$15\\% for drifting features).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig1_differential_response.pdf}\n\\caption{Differential depth response: Spearman correlations between individual features and generation depth. Central-tendency and diversity features (hapax ratio, TTR, entropy mean) show substantial monotonic drift; entropy std ($|\\rho|{=}0.17$) occupies an intermediate position; shape features (entropy max, tail decay) remain near-stationary ($|\\rho| < 0.10$).}\n\\label{fig:feature-drift}\n\\end{figure}\n\nPooled class-balanced Spearman correlations with depth confirm the split (Figure~\\ref{fig:feature-drift}):\ndrifting features show substantial monotonic trends (hapax ratio $\\rho = -0.63$, TTR $\\rho = -0.61$, entropy mean $\\rho = -0.60$),\nwhile shape features remain near-stationary (tail decay $|\\rho| = 0.04$).\nThe six-fold magnitude gap between drifting ($|\\rho| > 0.60$) and shape features ($|\\rho| < 0.10$) serves as the operative criterion for the DDR split, with entropy std occupying an intermediate position ($|\\rho| = 0.17$); shifting these descriptive thresholds by $\\pm 0.10$ does not alter feature grouping.\n\n\\paragraph{Distributional shift quantification.}\nTwo-sample KS tests between gen-1 and gen-2+ distributions confirm the split: drifting-feature KS statistics (0.516--0.537) are ${\\sim}10\\times$ larger than shape-feature statistics (0.043--0.052; all $p \\approx 0$ after Bonferroni correction).\nLevene tests reject equal variance for all features ($p < 10^{-10}$), but effect sizes differ markedly: shape-feature CV shift $<$3\\% vs.\\ $>$15\\% for drifting features, which supports ``approximately preserves'' as a practical characterization rather than a strict invariance claim.\n\n\\paragraph{Feature complementarity.}\nUnder 10-fold stratified CV, the full 7-feature set (F1\\,=\\,0.773) outperforms surface-only (F1\\,=\\,0.688) and reference-only (F1\\,=\\,0.713; McNemar $p \\approx 0$; Table~\\ref{tab:ablation} in Appendix~\\ref{app:ablation-table}).\nReference-only yields higher binary F1 (0.833 vs.\\ 0.695) since surface features introduce noise at the gen-1/gen-2+ boundary, but surface features are essential for 3-class gen-0 discrimination (Full 0.773 vs.\\ Reference-only 0.713).\nPermutation importance: hapax ratio (0.35), entropy mean (0.23), TTR (0.18); leave-one-feature-out confirms 6 of 7 features contribute positively (Appendix~\\ref{app:lofo}).\n\n\\paragraph{Cross-family reference models.}\nAlternative references (OLMo-2-1B, Qwen3-0.6B) achieve comparable LOGO F1 (spread 0.013; Table~\\ref{tab:cross-ref} in Appendix~\\ref{app:cross-ref}), with consistently negative entropy drift; this confirms DDR is a property of recursive generation.\n\n\\paragraph{Temperature sensitivity.}\nThe method operates reliably within $t \\in [0.5, 0.9]$: F1 varies by at most 1\\,pp from the default $t{=}0.7$ across this range (Appendix~\\ref{app:sampling-sensitivity}).\nAt $t{=}1.0$, performance degrades by ${\\sim}6$\\,pp as the primary depth signal collapses: entropy mean's Spearman correlation with depth drops from $\\rho = -0.60$ to $\\rho = -0.002$, indicating that high-temperature sampling injects sufficient token-level randomness to mask the systematic location shift that DDR exploits.\n\n\n\\subsection{Comparison with Detection Baselines}\n\\label{sec:results-baselines}\n\nWe repurpose four detection scores as ordinal depth predictors using the same XGBoost framework and LOGO splits (Table~\\ref{tab:baselines}, Figure~\\ref{fig:baseline-ci}).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig3_baseline_comparison.pdf}\n\\caption{LOGO binary F1 with 95\\% bootstrap CIs. Per-generator variance is higher for single detectors than for the ensemble.}\n\\label{fig:baseline-ci}\n\\end{figure}\n\n\\begin{table}[t]\n\\centering\n\\footnotesize\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Method} & \\textbf{Feat.} & \\textbf{3-cl F1} & \\textbf{Bin F1} & \\textbf{ms/text} \\\\\n\\midrule\n4-det.\\ + surface     & 6 & \\textbf{0.795} & \\textbf{0.708} & 22.8 \\\\\n4-detector ens.\\      & 4 & 0.785 & 0.700 & 22.8 \\\\\n7-feature (ours)      & 7 & 0.774 & 0.705 & \\textbf{9.7} \\\\\nAvg-LogProb           & 1 & 0.707 & 0.673 & --- \\\\\nFastDetectGPT         & 1 & 0.660 & 0.569 & --- \\\\\nLD-Score              & 1 & 0.630 & 0.675 & --- \\\\\nBinoculars            & 1 & 0.411 & 0.539 & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Depth classification (8-gen LOGO, pooled evaluation: predictions from all held-out folds are concatenated before computing F1, yielding slightly higher scores than the per-generator macro average in Table~\\ref{tab:logo-results}). All methods use identical XGBoost configuration ($n_\\text{estimators}{=}200$, $\\max_\\text{depth}{=}6$). Binary: gen-1 vs.\\ gen-2+. Inference cost: 7-feature requires one 410M reference model (905\\,MB); 4-det ensembles require two models totaling 1.4B parameters (2{,}868\\,MB).}\n\\label{tab:baselines}\n\\end{table}\n\nThe 7-feature ensemble exceeds all individual baselines in 3-class F1 ($\\Delta$\\,=\\,6.7--14.4\\,pp vs.\\ Avg-LogProb through LD-Score).\nMulti-detector ensembles achieve higher 3-class F1 (0.795 vs.\\ 0.774, +2.1\\,pp) and marginally higher binary F1 (0.708 vs.\\ 0.705, +0.3\\,pp), but require 2.4$\\times$ longer inference and 3.2$\\times$ more GPU memory.\n\n\nPreliminary downstream evaluation (fine-tuning OLMo-2-0425-1B on depth-stratified data; Appendix~\\ref{app:downstream}) finds that depth composition does not determine training utility at fixed sample count, though the evidence is limited (three seeds, single perplexity metric).\n",
    "structuredPatch": [
      {
        "oldStart": 79,
        "oldLines": 7,
        "newStart": 79,
        "newLines": 7,
        "lines": [
          " ",
          " \\paragraph{Temperature sensitivity.}",
          " The method operates reliably within $t \\in [0.5, 0.9]$: F1 varies by at most 1\\,pp from the default $t{=}0.7$ across this range (Appendix~\\ref{app:sampling-sensitivity}).",
          "-At $t{=}1.0$, performance degrades by ${\\sim}6$\\,pp as the primary depth signal collapses: entropy mean's Spearman correlation with depth drops from $\\rho = -0.60$ to $\\rho = -0.002$, indicating that high-temperature sampling injects sufficient token-level randomness to mask the systematic location shift that DDR exploits.",
          "+At $t{=}1.0$, performance degrades by ${\\sim}6$\\,pp as the primary depth signal collapses: entropy mean's Spearman correlation with depth drops from $\\rho = -0.60$ to $\\rho = -0.002$. This collapse indicates that high-temperature sampling injects sufficient token-level randomness to mask the systematic location shift that DDR exploits.",
          " ",
          " ",
          " \\subsection{Comparison with Detection Baselines}"
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

_source line 106_

**Batch 3**: method.tex (13 edits).

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "b7e6fe64-5070-4d8b-a07a-57e5b333a42d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UYoxg57iCdSuHDVeL6JWmK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 74548,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 74548
      },
      "output_tokens": 7,
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

_source line 107_

<details open><summary>🔧 Tool call — Edit · `toolu_01Pwh4RBKTn4rWUEMxd1RncM`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex",
  "old_string": "with generation depth, revealing differential depth response:",
  "new_string": "with generation depth and reveal differential depth response:"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "597cfd2e-fa8a-493d-a5df-32d7e7cdf995",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UYoxg57iCdSuHDVeL6JWmK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 74548,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 74548
      },
      "output_tokens": 7,
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

_source line 108 · 2026-05-17T19:57:34.852Z_

<details><summary>↩ Tool result · `toolu_01Pwh4RBKTn4rWUEMxd1RncM`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "114810ce-fac6-4f83-8b6e-3aaca44e7969",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex",
    "oldString": "with generation depth, revealing differential depth response:",
    "newString": "with generation depth and reveal differential depth response:",
    "originalFile": "\\section{Method}\n\\label{sec:method}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{fig2_framework.pdf}\n\\caption{Depth fingerprinting framework. (a)~Recursive generation chains are constructed by iteratively feeding text through a generator $G$. (b)~Seven features are extracted per text: five NLL statistics from a Pythia-410M reference model and two surface diversity measures. Horizontal bars show Spearman $\\rho$ with generation depth, revealing differential depth response: drifting features ($|\\rho| > 0.6$) capture the monotonic location shift, while stationary features ($|\\rho| < 0.1$) provide a stable baseline. (c)~An XGBoost classifier trained under Leave-One-Generator-Out (LOGO) cross-validation predicts depth class (gen-0\\,/\\,gen-1\\,/\\,gen-2+).}\n\\label{fig:framework}\n\\end{figure*}\n\n\\subsection{Task Formulation}\n\\label{sec:task}\n\nGiven a text $x$, the goal is to predict its \\emph{generation depth} $d \\in \\{0, 1, 2{+}\\}$, where $d{=}0$ denotes human-written text, $d{=}1$ denotes first-generation LLM output conditioned on human text, and $d{=}2{+}$ denotes text produced by recursively conditioning an LLM on its own prior output at least twice.\nFormally, let $\\mathcal{C}_0$ be a reference corpus of human-written text.\nA generation chain of depth $k$ is defined recursively: $x^{(0)} \\sim \\mathcal{C}_0$, and $x^{(k)} = G(x^{(k-1)})$ for $k \\geq 1$, where $G$ denotes stochastic LLM generation conditioned on its input.\nWe frame depth estimation as an ordinal classification task over three classes rather than binary real-vs-synthetic detection, enabling finer-grained provenance characterization.\nDepths beyond 2 are merged into a single $2{+}$ class, consistent with monotonic feature convergence that compresses inter-class margins beyond depth 2 (\\S\\ref{sec:results-differential}).\n\n\\subsection{Generation Chain Construction}\n\\label{sec:generation}\n\nWe construct generation chains using eight generators spanning five model families: \\textbf{Pythia} (2.8B, 1B) \\cite{pythia}, \\textbf{OLMo} (OLMo-2-1B) \\cite{olmo}, \\textbf{Qwen} (Qwen3-1.7B, Qwen3-0.6B, Qwen3-8B-Base) \\cite{qwen3}, \\textbf{Llama} (Llama-3.2-3B) \\cite{llama3}, and \\textbf{Mistral} (Mistral-7B-v0.3) \\cite{mistral7b}.\nThis selection covers parameter scales from 0.6B to 8B and diverse pretraining corpora, enabling evaluation of cross-generator and cross-scale generalization.\n\nFor each generator, we sample approximately 1{,}000 seed passages from English Wikipedia as $\\mathcal{C}_0$.\nThe same pool of seed passages serves as gen-0 for all generators.\nWe use shared seeds across generators to ensure that cross-generator comparisons control for input content, isolating the effect of the generation model from source text variation.\nIn LOGO evaluation, gen-0 samples from the held-out generator's chains also appear (with the same text) in the training generators' chains, creating a potential train--test overlap for the gen-0 class.\nWe address this with a supplementary binary evaluation excluding gen-0 entirely (\\S\\ref{sec:results-baselines}).\nEach seed is iteratively fed through the generator to produce a chain of depth 4 (i.e., gen-0 through gen-4), using the prompt ``\\texttt{Continue the following text: \\{text\\}}''.\nAll generation uses temperature $\\tau{=}0.7$, nucleus sampling with $p{=}0.9$, and maximum length of 256 new tokens.\nThe theoretical yield is $8 \\times {\\sim}1{,}000 \\times 5 = 39{,}815$ texts; after removing 2{,}746 chain breaks (empty or degenerate outputs at intermediate depths that prevented deeper generation) and 11 passages too short for feature extraction, 37{,}058 texts remain (Appendix~\\ref{app:dataset-stats}).\nFor classification, depths 2--4 are collapsed into the $2{+}$ class.\n\n\\subsection{Feature Extraction}\n\\label{sec:features}\n\nThe seven features are motivated by two complementary views of distributional drift.\nReference-model features capture how the text's token-level surprise distribution shifts relative to a fixed model; surface features capture how lexical diversity contracts under recursive generation.\nTogether, they span both the generative mechanism (what the model produces) and the surface manifestation (how the vocabulary changes); Figure~\\ref{fig:framework} provides an overview.\nThis two-pronged design is validated through leave-one-feature-out analysis (Appendix~\\ref{app:lofo}) and cross-group ablation (\\S\\ref{sec:results-differential}), confirming that both feature groups contribute to depth discrimination.\n\nWe extract seven distributional features per text, organized into two groups based on what they measure rather than how they are computed.\n\n\\paragraph{Reference-model features.}\nA held-out reference model (Pythia-410M, chosen to be smaller than all generators) computes per-token negative log-likelihood (NLL) for each text.\nWe use ``entropy'' as shorthand for token-level NLL throughout, following convention in prior detection work; these are point-wise NLL values, not Shannon entropy of the full distribution.\nAlthough Pythia-410M shares the GPT-NeoX architecture with two of the eight generators, cross-family reference model experiments (\\S\\ref{sec:results-differential}) confirm that depth features are not reference-specific (LOGO F1 varies by $\\leq$0.013 across Pythia, OLMo, and Qwen references).\nFrom the resulting NLL sequence, we extract five statistics:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{entropy\\_mean}: mean token-level NLL, capturing the average predictability of the text under the reference model;\n    \\item \\textbf{entropy\\_std}: standard deviation of token-level NLL, measuring the spread of per-token surprise;\n    \\item \\textbf{entropy\\_max}: maximum token-level NLL, capturing the most surprising token;\n    \\item \\textbf{entropy\\_min}: minimum token-level NLL, capturing the most predictable token. As generation depth increases, the floor of token-level surprise drops, reflecting the model's increasing confidence on its own outputs.\n    Retained because removing it does not improve performance (LOFO $\\Delta$F1\\,=\\,+0.01\\,pp, within bootstrap noise) and it completes the four-number NLL summary (mean, std, max, min), ensuring the classifier has access to the full marginal distribution shape;\n    \\item \\textbf{tail\\_decay}: slope of the vocabulary-level averaged log-probability distribution in the mid-rank region (ranks 100--1000).\n    For each text, we compute the mean log-probability of each vocabulary token across all positions under the reference model, sort tokens in descending order of mean log-probability, and fit a linear regression to ranks 100--1000.\n    The slope captures how steeply the reference model's probability mass decays beyond high-probability tokens, characterizing the shape of the distribution tail.\n    We select ranks 100--1000 because high-frequency tokens (ranks $<$ 100) exhibit minimal discriminative variance across depths, while ranks beyond 1000 are sparsely populated and noisy.\n\\end{itemize}\n\n\\paragraph{Surface features.}\nTwo features capture lexical diversity without requiring a reference model:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{TTR}: type-token ratio (number of unique word types divided by total tokens);\n    \\item \\textbf{hapax\\_ratio}: proportion of words appearing exactly once (\\emph{hapax legomena}).\n\\end{itemize}\n\n\\paragraph{Feature complementarity.}\nThe grouping reflects an empirical pattern we term \\emph{differential depth response}: central-tendency and diversity features (entropy\\_mean, TTR, hapax\\_ratio) show substantial monotonic drift with generation depth ($|\\rho| = 0.60$--$0.63$); entropy\\_min and entropy\\_std show moderate drift ($|\\rho| = 0.17$--$0.41$); and shape features (entropy\\_max, tail\\_decay) remain near-stationary ($|\\rho| < 0.10$).\nThis differential behavior, consistent with recursive generation shifting the location of the NLL distribution while approximately preserving distributional shape, motivates combining both feature types.\nAs shown in \\S\\ref{sec:results}, the full 7-feature set significantly outperforms either group alone.\n\n\\subsection{Evaluation Protocol}\n\\label{sec:evaluation}\n\n\\paragraph{Cross-validation.}\nTo evaluate generalization to unseen generators, we use \\textbf{Leave-One-Generator-Out (LOGO)} cross-validation over all eight generators; \\textbf{Leave-One-Family-Out (LOFO)} holds out entire model families.\nCross-model chains use the original five-generator subset (Pythia-2.8B/1B, OLMo-2-1B, Qwen3-1.7B/0.6B); Llama and Mistral were added subsequently for single-generator LOGO only.\nSome appendix analyses predate this expansion and use six generators (the original five plus Qwen3-8B); each table notes its generator subset.\n\n\\paragraph{Classifier.}\nWe use XGBoost \\cite{xgboost} throughout ($n\\_\\text{estimators}{=}200$, $\\max\\_\\text{depth}{=}6$, learning rate $0.1$), with identical hyperparameters across all methods in Table~\\ref{tab:baselines}.\nLOGO F1 is stable across random seeds (std\\,$<$\\,0.001 over 5 seeds).\nAlternative classifiers and ordinal-specific methods (CORAL \\cite{coral_ordinal}, Frank-Hall \\cite{frank_hall_ordinal}) yield comparable performance (Appendix~\\ref{app:classifier}), confirming that discriminative power resides in the features.\n\n\\paragraph{Metrics and statistical testing.}\nThe primary metric is \\textbf{macro-averaged F1} over the three depth classes.\nWe report 95\\% confidence intervals via percentile bootstrap ($n{=}1{,}000$), McNemar tests for pairwise comparisons, and paired bootstrap for baseline comparisons.\nAll $p$-values are two-sided; Bonferroni correction is applied within each family of simultaneous tests: the 21 distributional comparisons (7 features $\\times$ 3 depth-group pairs, \\S\\ref{sec:results-differential}) and the 4 pairwise baseline comparisons (\\S\\ref{sec:results-baselines}).\nFeature--depth correlations (\\S\\ref{sec:results-differential}) use class-balanced subsamples to control for depth-class imbalance.\n\n\\paragraph{Baselines.}\nWe compare the 7-feature ensemble against four single-score detection methods repurposed as depth predictors: Avg-LogProb, FastDetectGPT \\cite{fast_detectgpt}, Binoculars \\cite{binoculars}, and LD-Score \\cite{ld_score}.\nEach baseline score is used as a univariate feature in the same XGBoost framework under LOGO cross-validation, ensuring a controlled comparison.\n\n\\paragraph{Length confound control.}\nSince TTR and hapax\\_ratio are mechanically length-dependent, we verify depth signal is not a length artifact via length-matched subsampling that equalizes length distributions across depth classes (\\S\\ref{sec:results-classification}; Appendix~\\ref{app:length}).\n",
    "structuredPatch": [
      {
        "oldStart": 4,
        "oldLines": 7,
        "newStart": 4,
        "newLines": 7,
        "lines": [
          " \\begin{figure*}[t]",
          " \\centering",
          " \\includegraphics[width=\\textwidth]{fig2_framework.pdf}",
          "-\\caption{Depth fingerprinting framework. (a)~Recursive generation chains are constructed by iteratively feeding text through a generator $G$. (b)~Seven features are extracted per text: five NLL statistics from a Pythia-410M reference model and two surface diversity measures. Horizontal bars show Spearman $\\rho$ with generation depth, revealing differential depth response: drifting features ($|\\rho| > 0.6$) capture the monotonic location shift, while stationary features ($|\\rho| < 0.1$) provide a stable baseline. (c)~An XGBoost classifier trained under Leave-One-Generator-Out (LOGO) cross-validation predicts depth class (gen-0\\,/\\,gen-1\\,/\\,gen-2+).}",
          "+\\caption{Depth fingerprinting framework. (a)~Recursive generation chains are constructed by iteratively feeding text through a generator $G$. (b)~Seven features are extracted per text: five NLL statistics from a Pythia-410M reference model and two surface diversity measures. Horizontal bars show Spearman $\\rho$ with generation depth and reveal differential depth response: drifting features ($|\\rho| > 0.6$) capture the monotonic location shift, while stationary features ($|\\rho| < 0.1$) provide a stable baseline. (c)~An XGBoost classifier trained under Leave-One-Generator-Out (LOGO) cross-validation predicts depth class (gen-0\\,/\\,gen-1\\,/\\,gen-2+).}",
          " \\label{fig:framework}",
          " \\end{figure*}",
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


### Tool call

_source line 109_

<details open><summary>🔧 Tool call — Edit · `toolu_01V2PmyZRkLdD618ut7RVMiF`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex",
  "old_string": ", enabling finer-grained provenance characterization.",
  "new_string": ", which enables finer-grained provenance characterization."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "98948f7e-b365-4104-881b-49e11d04e01d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UYoxg57iCdSuHDVeL6JWmK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 74548,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 74548
      },
      "output_tokens": 7,
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

_source line 110 · 2026-05-17T19:57:35.743Z_

<details><summary>↩ Tool result · `toolu_01V2PmyZRkLdD618ut7RVMiF`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "8b4638aa-3a4f-4b47-9408-756cb3df8c65",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex",
    "oldString": ", enabling finer-grained provenance characterization.",
    "newString": ", which enables finer-grained provenance characterization.",
    "originalFile": "\\section{Method}\n\\label{sec:method}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{fig2_framework.pdf}\n\\caption{Depth fingerprinting framework. (a)~Recursive generation chains are constructed by iteratively feeding text through a generator $G$. (b)~Seven features are extracted per text: five NLL statistics from a Pythia-410M reference model and two surface diversity measures. Horizontal bars show Spearman $\\rho$ with generation depth and reveal differential depth response: drifting features ($|\\rho| > 0.6$) capture the monotonic location shift, while stationary features ($|\\rho| < 0.1$) provide a stable baseline. (c)~An XGBoost classifier trained under Leave-One-Generator-Out (LOGO) cross-validation predicts depth class (gen-0\\,/\\,gen-1\\,/\\,gen-2+).}\n\\label{fig:framework}\n\\end{figure*}\n\n\\subsection{Task Formulation}\n\\label{sec:task}\n\nGiven a text $x$, the goal is to predict its \\emph{generation depth} $d \\in \\{0, 1, 2{+}\\}$, where $d{=}0$ denotes human-written text, $d{=}1$ denotes first-generation LLM output conditioned on human text, and $d{=}2{+}$ denotes text produced by recursively conditioning an LLM on its own prior output at least twice.\nFormally, let $\\mathcal{C}_0$ be a reference corpus of human-written text.\nA generation chain of depth $k$ is defined recursively: $x^{(0)} \\sim \\mathcal{C}_0$, and $x^{(k)} = G(x^{(k-1)})$ for $k \\geq 1$, where $G$ denotes stochastic LLM generation conditioned on its input.\nWe frame depth estimation as an ordinal classification task over three classes rather than binary real-vs-synthetic detection, enabling finer-grained provenance characterization.\nDepths beyond 2 are merged into a single $2{+}$ class, consistent with monotonic feature convergence that compresses inter-class margins beyond depth 2 (\\S\\ref{sec:results-differential}).\n\n\\subsection{Generation Chain Construction}\n\\label{sec:generation}\n\nWe construct generation chains using eight generators spanning five model families: \\textbf{Pythia} (2.8B, 1B) \\cite{pythia}, \\textbf{OLMo} (OLMo-2-1B) \\cite{olmo}, \\textbf{Qwen} (Qwen3-1.7B, Qwen3-0.6B, Qwen3-8B-Base) \\cite{qwen3}, \\textbf{Llama} (Llama-3.2-3B) \\cite{llama3}, and \\textbf{Mistral} (Mistral-7B-v0.3) \\cite{mistral7b}.\nThis selection covers parameter scales from 0.6B to 8B and diverse pretraining corpora, enabling evaluation of cross-generator and cross-scale generalization.\n\nFor each generator, we sample approximately 1{,}000 seed passages from English Wikipedia as $\\mathcal{C}_0$.\nThe same pool of seed passages serves as gen-0 for all generators.\nWe use shared seeds across generators to ensure that cross-generator comparisons control for input content, isolating the effect of the generation model from source text variation.\nIn LOGO evaluation, gen-0 samples from the held-out generator's chains also appear (with the same text) in the training generators' chains, creating a potential train--test overlap for the gen-0 class.\nWe address this with a supplementary binary evaluation excluding gen-0 entirely (\\S\\ref{sec:results-baselines}).\nEach seed is iteratively fed through the generator to produce a chain of depth 4 (i.e., gen-0 through gen-4), using the prompt ``\\texttt{Continue the following text: \\{text\\}}''.\nAll generation uses temperature $\\tau{=}0.7$, nucleus sampling with $p{=}0.9$, and maximum length of 256 new tokens.\nThe theoretical yield is $8 \\times {\\sim}1{,}000 \\times 5 = 39{,}815$ texts; after removing 2{,}746 chain breaks (empty or degenerate outputs at intermediate depths that prevented deeper generation) and 11 passages too short for feature extraction, 37{,}058 texts remain (Appendix~\\ref{app:dataset-stats}).\nFor classification, depths 2--4 are collapsed into the $2{+}$ class.\n\n\\subsection{Feature Extraction}\n\\label{sec:features}\n\nThe seven features are motivated by two complementary views of distributional drift.\nReference-model features capture how the text's token-level surprise distribution shifts relative to a fixed model; surface features capture how lexical diversity contracts under recursive generation.\nTogether, they span both the generative mechanism (what the model produces) and the surface manifestation (how the vocabulary changes); Figure~\\ref{fig:framework} provides an overview.\nThis two-pronged design is validated through leave-one-feature-out analysis (Appendix~\\ref{app:lofo}) and cross-group ablation (\\S\\ref{sec:results-differential}), confirming that both feature groups contribute to depth discrimination.\n\nWe extract seven distributional features per text, organized into two groups based on what they measure rather than how they are computed.\n\n\\paragraph{Reference-model features.}\nA held-out reference model (Pythia-410M, chosen to be smaller than all generators) computes per-token negative log-likelihood (NLL) for each text.\nWe use ``entropy'' as shorthand for token-level NLL throughout, following convention in prior detection work; these are point-wise NLL values, not Shannon entropy of the full distribution.\nAlthough Pythia-410M shares the GPT-NeoX architecture with two of the eight generators, cross-family reference model experiments (\\S\\ref{sec:results-differential}) confirm that depth features are not reference-specific (LOGO F1 varies by $\\leq$0.013 across Pythia, OLMo, and Qwen references).\nFrom the resulting NLL sequence, we extract five statistics:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{entropy\\_mean}: mean token-level NLL, capturing the average predictability of the text under the reference model;\n    \\item \\textbf{entropy\\_std}: standard deviation of token-level NLL, measuring the spread of per-token surprise;\n    \\item \\textbf{entropy\\_max}: maximum token-level NLL, capturing the most surprising token;\n    \\item \\textbf{entropy\\_min}: minimum token-level NLL, capturing the most predictable token. As generation depth increases, the floor of token-level surprise drops, reflecting the model's increasing confidence on its own outputs.\n    Retained because removing it does not improve performance (LOFO $\\Delta$F1\\,=\\,+0.01\\,pp, within bootstrap noise) and it completes the four-number NLL summary (mean, std, max, min), ensuring the classifier has access to the full marginal distribution shape;\n    \\item \\textbf{tail\\_decay}: slope of the vocabulary-level averaged log-probability distribution in the mid-rank region (ranks 100--1000).\n    For each text, we compute the mean log-probability of each vocabulary token across all positions under the reference model, sort tokens in descending order of mean log-probability, and fit a linear regression to ranks 100--1000.\n    The slope captures how steeply the reference model's probability mass decays beyond high-probability tokens, characterizing the shape of the distribution tail.\n    We select ranks 100--1000 because high-frequency tokens (ranks $<$ 100) exhibit minimal discriminative variance across depths, while ranks beyond 1000 are sparsely populated and noisy.\n\\end{itemize}\n\n\\paragraph{Surface features.}\nTwo features capture lexical diversity without requiring a reference model:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{TTR}: type-token ratio (number of unique word types divided by total tokens);\n    \\item \\textbf{hapax\\_ratio}: proportion of words appearing exactly once (\\emph{hapax legomena}).\n\\end{itemize}\n\n\\paragraph{Feature complementarity.}\nThe grouping reflects an empirical pattern we term \\emph{differential depth response}: central-tendency and diversity features (entropy\\_mean, TTR, hapax\\_ratio) show substantial monotonic drift with generation depth ($|\\rho| = 0.60$--$0.63$); entropy\\_min and entropy\\_std show moderate drift ($|\\rho| = 0.17$--$0.41$); and shape features (entropy\\_max, tail\\_decay) remain near-stationary ($|\\rho| < 0.10$).\nThis differential behavior, consistent with recursive generation shifting the location of the NLL distribution while approximately preserving distributional shape, motivates combining both feature types.\nAs shown in \\S\\ref{sec:results}, the full 7-feature set significantly outperforms either group alone.\n\n\\subsection{Evaluation Protocol}\n\\label{sec:evaluation}\n\n\\paragraph{Cross-validation.}\nTo evaluate generalization to unseen generators, we use \\textbf{Leave-One-Generator-Out (LOGO)} cross-validation over all eight generators; \\textbf{Leave-One-Family-Out (LOFO)} holds out entire model families.\nCross-model chains use the original five-generator subset (Pythia-2.8B/1B, OLMo-2-1B, Qwen3-1.7B/0.6B); Llama and Mistral were added subsequently for single-generator LOGO only.\nSome appendix analyses predate this expansion and use six generators (the original five plus Qwen3-8B); each table notes its generator subset.\n\n\\paragraph{Classifier.}\nWe use XGBoost \\cite{xgboost} throughout ($n\\_\\text{estimators}{=}200$, $\\max\\_\\text{depth}{=}6$, learning rate $0.1$), with identical hyperparameters across all methods in Table~\\ref{tab:baselines}.\nLOGO F1 is stable across random seeds (std\\,$<$\\,0.001 over 5 seeds).\nAlternative classifiers and ordinal-specific methods (CORAL \\cite{coral_ordinal}, Frank-Hall \\cite{frank_hall_ordinal}) yield comparable performance (Appendix~\\ref{app:classifier}), confirming that discriminative power resides in the features.\n\n\\paragraph{Metrics and statistical testing.}\nThe primary metric is \\textbf{macro-averaged F1} over the three depth classes.\nWe report 95\\% confidence intervals via percentile bootstrap ($n{=}1{,}000$), McNemar tests for pairwise comparisons, and paired bootstrap for baseline comparisons.\nAll $p$-values are two-sided; Bonferroni correction is applied within each family of simultaneous tests: the 21 distributional comparisons (7 features $\\times$ 3 depth-group pairs, \\S\\ref{sec:results-differential}) and the 4 pairwise baseline comparisons (\\S\\ref{sec:results-baselines}).\nFeature--depth correlations (\\S\\ref{sec:results-differential}) use class-balanced subsamples to control for depth-class imbalance.\n\n\\paragraph{Baselines.}\nWe compare the 7-feature ensemble against four single-score detection methods repurposed as depth predictors: Avg-LogProb, FastDetectGPT \\cite{fast_detectgpt}, Binoculars \\cite{binoculars}, and LD-Score \\cite{ld_score}.\nEach baseline score is used as a univariate feature in the same XGBoost framework under LOGO cross-validation, ensuring a controlled comparison.\n\n\\paragraph{Length confound control.}\nSince TTR and hapax\\_ratio are mechanically length-dependent, we verify depth signal is not a length artifact via length-matched subsampling that equalizes length distributions across depth classes (\\S\\ref{sec:results-classification}; Appendix~\\ref{app:length}).\n",
    "structuredPatch": [
      {
        "oldStart": 14,
        "oldLines": 7,
        "newStart": 14,
        "newLines": 7,
        "lines": [
          " Given a text $x$, the goal is to predict its \\emph{generation depth} $d \\in \\{0, 1, 2{+}\\}$, where $d{=}0$ denotes human-written text, $d{=}1$ denotes first-generation LLM output conditioned on human text, and $d{=}2{+}$ denotes text produced by recursively conditioning an LLM on its own prior output at least twice.",
          " Formally, let $\\mathcal{C}_0$ be a reference corpus of human-written text.",
          " A generation chain of depth $k$ is defined recursively: $x^{(0)} \\sim \\mathcal{C}_0$, and $x^{(k)} = G(x^{(k-1)})$ for $k \\geq 1$, where $G$ denotes stochastic LLM generation conditioned on its input.",
          "-We frame depth estimation as an ordinal classification task over three classes rather than binary real-vs-synthetic detection, enabling finer-grained provenance characterization.",
          "+We frame depth estimation as an ordinal classification task over three classes rather than binary real-vs-synthetic detection, which enables finer-grained provenance characterization.",
          " Depths beyond 2 are merged into a single $2{+}$ class, consistent with monotonic feature convergence that compresses inter-class margins beyond depth 2 (\\S\\ref{sec:results-differential}).",
          " ",
          " \\subsection{Generation Chain Construction}"
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

_source line 111_

<details open><summary>🔧 Tool call — Edit · `toolu_01XTkpHsokyLMupEMVuTEhU9`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex",
  "old_string": ", enabling evaluation of cross-generator and cross-scale generalization.",
  "new_string": ", which enables evaluation of cross-generator and cross-scale generalization."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "a0766756-2db2-4ca0-881b-279224ee6858",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UYoxg57iCdSuHDVeL6JWmK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 74548,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 74548
      },
      "output_tokens": 7,
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

_source line 112 · 2026-05-17T19:57:37.637Z_

<details><summary>↩ Tool result · `toolu_01XTkpHsokyLMupEMVuTEhU9`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "6adc4a7c-7f9a-44e9-9170-bbb476f08022",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex",
    "oldString": ", enabling evaluation of cross-generator and cross-scale generalization.",
    "newString": ", which enables evaluation of cross-generator and cross-scale generalization.",
    "originalFile": "\\section{Method}\n\\label{sec:method}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{fig2_framework.pdf}\n\\caption{Depth fingerprinting framework. (a)~Recursive generation chains are constructed by iteratively feeding text through a generator $G$. (b)~Seven features are extracted per text: five NLL statistics from a Pythia-410M reference model and two surface diversity measures. Horizontal bars show Spearman $\\rho$ with generation depth and reveal differential depth response: drifting features ($|\\rho| > 0.6$) capture the monotonic location shift, while stationary features ($|\\rho| < 0.1$) provide a stable baseline. (c)~An XGBoost classifier trained under Leave-One-Generator-Out (LOGO) cross-validation predicts depth class (gen-0\\,/\\,gen-1\\,/\\,gen-2+).}\n\\label{fig:framework}\n\\end{figure*}\n\n\\subsection{Task Formulation}\n\\label{sec:task}\n\nGiven a text $x$, the goal is to predict its \\emph{generation depth} $d \\in \\{0, 1, 2{+}\\}$, where $d{=}0$ denotes human-written text, $d{=}1$ denotes first-generation LLM output conditioned on human text, and $d{=}2{+}$ denotes text produced by recursively conditioning an LLM on its own prior output at least twice.\nFormally, let $\\mathcal{C}_0$ be a reference corpus of human-written text.\nA generation chain of depth $k$ is defined recursively: $x^{(0)} \\sim \\mathcal{C}_0$, and $x^{(k)} = G(x^{(k-1)})$ for $k \\geq 1$, where $G$ denotes stochastic LLM generation conditioned on its input.\nWe frame depth estimation as an ordinal classification task over three classes rather than binary real-vs-synthetic detection, which enables finer-grained provenance characterization.\nDepths beyond 2 are merged into a single $2{+}$ class, consistent with monotonic feature convergence that compresses inter-class margins beyond depth 2 (\\S\\ref{sec:results-differential}).\n\n\\subsection{Generation Chain Construction}\n\\label{sec:generation}\n\nWe construct generation chains using eight generators spanning five model families: \\textbf{Pythia} (2.8B, 1B) \\cite{pythia}, \\textbf{OLMo} (OLMo-2-1B) \\cite{olmo}, \\textbf{Qwen} (Qwen3-1.7B, Qwen3-0.6B, Qwen3-8B-Base) \\cite{qwen3}, \\textbf{Llama} (Llama-3.2-3B) \\cite{llama3}, and \\textbf{Mistral} (Mistral-7B-v0.3) \\cite{mistral7b}.\nThis selection covers parameter scales from 0.6B to 8B and diverse pretraining corpora, enabling evaluation of cross-generator and cross-scale generalization.\n\nFor each generator, we sample approximately 1{,}000 seed passages from English Wikipedia as $\\mathcal{C}_0$.\nThe same pool of seed passages serves as gen-0 for all generators.\nWe use shared seeds across generators to ensure that cross-generator comparisons control for input content, isolating the effect of the generation model from source text variation.\nIn LOGO evaluation, gen-0 samples from the held-out generator's chains also appear (with the same text) in the training generators' chains, creating a potential train--test overlap for the gen-0 class.\nWe address this with a supplementary binary evaluation excluding gen-0 entirely (\\S\\ref{sec:results-baselines}).\nEach seed is iteratively fed through the generator to produce a chain of depth 4 (i.e., gen-0 through gen-4), using the prompt ``\\texttt{Continue the following text: \\{text\\}}''.\nAll generation uses temperature $\\tau{=}0.7$, nucleus sampling with $p{=}0.9$, and maximum length of 256 new tokens.\nThe theoretical yield is $8 \\times {\\sim}1{,}000 \\times 5 = 39{,}815$ texts; after removing 2{,}746 chain breaks (empty or degenerate outputs at intermediate depths that prevented deeper generation) and 11 passages too short for feature extraction, 37{,}058 texts remain (Appendix~\\ref{app:dataset-stats}).\nFor classification, depths 2--4 are collapsed into the $2{+}$ class.\n\n\\subsection{Feature Extraction}\n\\label{sec:features}\n\nThe seven features are motivated by two complementary views of distributional drift.\nReference-model features capture how the text's token-level surprise distribution shifts relative to a fixed model; surface features capture how lexical diversity contracts under recursive generation.\nTogether, they span both the generative mechanism (what the model produces) and the surface manifestation (how the vocabulary changes); Figure~\\ref{fig:framework} provides an overview.\nThis two-pronged design is validated through leave-one-feature-out analysis (Appendix~\\ref{app:lofo}) and cross-group ablation (\\S\\ref{sec:results-differential}), confirming that both feature groups contribute to depth discrimination.\n\nWe extract seven distributional features per text, organized into two groups based on what they measure rather than how they are computed.\n\n\\paragraph{Reference-model features.}\nA held-out reference model (Pythia-410M, chosen to be smaller than all generators) computes per-token negative log-likelihood (NLL) for each text.\nWe use ``entropy'' as shorthand for token-level NLL throughout, following convention in prior detection work; these are point-wise NLL values, not Shannon entropy of the full distribution.\nAlthough Pythia-410M shares the GPT-NeoX architecture with two of the eight generators, cross-family reference model experiments (\\S\\ref{sec:results-differential}) confirm that depth features are not reference-specific (LOGO F1 varies by $\\leq$0.013 across Pythia, OLMo, and Qwen references).\nFrom the resulting NLL sequence, we extract five statistics:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{entropy\\_mean}: mean token-level NLL, capturing the average predictability of the text under the reference model;\n    \\item \\textbf{entropy\\_std}: standard deviation of token-level NLL, measuring the spread of per-token surprise;\n    \\item \\textbf{entropy\\_max}: maximum token-level NLL, capturing the most surprising token;\n    \\item \\textbf{entropy\\_min}: minimum token-level NLL, capturing the most predictable token. As generation depth increases, the floor of token-level surprise drops, reflecting the model's increasing confidence on its own outputs.\n    Retained because removing it does not improve performance (LOFO $\\Delta$F1\\,=\\,+0.01\\,pp, within bootstrap noise) and it completes the four-number NLL summary (mean, std, max, min), ensuring the classifier has access to the full marginal distribution shape;\n    \\item \\textbf{tail\\_decay}: slope of the vocabulary-level averaged log-probability distribution in the mid-rank region (ranks 100--1000).\n    For each text, we compute the mean log-probability of each vocabulary token across all positions under the reference model, sort tokens in descending order of mean log-probability, and fit a linear regression to ranks 100--1000.\n    The slope captures how steeply the reference model's probability mass decays beyond high-probability tokens, characterizing the shape of the distribution tail.\n    We select ranks 100--1000 because high-frequency tokens (ranks $<$ 100) exhibit minimal discriminative variance across depths, while ranks beyond 1000 are sparsely populated and noisy.\n\\end{itemize}\n\n\\paragraph{Surface features.}\nTwo features capture lexical diversity without requiring a reference model:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{TTR}: type-token ratio (number of unique word types divided by total tokens);\n    \\item \\textbf{hapax\\_ratio}: proportion of words appearing exactly once (\\emph{hapax legomena}).\n\\end{itemize}\n\n\\paragraph{Feature complementarity.}\nThe grouping reflects an empirical pattern we term \\emph{differential depth response}: central-tendency and diversity features (entropy\\_mean, TTR, hapax\\_ratio) show substantial monotonic drift with generation depth ($|\\rho| = 0.60$--$0.63$); entropy\\_min and entropy\\_std show moderate drift ($|\\rho| = 0.17$--$0.41$); and shape features (entropy\\_max, tail\\_decay) remain near-stationary ($|\\rho| < 0.10$).\nThis differential behavior, consistent with recursive generation shifting the location of the NLL distribution while approximately preserving distributional shape, motivates combining both feature types.\nAs shown in \\S\\ref{sec:results}, the full 7-feature set significantly outperforms either group alone.\n\n\\subsection{Evaluation Protocol}\n\\label{sec:evaluation}\n\n\\paragraph{Cross-validation.}\nTo evaluate generalization to unseen generators, we use \\textbf{Leave-One-Generator-Out (LOGO)} cross-validation over all eight generators; \\textbf{Leave-One-Family-Out (LOFO)} holds out entire model families.\nCross-model chains use the original five-generator subset (Pythia-2.8B/1B, OLMo-2-1B, Qwen3-1.7B/0.6B); Llama and Mistral were added subsequently for single-generator LOGO only.\nSome appendix analyses predate this expansion and use six generators (the original five plus Qwen3-8B); each table notes its generator subset.\n\n\\paragraph{Classifier.}\nWe use XGBoost \\cite{xgboost} throughout ($n\\_\\text{estimators}{=}200$, $\\max\\_\\text{depth}{=}6$, learning rate $0.1$), with identical hyperparameters across all methods in Table~\\ref{tab:baselines}.\nLOGO F1 is stable across random seeds (std\\,$<$\\,0.001 over 5 seeds).\nAlternative classifiers and ordinal-specific methods (CORAL \\cite{coral_ordinal}, Frank-Hall \\cite{frank_hall_ordinal}) yield comparable performance (Appendix~\\ref{app:classifier}), confirming that discriminative power resides in the features.\n\n\\paragraph{Metrics and statistical testing.}\nThe primary metric is \\textbf{macro-averaged F1} over the three depth classes.\nWe report 95\\% confidence intervals via percentile bootstrap ($n{=}1{,}000$), McNemar tests for pairwise comparisons, and paired bootstrap for baseline comparisons.\nAll $p$-values are two-sided; Bonferroni correction is applied within each family of simultaneous tests: the 21 distributional comparisons (7 features $\\times$ 3 depth-group pairs, \\S\\ref{sec:results-differential}) and the 4 pairwise baseline comparisons (\\S\\ref{sec:results-baselines}).\nFeature--depth correlations (\\S\\ref{sec:results-differential}) use class-balanced subsamples to control for depth-class imbalance.\n\n\\paragraph{Baselines.}\nWe compare the 7-feature ensemble against four single-score detection methods repurposed as depth predictors: Avg-LogProb, FastDetectGPT \\cite{fast_detectgpt}, Binoculars \\cite{binoculars}, and LD-Score \\cite{ld_score}.\nEach baseline score is used as a univariate feature in the same XGBoost framework under LOGO cross-validation, ensuring a controlled comparison.\n\n\\paragraph{Length confound control.}\nSince TTR and hapax\\_ratio are mechanically length-dependent, we verify depth signal is not a length artifact via length-matched subsampling that equalizes length distributions across depth classes (\\S\\ref{sec:results-classification}; Appendix~\\ref{app:length}).\n",
    "structuredPatch": [
      {
        "oldStart": 21,
        "oldLines": 7,
        "newStart": 21,
        "newLines": 7,
        "lines": [
          " \\label{sec:generation}",
          " ",
          " We construct generation chains using eight generators spanning five model families: \\textbf{Pythia} (2.8B, 1B) \\cite{pythia}, \\textbf{OLMo} (OLMo-2-1B) \\cite{olmo}, \\textbf{Qwen} (Qwen3-1.7B, Qwen3-0.6B, Qwen3-8B-Base) \\cite{qwen3}, \\textbf{Llama} (Llama-3.2-3B) \\cite{llama3}, and \\textbf{Mistral} (Mistral-7B-v0.3) \\cite{mistral7b}.",
          "-This selection covers parameter scales from 0.6B to 8B and diverse pretraining corpora, enabling evaluation of cross-generator and cross-scale generalization.",
          "+This selection covers parameter scales from 0.6B to 8B and diverse pretraining corpora, which enables evaluation of cross-generator and cross-scale generalization.",
          " ",
          " For each generator, we sample approximately 1{,}000 seed passages from English Wikipedia as $\\mathcal{C}_0$.",
          " The same pool of seed passages serves as gen-0 for all generators."
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

_source line 113_

<details open><summary>🔧 Tool call — Edit · `toolu_017rezMZXhLZMTdMQvaq7rR1`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex",
  "old_string": ", isolating the effect of the generation model from source text variation.",
  "new_string": ", which isolates the effect of the generation model from source text variation."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "d7278db6-91db-419d-b038-dde1a57548b3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UYoxg57iCdSuHDVeL6JWmK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 74548,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 74548
      },
      "output_tokens": 7,
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

_source line 114 · 2026-05-17T19:57:39.094Z_

<details><summary>↩ Tool result · `toolu_017rezMZXhLZMTdMQvaq7rR1`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "1b50ee8f-779e-4839-9713-9294392f9267",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex",
    "oldString": ", isolating the effect of the generation model from source text variation.",
    "newString": ", which isolates the effect of the generation model from source text variation.",
    "originalFile": "\\section{Method}\n\\label{sec:method}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{fig2_framework.pdf}\n\\caption{Depth fingerprinting framework. (a)~Recursive generation chains are constructed by iteratively feeding text through a generator $G$. (b)~Seven features are extracted per text: five NLL statistics from a Pythia-410M reference model and two surface diversity measures. Horizontal bars show Spearman $\\rho$ with generation depth and reveal differential depth response: drifting features ($|\\rho| > 0.6$) capture the monotonic location shift, while stationary features ($|\\rho| < 0.1$) provide a stable baseline. (c)~An XGBoost classifier trained under Leave-One-Generator-Out (LOGO) cross-validation predicts depth class (gen-0\\,/\\,gen-1\\,/\\,gen-2+).}\n\\label{fig:framework}\n\\end{figure*}\n\n\\subsection{Task Formulation}\n\\label{sec:task}\n\nGiven a text $x$, the goal is to predict its \\emph{generation depth} $d \\in \\{0, 1, 2{+}\\}$, where $d{=}0$ denotes human-written text, $d{=}1$ denotes first-generation LLM output conditioned on human text, and $d{=}2{+}$ denotes text produced by recursively conditioning an LLM on its own prior output at least twice.\nFormally, let $\\mathcal{C}_0$ be a reference corpus of human-written text.\nA generation chain of depth $k$ is defined recursively: $x^{(0)} \\sim \\mathcal{C}_0$, and $x^{(k)} = G(x^{(k-1)})$ for $k \\geq 1$, where $G$ denotes stochastic LLM generation conditioned on its input.\nWe frame depth estimation as an ordinal classification task over three classes rather than binary real-vs-synthetic detection, which enables finer-grained provenance characterization.\nDepths beyond 2 are merged into a single $2{+}$ class, consistent with monotonic feature convergence that compresses inter-class margins beyond depth 2 (\\S\\ref{sec:results-differential}).\n\n\\subsection{Generation Chain Construction}\n\\label{sec:generation}\n\nWe construct generation chains using eight generators spanning five model families: \\textbf{Pythia} (2.8B, 1B) \\cite{pythia}, \\textbf{OLMo} (OLMo-2-1B) \\cite{olmo}, \\textbf{Qwen} (Qwen3-1.7B, Qwen3-0.6B, Qwen3-8B-Base) \\cite{qwen3}, \\textbf{Llama} (Llama-3.2-3B) \\cite{llama3}, and \\textbf{Mistral} (Mistral-7B-v0.3) \\cite{mistral7b}.\nThis selection covers parameter scales from 0.6B to 8B and diverse pretraining corpora, which enables evaluation of cross-generator and cross-scale generalization.\n\nFor each generator, we sample approximately 1{,}000 seed passages from English Wikipedia as $\\mathcal{C}_0$.\nThe same pool of seed passages serves as gen-0 for all generators.\nWe use shared seeds across generators to ensure that cross-generator comparisons control for input content, isolating the effect of the generation model from source text variation.\nIn LOGO evaluation, gen-0 samples from the held-out generator's chains also appear (with the same text) in the training generators' chains, creating a potential train--test overlap for the gen-0 class.\nWe address this with a supplementary binary evaluation excluding gen-0 entirely (\\S\\ref{sec:results-baselines}).\nEach seed is iteratively fed through the generator to produce a chain of depth 4 (i.e., gen-0 through gen-4), using the prompt ``\\texttt{Continue the following text: \\{text\\}}''.\nAll generation uses temperature $\\tau{=}0.7$, nucleus sampling with $p{=}0.9$, and maximum length of 256 new tokens.\nThe theoretical yield is $8 \\times {\\sim}1{,}000 \\times 5 = 39{,}815$ texts; after removing 2{,}746 chain breaks (empty or degenerate outputs at intermediate depths that prevented deeper generation) and 11 passages too short for feature extraction, 37{,}058 texts remain (Appendix~\\ref{app:dataset-stats}).\nFor classification, depths 2--4 are collapsed into the $2{+}$ class.\n\n\\subsection{Feature Extraction}\n\\label{sec:features}\n\nThe seven features are motivated by two complementary views of distributional drift.\nReference-model features capture how the text's token-level surprise distribution shifts relative to a fixed model; surface features capture how lexical diversity contracts under recursive generation.\nTogether, they span both the generative mechanism (what the model produces) and the surface manifestation (how the vocabulary changes); Figure~\\ref{fig:framework} provides an overview.\nThis two-pronged design is validated through leave-one-feature-out analysis (Appendix~\\ref{app:lofo}) and cross-group ablation (\\S\\ref{sec:results-differential}), confirming that both feature groups contribute to depth discrimination.\n\nWe extract seven distributional features per text, organized into two groups based on what they measure rather than how they are computed.\n\n\\paragraph{Reference-model features.}\nA held-out reference model (Pythia-410M, chosen to be smaller than all generators) computes per-token negative log-likelihood (NLL) for each text.\nWe use ``entropy'' as shorthand for token-level NLL throughout, following convention in prior detection work; these are point-wise NLL values, not Shannon entropy of the full distribution.\nAlthough Pythia-410M shares the GPT-NeoX architecture with two of the eight generators, cross-family reference model experiments (\\S\\ref{sec:results-differential}) confirm that depth features are not reference-specific (LOGO F1 varies by $\\leq$0.013 across Pythia, OLMo, and Qwen references).\nFrom the resulting NLL sequence, we extract five statistics:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{entropy\\_mean}: mean token-level NLL, capturing the average predictability of the text under the reference model;\n    \\item \\textbf{entropy\\_std}: standard deviation of token-level NLL, measuring the spread of per-token surprise;\n    \\item \\textbf{entropy\\_max}: maximum token-level NLL, capturing the most surprising token;\n    \\item \\textbf{entropy\\_min}: minimum token-level NLL, capturing the most predictable token. As generation depth increases, the floor of token-level surprise drops, reflecting the model's increasing confidence on its own outputs.\n    Retained because removing it does not improve performance (LOFO $\\Delta$F1\\,=\\,+0.01\\,pp, within bootstrap noise) and it completes the four-number NLL summary (mean, std, max, min), ensuring the classifier has access to the full marginal distribution shape;\n    \\item \\textbf{tail\\_decay}: slope of the vocabulary-level averaged log-probability distribution in the mid-rank region (ranks 100--1000).\n    For each text, we compute the mean log-probability of each vocabulary token across all positions under the reference model, sort tokens in descending order of mean log-probability, and fit a linear regression to ranks 100--1000.\n    The slope captures how steeply the reference model's probability mass decays beyond high-probability tokens, characterizing the shape of the distribution tail.\n    We select ranks 100--1000 because high-frequency tokens (ranks $<$ 100) exhibit minimal discriminative variance across depths, while ranks beyond 1000 are sparsely populated and noisy.\n\\end{itemize}\n\n\\paragraph{Surface features.}\nTwo features capture lexical diversity without requiring a reference model:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{TTR}: type-token ratio (number of unique word types divided by total tokens);\n    \\item \\textbf{hapax\\_ratio}: proportion of words appearing exactly once (\\emph{hapax legomena}).\n\\end{itemize}\n\n\\paragraph{Feature complementarity.}\nThe grouping reflects an empirical pattern we term \\emph{differential depth response}: central-tendency and diversity features (entropy\\_mean, TTR, hapax\\_ratio) show substantial monotonic drift with generation depth ($|\\rho| = 0.60$--$0.63$); entropy\\_min and entropy\\_std show moderate drift ($|\\rho| = 0.17$--$0.41$); and shape features (entropy\\_max, tail\\_decay) remain near-stationary ($|\\rho| < 0.10$).\nThis differential behavior, consistent with recursive generation shifting the location of the NLL distribution while approximately preserving distributional shape, motivates combining both feature types.\nAs shown in \\S\\ref{sec:results}, the full 7-feature set significantly outperforms either group alone.\n\n\\subsection{Evaluation Protocol}\n\\label{sec:evaluation}\n\n\\paragraph{Cross-validation.}\nTo evaluate generalization to unseen generators, we use \\textbf{Leave-One-Generator-Out (LOGO)} cross-validation over all eight generators; \\textbf{Leave-One-Family-Out (LOFO)} holds out entire model families.\nCross-model chains use the original five-generator subset (Pythia-2.8B/1B, OLMo-2-1B, Qwen3-1.7B/0.6B); Llama and Mistral were added subsequently for single-generator LOGO only.\nSome appendix analyses predate this expansion and use six generators (the original five plus Qwen3-8B); each table notes its generator subset.\n\n\\paragraph{Classifier.}\nWe use XGBoost \\cite{xgboost} throughout ($n\\_\\text{estimators}{=}200$, $\\max\\_\\text{depth}{=}6$, learning rate $0.1$), with identical hyperparameters across all methods in Table~\\ref{tab:baselines}.\nLOGO F1 is stable across random seeds (std\\,$<$\\,0.001 over 5 seeds).\nAlternative classifiers and ordinal-specific methods (CORAL \\cite{coral_ordinal}, Frank-Hall \\cite{frank_hall_ordinal}) yield comparable performance (Appendix~\\ref{app:classifier}), confirming that discriminative power resides in the features.\n\n\\paragraph{Metrics and statistical testing.}\nThe primary metric is \\textbf{macro-averaged F1} over the three depth classes.\nWe report 95\\% confidence intervals via percentile bootstrap ($n{=}1{,}000$), McNemar tests for pairwise comparisons, and paired bootstrap for baseline comparisons.\nAll $p$-values are two-sided; Bonferroni correction is applied within each family of simultaneous tests: the 21 distributional comparisons (7 features $\\times$ 3 depth-group pairs, \\S\\ref{sec:results-differential}) and the 4 pairwise baseline comparisons (\\S\\ref{sec:results-baselines}).\nFeature--depth correlations (\\S\\ref{sec:results-differential}) use class-balanced subsamples to control for depth-class imbalance.\n\n\\paragraph{Baselines.}\nWe compare the 7-feature ensemble against four single-score detection methods repurposed as depth predictors: Avg-LogProb, FastDetectGPT \\cite{fast_detectgpt}, Binoculars \\cite{binoculars}, and LD-Score \\cite{ld_score}.\nEach baseline score is used as a univariate feature in the same XGBoost framework under LOGO cross-validation, ensuring a controlled comparison.\n\n\\paragraph{Length confound control.}\nSince TTR and hapax\\_ratio are mechanically length-dependent, we verify depth signal is not a length artifact via length-matched subsampling that equalizes length distributions across depth classes (\\S\\ref{sec:results-classification}; Appendix~\\ref{app:length}).\n",
    "structuredPatch": [
      {
        "oldStart": 25,
        "oldLines": 7,
        "newStart": 25,
        "newLines": 7,
        "lines": [
          " ",
          " For each generator, we sample approximately 1{,}000 seed passages from English Wikipedia as $\\mathcal{C}_0$.",
          " The same pool of seed passages serves as gen-0 for all generators.",
          "-We use shared seeds across generators to ensure that cross-generator comparisons control for input content, isolating the effect of the generation model from source text variation.",
          "+We use shared seeds across generators to ensure that cross-generator comparisons control for input content, which isolates the effect of the generation model from source text variation.",
          " In LOGO evaluation, gen-0 samples from the held-out generator's chains also appear (with the same text) in the training generators' chains, creating a potential train--test overlap for the gen-0 class.",
          " We address this with a supplementary binary evaluation excluding gen-0 entirely (\\S\\ref{sec:results-baselines}).",
          " Each seed is iteratively fed through the generator to produce a chain of depth 4 (i.e., gen-0 through gen-4), using the prompt ``\\texttt{Continue the following text: \\{text\\}}''."
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

_source line 115_

<details open><summary>🔧 Tool call — Edit · `toolu_01HFSUHQMyG1Wb7D1TKi6fej`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex",
  "old_string": "(\\S\\ref{sec:results-differential}), confirming that both feature groups contribute to depth discrimination.",
  "new_string": "(\\S\\ref{sec:results-differential}), which confirms that both feature groups contribute to depth discrimination."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "c0278289-bbd0-481f-90d3-75353e47ed15",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UYoxg57iCdSuHDVeL6JWmK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 74548,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 74548
      },
      "output_tokens": 7,
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

_source line 116 · 2026-05-17T19:57:40.971Z_

<details><summary>↩ Tool result · `toolu_01HFSUHQMyG1Wb7D1TKi6fej`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "45cf75ef-3c81-4cdb-9545-1d7a3ad50079",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex",
    "oldString": "(\\S\\ref{sec:results-differential}), confirming that both feature groups contribute to depth discrimination.",
    "newString": "(\\S\\ref{sec:results-differential}), which confirms that both feature groups contribute to depth discrimination.",
    "originalFile": "\\section{Method}\n\\label{sec:method}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{fig2_framework.pdf}\n\\caption{Depth fingerprinting framework. (a)~Recursive generation chains are constructed by iteratively feeding text through a generator $G$. (b)~Seven features are extracted per text: five NLL statistics from a Pythia-410M reference model and two surface diversity measures. Horizontal bars show Spearman $\\rho$ with generation depth and reveal differential depth response: drifting features ($|\\rho| > 0.6$) capture the monotonic location shift, while stationary features ($|\\rho| < 0.1$) provide a stable baseline. (c)~An XGBoost classifier trained under Leave-One-Generator-Out (LOGO) cross-validation predicts depth class (gen-0\\,/\\,gen-1\\,/\\,gen-2+).}\n\\label{fig:framework}\n\\end{figure*}\n\n\\subsection{Task Formulation}\n\\label{sec:task}\n\nGiven a text $x$, the goal is to predict its \\emph{generation depth} $d \\in \\{0, 1, 2{+}\\}$, where $d{=}0$ denotes human-written text, $d{=}1$ denotes first-generation LLM output conditioned on human text, and $d{=}2{+}$ denotes text produced by recursively conditioning an LLM on its own prior output at least twice.\nFormally, let $\\mathcal{C}_0$ be a reference corpus of human-written text.\nA generation chain of depth $k$ is defined recursively: $x^{(0)} \\sim \\mathcal{C}_0$, and $x^{(k)} = G(x^{(k-1)})$ for $k \\geq 1$, where $G$ denotes stochastic LLM generation conditioned on its input.\nWe frame depth estimation as an ordinal classification task over three classes rather than binary real-vs-synthetic detection, which enables finer-grained provenance characterization.\nDepths beyond 2 are merged into a single $2{+}$ class, consistent with monotonic feature convergence that compresses inter-class margins beyond depth 2 (\\S\\ref{sec:results-differential}).\n\n\\subsection{Generation Chain Construction}\n\\label{sec:generation}\n\nWe construct generation chains using eight generators spanning five model families: \\textbf{Pythia} (2.8B, 1B) \\cite{pythia}, \\textbf{OLMo} (OLMo-2-1B) \\cite{olmo}, \\textbf{Qwen} (Qwen3-1.7B, Qwen3-0.6B, Qwen3-8B-Base) \\cite{qwen3}, \\textbf{Llama} (Llama-3.2-3B) \\cite{llama3}, and \\textbf{Mistral} (Mistral-7B-v0.3) \\cite{mistral7b}.\nThis selection covers parameter scales from 0.6B to 8B and diverse pretraining corpora, which enables evaluation of cross-generator and cross-scale generalization.\n\nFor each generator, we sample approximately 1{,}000 seed passages from English Wikipedia as $\\mathcal{C}_0$.\nThe same pool of seed passages serves as gen-0 for all generators.\nWe use shared seeds across generators to ensure that cross-generator comparisons control for input content, which isolates the effect of the generation model from source text variation.\nIn LOGO evaluation, gen-0 samples from the held-out generator's chains also appear (with the same text) in the training generators' chains, creating a potential train--test overlap for the gen-0 class.\nWe address this with a supplementary binary evaluation excluding gen-0 entirely (\\S\\ref{sec:results-baselines}).\nEach seed is iteratively fed through the generator to produce a chain of depth 4 (i.e., gen-0 through gen-4), using the prompt ``\\texttt{Continue the following text: \\{text\\}}''.\nAll generation uses temperature $\\tau{=}0.7$, nucleus sampling with $p{=}0.9$, and maximum length of 256 new tokens.\nThe theoretical yield is $8 \\times {\\sim}1{,}000 \\times 5 = 39{,}815$ texts; after removing 2{,}746 chain breaks (empty or degenerate outputs at intermediate depths that prevented deeper generation) and 11 passages too short for feature extraction, 37{,}058 texts remain (Appendix~\\ref{app:dataset-stats}).\nFor classification, depths 2--4 are collapsed into the $2{+}$ class.\n\n\\subsection{Feature Extraction}\n\\label{sec:features}\n\nThe seven features are motivated by two complementary views of distributional drift.\nReference-model features capture how the text's token-level surprise distribution shifts relative to a fixed model; surface features capture how lexical diversity contracts under recursive generation.\nTogether, they span both the generative mechanism (what the model produces) and the surface manifestation (how the vocabulary changes); Figure~\\ref{fig:framework} provides an overview.\nThis two-pronged design is validated through leave-one-feature-out analysis (Appendix~\\ref{app:lofo}) and cross-group ablation (\\S\\ref{sec:results-differential}), confirming that both feature groups contribute to depth discrimination.\n\nWe extract seven distributional features per text, organized into two groups based on what they measure rather than how they are computed.\n\n\\paragraph{Reference-model features.}\nA held-out reference model (Pythia-410M, chosen to be smaller than all generators) computes per-token negative log-likelihood (NLL) for each text.\nWe use ``entropy'' as shorthand for token-level NLL throughout, following convention in prior detection work; these are point-wise NLL values, not Shannon entropy of the full distribution.\nAlthough Pythia-410M shares the GPT-NeoX architecture with two of the eight generators, cross-family reference model experiments (\\S\\ref{sec:results-differential}) confirm that depth features are not reference-specific (LOGO F1 varies by $\\leq$0.013 across Pythia, OLMo, and Qwen references).\nFrom the resulting NLL sequence, we extract five statistics:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{entropy\\_mean}: mean token-level NLL, capturing the average predictability of the text under the reference model;\n    \\item \\textbf{entropy\\_std}: standard deviation of token-level NLL, measuring the spread of per-token surprise;\n    \\item \\textbf{entropy\\_max}: maximum token-level NLL, capturing the most surprising token;\n    \\item \\textbf{entropy\\_min}: minimum token-level NLL, capturing the most predictable token. As generation depth increases, the floor of token-level surprise drops, reflecting the model's increasing confidence on its own outputs.\n    Retained because removing it does not improve performance (LOFO $\\Delta$F1\\,=\\,+0.01\\,pp, within bootstrap noise) and it completes the four-number NLL summary (mean, std, max, min), ensuring the classifier has access to the full marginal distribution shape;\n    \\item \\textbf{tail\\_decay}: slope of the vocabulary-level averaged log-probability distribution in the mid-rank region (ranks 100--1000).\n    For each text, we compute the mean log-probability of each vocabulary token across all positions under the reference model, sort tokens in descending order of mean log-probability, and fit a linear regression to ranks 100--1000.\n    The slope captures how steeply the reference model's probability mass decays beyond high-probability tokens, characterizing the shape of the distribution tail.\n    We select ranks 100--1000 because high-frequency tokens (ranks $<$ 100) exhibit minimal discriminative variance across depths, while ranks beyond 1000 are sparsely populated and noisy.\n\\end{itemize}\n\n\\paragraph{Surface features.}\nTwo features capture lexical diversity without requiring a reference model:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{TTR}: type-token ratio (number of unique word types divided by total tokens);\n    \\item \\textbf{hapax\\_ratio}: proportion of words appearing exactly once (\\emph{hapax legomena}).\n\\end{itemize}\n\n\\paragraph{Feature complementarity.}\nThe grouping reflects an empirical pattern we term \\emph{differential depth response}: central-tendency and diversity features (entropy\\_mean, TTR, hapax\\_ratio) show substantial monotonic drift with generation depth ($|\\rho| = 0.60$--$0.63$); entropy\\_min and entropy\\_std show moderate drift ($|\\rho| = 0.17$--$0.41$); and shape features (entropy\\_max, tail\\_decay) remain near-stationary ($|\\rho| < 0.10$).\nThis differential behavior, consistent with recursive generation shifting the location of the NLL distribution while approximately preserving distributional shape, motivates combining both feature types.\nAs shown in \\S\\ref{sec:results}, the full 7-feature set significantly outperforms either group alone.\n\n\\subsection{Evaluation Protocol}\n\\label{sec:evaluation}\n\n\\paragraph{Cross-validation.}\nTo evaluate generalization to unseen generators, we use \\textbf{Leave-One-Generator-Out (LOGO)} cross-validation over all eight generators; \\textbf{Leave-One-Family-Out (LOFO)} holds out entire model families.\nCross-model chains use the original five-generator subset (Pythia-2.8B/1B, OLMo-2-1B, Qwen3-1.7B/0.6B); Llama and Mistral were added subsequently for single-generator LOGO only.\nSome appendix analyses predate this expansion and use six generators (the original five plus Qwen3-8B); each table notes its generator subset.\n\n\\paragraph{Classifier.}\nWe use XGBoost \\cite{xgboost} throughout ($n\\_\\text{estimators}{=}200$, $\\max\\_\\text{depth}{=}6$, learning rate $0.1$), with identical hyperparameters across all methods in Table~\\ref{tab:baselines}.\nLOGO F1 is stable across random seeds (std\\,$<$\\,0.001 over 5 seeds).\nAlternative classifiers and ordinal-specific methods (CORAL \\cite{coral_ordinal}, Frank-Hall \\cite{frank_hall_ordinal}) yield comparable performance (Appendix~\\ref{app:classifier}), confirming that discriminative power resides in the features.\n\n\\paragraph{Metrics and statistical testing.}\nThe primary metric is \\textbf{macro-averaged F1} over the three depth classes.\nWe report 95\\% confidence intervals via percentile bootstrap ($n{=}1{,}000$), McNemar tests for pairwise comparisons, and paired bootstrap for baseline comparisons.\nAll $p$-values are two-sided; Bonferroni correction is applied within each family of simultaneous tests: the 21 distributional comparisons (7 features $\\times$ 3 depth-group pairs, \\S\\ref{sec:results-differential}) and the 4 pairwise baseline comparisons (\\S\\ref{sec:results-baselines}).\nFeature--depth correlations (\\S\\ref{sec:results-differential}) use class-balanced subsamples to control for depth-class imbalance.\n\n\\paragraph{Baselines.}\nWe compare the 7-feature ensemble against four single-score detection methods repurposed as depth predictors: Avg-LogProb, FastDetectGPT \\cite{fast_detectgpt}, Binoculars \\cite{binoculars}, and LD-Score \\cite{ld_score}.\nEach baseline score is used as a univariate feature in the same XGBoost framework under LOGO cross-validation, ensuring a controlled comparison.\n\n\\paragraph{Length confound control.}\nSince TTR and hapax\\_ratio are mechanically length-dependent, we verify depth signal is not a length artifact via length-matched subsampling that equalizes length distributions across depth classes (\\S\\ref{sec:results-classification}; Appendix~\\ref{app:length}).\n",
    "structuredPatch": [
      {
        "oldStart": 39,
        "oldLines": 7,
        "newStart": 39,
        "newLines": 7,
        "lines": [
          " The seven features are motivated by two complementary views of distributional drift.",
          " Reference-model features capture how the text's token-level surprise distribution shifts relative to a fixed model; surface features capture how lexical diversity contracts under recursive generation.",
          " Together, they span both the generative mechanism (what the model produces) and the surface manifestation (how the vocabulary changes); Figure~\\ref{fig:framework} provides an overview.",
          "-This two-pronged design is validated through leave-one-feature-out analysis (Appendix~\\ref{app:lofo}) and cross-group ablation (\\S\\ref{sec:results-differential}), confirming that both feature groups contribute to depth discrimination.",
          "+This two-pronged design is validated through leave-one-feature-out analysis (Appendix~\\ref{app:lofo}) and cross-group ablation (\\S\\ref{sec:results-differential}), which confirms that both feature groups contribute to depth discrimination.",
          " ",
          " We extract seven distributional features per text, organized into two groups based on what they measure rather than how they are computed.",
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


### Tool call

_source line 117_

<details open><summary>🔧 Tool call — Edit · `toolu_01U8eqZyJNybgptK3KQfW1dU`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex",
  "old_string": "mean token-level NLL, capturing the average predictability of the text under the reference model;",
  "new_string": "mean token-level NLL, which captures the average predictability of the text under the reference model;"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "aab02869-c7a7-4251-8369-29cf20ba71b5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UYoxg57iCdSuHDVeL6JWmK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 74548,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 74548
      },
      "output_tokens": 7,
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

_source line 118 · 2026-05-17T19:57:42.341Z_

<details><summary>↩ Tool result · `toolu_01U8eqZyJNybgptK3KQfW1dU`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "0188c65a-d879-490f-afaf-4194263d5dd5",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex",
    "oldString": "mean token-level NLL, capturing the average predictability of the text under the reference model;",
    "newString": "mean token-level NLL, which captures the average predictability of the text under the reference model;",
    "originalFile": "\\section{Method}\n\\label{sec:method}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{fig2_framework.pdf}\n\\caption{Depth fingerprinting framework. (a)~Recursive generation chains are constructed by iteratively feeding text through a generator $G$. (b)~Seven features are extracted per text: five NLL statistics from a Pythia-410M reference model and two surface diversity measures. Horizontal bars show Spearman $\\rho$ with generation depth and reveal differential depth response: drifting features ($|\\rho| > 0.6$) capture the monotonic location shift, while stationary features ($|\\rho| < 0.1$) provide a stable baseline. (c)~An XGBoost classifier trained under Leave-One-Generator-Out (LOGO) cross-validation predicts depth class (gen-0\\,/\\,gen-1\\,/\\,gen-2+).}\n\\label{fig:framework}\n\\end{figure*}\n\n\\subsection{Task Formulation}\n\\label{sec:task}\n\nGiven a text $x$, the goal is to predict its \\emph{generation depth} $d \\in \\{0, 1, 2{+}\\}$, where $d{=}0$ denotes human-written text, $d{=}1$ denotes first-generation LLM output conditioned on human text, and $d{=}2{+}$ denotes text produced by recursively conditioning an LLM on its own prior output at least twice.\nFormally, let $\\mathcal{C}_0$ be a reference corpus of human-written text.\nA generation chain of depth $k$ is defined recursively: $x^{(0)} \\sim \\mathcal{C}_0$, and $x^{(k)} = G(x^{(k-1)})$ for $k \\geq 1$, where $G$ denotes stochastic LLM generation conditioned on its input.\nWe frame depth estimation as an ordinal classification task over three classes rather than binary real-vs-synthetic detection, which enables finer-grained provenance characterization.\nDepths beyond 2 are merged into a single $2{+}$ class, consistent with monotonic feature convergence that compresses inter-class margins beyond depth 2 (\\S\\ref{sec:results-differential}).\n\n\\subsection{Generation Chain Construction}\n\\label{sec:generation}\n\nWe construct generation chains using eight generators spanning five model families: \\textbf{Pythia} (2.8B, 1B) \\cite{pythia}, \\textbf{OLMo} (OLMo-2-1B) \\cite{olmo}, \\textbf{Qwen} (Qwen3-1.7B, Qwen3-0.6B, Qwen3-8B-Base) \\cite{qwen3}, \\textbf{Llama} (Llama-3.2-3B) \\cite{llama3}, and \\textbf{Mistral} (Mistral-7B-v0.3) \\cite{mistral7b}.\nThis selection covers parameter scales from 0.6B to 8B and diverse pretraining corpora, which enables evaluation of cross-generator and cross-scale generalization.\n\nFor each generator, we sample approximately 1{,}000 seed passages from English Wikipedia as $\\mathcal{C}_0$.\nThe same pool of seed passages serves as gen-0 for all generators.\nWe use shared seeds across generators to ensure that cross-generator comparisons control for input content, which isolates the effect of the generation model from source text variation.\nIn LOGO evaluation, gen-0 samples from the held-out generator's chains also appear (with the same text) in the training generators' chains, creating a potential train--test overlap for the gen-0 class.\nWe address this with a supplementary binary evaluation excluding gen-0 entirely (\\S\\ref{sec:results-baselines}).\nEach seed is iteratively fed through the generator to produce a chain of depth 4 (i.e., gen-0 through gen-4), using the prompt ``\\texttt{Continue the following text: \\{text\\}}''.\nAll generation uses temperature $\\tau{=}0.7$, nucleus sampling with $p{=}0.9$, and maximum length of 256 new tokens.\nThe theoretical yield is $8 \\times {\\sim}1{,}000 \\times 5 = 39{,}815$ texts; after removing 2{,}746 chain breaks (empty or degenerate outputs at intermediate depths that prevented deeper generation) and 11 passages too short for feature extraction, 37{,}058 texts remain (Appendix~\\ref{app:dataset-stats}).\nFor classification, depths 2--4 are collapsed into the $2{+}$ class.\n\n\\subsection{Feature Extraction}\n\\label{sec:features}\n\nThe seven features are motivated by two complementary views of distributional drift.\nReference-model features capture how the text's token-level surprise distribution shifts relative to a fixed model; surface features capture how lexical diversity contracts under recursive generation.\nTogether, they span both the generative mechanism (what the model produces) and the surface manifestation (how the vocabulary changes); Figure~\\ref{fig:framework} provides an overview.\nThis two-pronged design is validated through leave-one-feature-out analysis (Appendix~\\ref{app:lofo}) and cross-group ablation (\\S\\ref{sec:results-differential}), which confirms that both feature groups contribute to depth discrimination.\n\nWe extract seven distributional features per text, organized into two groups based on what they measure rather than how they are computed.\n\n\\paragraph{Reference-model features.}\nA held-out reference model (Pythia-410M, chosen to be smaller than all generators) computes per-token negative log-likelihood (NLL) for each text.\nWe use ``entropy'' as shorthand for token-level NLL throughout, following convention in prior detection work; these are point-wise NLL values, not Shannon entropy of the full distribution.\nAlthough Pythia-410M shares the GPT-NeoX architecture with two of the eight generators, cross-family reference model experiments (\\S\\ref{sec:results-differential}) confirm that depth features are not reference-specific (LOGO F1 varies by $\\leq$0.013 across Pythia, OLMo, and Qwen references).\nFrom the resulting NLL sequence, we extract five statistics:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{entropy\\_mean}: mean token-level NLL, capturing the average predictability of the text under the reference model;\n    \\item \\textbf{entropy\\_std}: standard deviation of token-level NLL, measuring the spread of per-token surprise;\n    \\item \\textbf{entropy\\_max}: maximum token-level NLL, capturing the most surprising token;\n    \\item \\textbf{entropy\\_min}: minimum token-level NLL, capturing the most predictable token. As generation depth increases, the floor of token-level surprise drops, reflecting the model's increasing confidence on its own outputs.\n    Retained because removing it does not improve performance (LOFO $\\Delta$F1\\,=\\,+0.01\\,pp, within bootstrap noise) and it completes the four-number NLL summary (mean, std, max, min), ensuring the classifier has access to the full marginal distribution shape;\n    \\item \\textbf{tail\\_decay}: slope of the vocabulary-level averaged log-probability distribution in the mid-rank region (ranks 100--1000).\n    For each text, we compute the mean log-probability of each vocabulary token across all positions under the reference model, sort tokens in descending order of mean log-probability, and fit a linear regression to ranks 100--1000.\n    The slope captures how steeply the reference model's probability mass decays beyond high-probability tokens, characterizing the shape of the distribution tail.\n    We select ranks 100--1000 because high-frequency tokens (ranks $<$ 100) exhibit minimal discriminative variance across depths, while ranks beyond 1000 are sparsely populated and noisy.\n\\end{itemize}\n\n\\paragraph{Surface features.}\nTwo features capture lexical diversity without requiring a reference model:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{TTR}: type-token ratio (number of unique word types divided by total tokens);\n    \\item \\textbf{hapax\\_ratio}: proportion of words appearing exactly once (\\emph{hapax legomena}).\n\\end{itemize}\n\n\\paragraph{Feature complementarity.}\nThe grouping reflects an empirical pattern we term \\emph{differential depth response}: central-tendency and diversity features (entropy\\_mean, TTR, hapax\\_ratio) show substantial monotonic drift with generation depth ($|\\rho| = 0.60$--$0.63$); entropy\\_min and entropy\\_std show moderate drift ($|\\rho| = 0.17$--$0.41$); and shape features (entropy\\_max, tail\\_decay) remain near-stationary ($|\\rho| < 0.10$).\nThis differential behavior, consistent with recursive generation shifting the location of the NLL distribution while approximately preserving distributional shape, motivates combining both feature types.\nAs shown in \\S\\ref{sec:results}, the full 7-feature set significantly outperforms either group alone.\n\n\\subsection{Evaluation Protocol}\n\\label{sec:evaluation}\n\n\\paragraph{Cross-validation.}\nTo evaluate generalization to unseen generators, we use \\textbf{Leave-One-Generator-Out (LOGO)} cross-validation over all eight generators; \\textbf{Leave-One-Family-Out (LOFO)} holds out entire model families.\nCross-model chains use the original five-generator subset (Pythia-2.8B/1B, OLMo-2-1B, Qwen3-1.7B/0.6B); Llama and Mistral were added subsequently for single-generator LOGO only.\nSome appendix analyses predate this expansion and use six generators (the original five plus Qwen3-8B); each table notes its generator subset.\n\n\\paragraph{Classifier.}\nWe use XGBoost \\cite{xgboost} throughout ($n\\_\\text{estimators}{=}200$, $\\max\\_\\text{depth}{=}6$, learning rate $0.1$), with identical hyperparameters across all methods in Table~\\ref{tab:baselines}.\nLOGO F1 is stable across random seeds (std\\,$<$\\,0.001 over 5 seeds).\nAlternative classifiers and ordinal-specific methods (CORAL \\cite{coral_ordinal}, Frank-Hall \\cite{frank_hall_ordinal}) yield comparable performance (Appendix~\\ref{app:classifier}), confirming that discriminative power resides in the features.\n\n\\paragraph{Metrics and statistical testing.}\nThe primary metric is \\textbf{macro-averaged F1} over the three depth classes.\nWe report 95\\% confidence intervals via percentile bootstrap ($n{=}1{,}000$), McNemar tests for pairwise comparisons, and paired bootstrap for baseline comparisons.\nAll $p$-values are two-sided; Bonferroni correction is applied within each family of simultaneous tests: the 21 distributional comparisons (7 features $\\times$ 3 depth-group pairs, \\S\\ref{sec:results-differential}) and the 4 pairwise baseline comparisons (\\S\\ref{sec:results-baselines}).\nFeature--depth correlations (\\S\\ref{sec:results-differential}) use class-balanced subsamples to control for depth-class imbalance.\n\n\\paragraph{Baselines.}\nWe compare the 7-feature ensemble against four single-score detection methods repurposed as depth predictors: Avg-LogProb, FastDetectGPT \\cite{fast_detectgpt}, Binoculars \\cite{binoculars}, and LD-Score \\cite{ld_score}.\nEach baseline score is used as a univariate feature in the same XGBoost framework under LOGO cross-validation, ensuring a controlled comparison.\n\n\\paragraph{Length confound control.}\nSince TTR and hapax\\_ratio are mechanically length-dependent, we verify depth signal is not a length artifact via length-matched subsampling that equalizes length distributions across depth classes (\\S\\ref{sec:results-classification}; Appendix~\\ref{app:length}).\n",
    "structuredPatch": [
      {
        "oldStart": 49,
        "oldLines": 7,
        "newStart": 49,
        "newLines": 7,
        "lines": [
          " Although Pythia-410M shares the GPT-NeoX architecture with two of the eight generators, cross-family reference model experiments (\\S\\ref{sec:results-differential}) confirm that depth features are not reference-specific (LOGO F1 varies by $\\leq$0.013 across Pythia, OLMo, and Qwen references).",
          " From the resulting NLL sequence, we extract five statistics:",
          " \\begin{itemize}[nosep,leftmargin=*]",
          "-    \\item \\textbf{entropy\\_mean}: mean token-level NLL, capturing the average predictability of the text under the reference model;",
          "+    \\item \\textbf{entropy\\_mean}: mean token-level NLL, which captures the average predictability of the text under the reference model;",
          "     \\item \\textbf{entropy\\_std}: standard deviation of token-level NLL, measuring the spread of per-token surprise;",
          "     \\item \\textbf{entropy\\_max}: maximum token-level NLL, capturing the most surprising token;",
          "     \\item \\textbf{entropy\\_min}: minimum token-level NLL, capturing the most predictable token. As generation depth increases, the floor of token-level surprise drops, reflecting the model's increasing confidence on its own outputs."
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

_source line 119_

<details open><summary>🔧 Tool call — Edit · `toolu_01BNybH19uE7366DpNHnvmRS`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex",
  "old_string": "standard deviation of token-level NLL, measuring the spread of per-token surprise;",
  "new_string": "standard deviation of token-level NLL, which measures the spread of per-token surprise;"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "299dcb42-e08e-4518-a916-96457fe782a0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UYoxg57iCdSuHDVeL6JWmK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 74548,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 74548
      },
      "output_tokens": 7,
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

_source line 120 · 2026-05-17T19:57:43.784Z_

<details><summary>↩ Tool result · `toolu_01BNybH19uE7366DpNHnvmRS`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "e9bae424-ded6-4b43-bb8c-682da3a10cea",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex",
    "oldString": "standard deviation of token-level NLL, measuring the spread of per-token surprise;",
    "newString": "standard deviation of token-level NLL, which measures the spread of per-token surprise;",
    "originalFile": "\\section{Method}\n\\label{sec:method}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{fig2_framework.pdf}\n\\caption{Depth fingerprinting framework. (a)~Recursive generation chains are constructed by iteratively feeding text through a generator $G$. (b)~Seven features are extracted per text: five NLL statistics from a Pythia-410M reference model and two surface diversity measures. Horizontal bars show Spearman $\\rho$ with generation depth and reveal differential depth response: drifting features ($|\\rho| > 0.6$) capture the monotonic location shift, while stationary features ($|\\rho| < 0.1$) provide a stable baseline. (c)~An XGBoost classifier trained under Leave-One-Generator-Out (LOGO) cross-validation predicts depth class (gen-0\\,/\\,gen-1\\,/\\,gen-2+).}\n\\label{fig:framework}\n\\end{figure*}\n\n\\subsection{Task Formulation}\n\\label{sec:task}\n\nGiven a text $x$, the goal is to predict its \\emph{generation depth} $d \\in \\{0, 1, 2{+}\\}$, where $d{=}0$ denotes human-written text, $d{=}1$ denotes first-generation LLM output conditioned on human text, and $d{=}2{+}$ denotes text produced by recursively conditioning an LLM on its own prior output at least twice.\nFormally, let $\\mathcal{C}_0$ be a reference corpus of human-written text.\nA generation chain of depth $k$ is defined recursively: $x^{(0)} \\sim \\mathcal{C}_0$, and $x^{(k)} = G(x^{(k-1)})$ for $k \\geq 1$, where $G$ denotes stochastic LLM generation conditioned on its input.\nWe frame depth estimation as an ordinal classification task over three classes rather than binary real-vs-synthetic detection, which enables finer-grained provenance characterization.\nDepths beyond 2 are merged into a single $2{+}$ class, consistent with monotonic feature convergence that compresses inter-class margins beyond depth 2 (\\S\\ref{sec:results-differential}).\n\n\\subsection{Generation Chain Construction}\n\\label{sec:generation}\n\nWe construct generation chains using eight generators spanning five model families: \\textbf{Pythia} (2.8B, 1B) \\cite{pythia}, \\textbf{OLMo} (OLMo-2-1B) \\cite{olmo}, \\textbf{Qwen} (Qwen3-1.7B, Qwen3-0.6B, Qwen3-8B-Base) \\cite{qwen3}, \\textbf{Llama} (Llama-3.2-3B) \\cite{llama3}, and \\textbf{Mistral} (Mistral-7B-v0.3) \\cite{mistral7b}.\nThis selection covers parameter scales from 0.6B to 8B and diverse pretraining corpora, which enables evaluation of cross-generator and cross-scale generalization.\n\nFor each generator, we sample approximately 1{,}000 seed passages from English Wikipedia as $\\mathcal{C}_0$.\nThe same pool of seed passages serves as gen-0 for all generators.\nWe use shared seeds across generators to ensure that cross-generator comparisons control for input content, which isolates the effect of the generation model from source text variation.\nIn LOGO evaluation, gen-0 samples from the held-out generator's chains also appear (with the same text) in the training generators' chains, creating a potential train--test overlap for the gen-0 class.\nWe address this with a supplementary binary evaluation excluding gen-0 entirely (\\S\\ref{sec:results-baselines}).\nEach seed is iteratively fed through the generator to produce a chain of depth 4 (i.e., gen-0 through gen-4), using the prompt ``\\texttt{Continue the following text: \\{text\\}}''.\nAll generation uses temperature $\\tau{=}0.7$, nucleus sampling with $p{=}0.9$, and maximum length of 256 new tokens.\nThe theoretical yield is $8 \\times {\\sim}1{,}000 \\times 5 = 39{,}815$ texts; after removing 2{,}746 chain breaks (empty or degenerate outputs at intermediate depths that prevented deeper generation) and 11 passages too short for feature extraction, 37{,}058 texts remain (Appendix~\\ref{app:dataset-stats}).\nFor classification, depths 2--4 are collapsed into the $2{+}$ class.\n\n\\subsection{Feature Extraction}\n\\label{sec:features}\n\nThe seven features are motivated by two complementary views of distributional drift.\nReference-model features capture how the text's token-level surprise distribution shifts relative to a fixed model; surface features capture how lexical diversity contracts under recursive generation.\nTogether, they span both the generative mechanism (what the model produces) and the surface manifestation (how the vocabulary changes); Figure~\\ref{fig:framework} provides an overview.\nThis two-pronged design is validated through leave-one-feature-out analysis (Appendix~\\ref{app:lofo}) and cross-group ablation (\\S\\ref{sec:results-differential}), which confirms that both feature groups contribute to depth discrimination.\n\nWe extract seven distributional features per text, organized into two groups based on what they measure rather than how they are computed.\n\n\\paragraph{Reference-model features.}\nA held-out reference model (Pythia-410M, chosen to be smaller than all generators) computes per-token negative log-likelihood (NLL) for each text.\nWe use ``entropy'' as shorthand for token-level NLL throughout, following convention in prior detection work; these are point-wise NLL values, not Shannon entropy of the full distribution.\nAlthough Pythia-410M shares the GPT-NeoX architecture with two of the eight generators, cross-family reference model experiments (\\S\\ref{sec:results-differential}) confirm that depth features are not reference-specific (LOGO F1 varies by $\\leq$0.013 across Pythia, OLMo, and Qwen references).\nFrom the resulting NLL sequence, we extract five statistics:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{entropy\\_mean}: mean token-level NLL, which captures the average predictability of the text under the reference model;\n    \\item \\textbf{entropy\\_std}: standard deviation of token-level NLL, measuring the spread of per-token surprise;\n    \\item \\textbf{entropy\\_max}: maximum token-level NLL, capturing the most surprising token;\n    \\item \\textbf{entropy\\_min}: minimum token-level NLL, capturing the most predictable token. As generation depth increases, the floor of token-level surprise drops, reflecting the model's increasing confidence on its own outputs.\n    Retained because removing it does not improve performance (LOFO $\\Delta$F1\\,=\\,+0.01\\,pp, within bootstrap noise) and it completes the four-number NLL summary (mean, std, max, min), ensuring the classifier has access to the full marginal distribution shape;\n    \\item \\textbf{tail\\_decay}: slope of the vocabulary-level averaged log-probability distribution in the mid-rank region (ranks 100--1000).\n    For each text, we compute the mean log-probability of each vocabulary token across all positions under the reference model, sort tokens in descending order of mean log-probability, and fit a linear regression to ranks 100--1000.\n    The slope captures how steeply the reference model's probability mass decays beyond high-probability tokens, characterizing the shape of the distribution tail.\n    We select ranks 100--1000 because high-frequency tokens (ranks $<$ 100) exhibit minimal discriminative variance across depths, while ranks beyond 1000 are sparsely populated and noisy.\n\\end{itemize}\n\n\\paragraph{Surface features.}\nTwo features capture lexical diversity without requiring a reference model:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{TTR}: type-token ratio (number of unique word types divided by total tokens);\n    \\item \\textbf{hapax\\_ratio}: proportion of words appearing exactly once (\\emph{hapax legomena}).\n\\end{itemize}\n\n\\paragraph{Feature complementarity.}\nThe grouping reflects an empirical pattern we term \\emph{differential depth response}: central-tendency and diversity features (entropy\\_mean, TTR, hapax\\_ratio) show substantial monotonic drift with generation depth ($|\\rho| = 0.60$--$0.63$); entropy\\_min and entropy\\_std show moderate drift ($|\\rho| = 0.17$--$0.41$); and shape features (entropy\\_max, tail\\_decay) remain near-stationary ($|\\rho| < 0.10$).\nThis differential behavior, consistent with recursive generation shifting the location of the NLL distribution while approximately preserving distributional shape, motivates combining both feature types.\nAs shown in \\S\\ref{sec:results}, the full 7-feature set significantly outperforms either group alone.\n\n\\subsection{Evaluation Protocol}\n\\label{sec:evaluation}\n\n\\paragraph{Cross-validation.}\nTo evaluate generalization to unseen generators, we use \\textbf{Leave-One-Generator-Out (LOGO)} cross-validation over all eight generators; \\textbf{Leave-One-Family-Out (LOFO)} holds out entire model families.\nCross-model chains use the original five-generator subset (Pythia-2.8B/1B, OLMo-2-1B, Qwen3-1.7B/0.6B); Llama and Mistral were added subsequently for single-generator LOGO only.\nSome appendix analyses predate this expansion and use six generators (the original five plus Qwen3-8B); each table notes its generator subset.\n\n\\paragraph{Classifier.}\nWe use XGBoost \\cite{xgboost} throughout ($n\\_\\text{estimators}{=}200$, $\\max\\_\\text{depth}{=}6$, learning rate $0.1$), with identical hyperparameters across all methods in Table~\\ref{tab:baselines}.\nLOGO F1 is stable across random seeds (std\\,$<$\\,0.001 over 5 seeds).\nAlternative classifiers and ordinal-specific methods (CORAL \\cite{coral_ordinal}, Frank-Hall \\cite{frank_hall_ordinal}) yield comparable performance (Appendix~\\ref{app:classifier}), confirming that discriminative power resides in the features.\n\n\\paragraph{Metrics and statistical testing.}\nThe primary metric is \\textbf{macro-averaged F1} over the three depth classes.\nWe report 95\\% confidence intervals via percentile bootstrap ($n{=}1{,}000$), McNemar tests for pairwise comparisons, and paired bootstrap for baseline comparisons.\nAll $p$-values are two-sided; Bonferroni correction is applied within each family of simultaneous tests: the 21 distributional comparisons (7 features $\\times$ 3 depth-group pairs, \\S\\ref{sec:results-differential}) and the 4 pairwise baseline comparisons (\\S\\ref{sec:results-baselines}).\nFeature--depth correlations (\\S\\ref{sec:results-differential}) use class-balanced subsamples to control for depth-class imbalance.\n\n\\paragraph{Baselines.}\nWe compare the 7-feature ensemble against four single-score detection methods repurposed as depth predictors: Avg-LogProb, FastDetectGPT \\cite{fast_detectgpt}, Binoculars \\cite{binoculars}, and LD-Score \\cite{ld_score}.\nEach baseline score is used as a univariate feature in the same XGBoost framework under LOGO cross-validation, ensuring a controlled comparison.\n\n\\paragraph{Length confound control.}\nSince TTR and hapax\\_ratio are mechanically length-dependent, we verify depth signal is not a length artifact via length-matched subsampling that equalizes length distributions across depth classes (\\S\\ref{sec:results-classification}; Appendix~\\ref{app:length}).\n",
    "structuredPatch": [
      {
        "oldStart": 50,
        "oldLines": 7,
        "newStart": 50,
        "newLines": 7,
        "lines": [
          " From the resulting NLL sequence, we extract five statistics:",
          " \\begin{itemize}[nosep,leftmargin=*]",
          "     \\item \\textbf{entropy\\_mean}: mean token-level NLL, which captures the average predictability of the text under the reference model;",
          "-    \\item \\textbf{entropy\\_std}: standard deviation of token-level NLL, measuring the spread of per-token surprise;",
          "+    \\item \\textbf{entropy\\_std}: standard deviation of token-level NLL, which measures the spread of per-token surprise;",
          "     \\item \\textbf{entropy\\_max}: maximum token-level NLL, capturing the most surprising token;",
          "     \\item \\textbf{entropy\\_min}: minimum token-level NLL, capturing the most predictable token. As generation depth increases, the floor of token-level surprise drops, reflecting the model's increasing confidence on its own outputs.",
          "     Retained because removing it does not improve performance (LOFO $\\Delta$F1\\,=\\,+0.01\\,pp, within bootstrap noise) and it completes the four-number NLL summary (mean, std, max, min), ensuring the classifier has access to the full marginal distribution shape;"
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

_source line 121_

<details open><summary>🔧 Tool call — Edit · `toolu_01SXgAvmervkJXRPiZQbvAai`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex",
  "old_string": "maximum token-level NLL, capturing the most surprising token;",
  "new_string": "maximum token-level NLL, which captures the most surprising token;"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "dfdae1b7-d9b1-4be0-8b7f-72a649d8184d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UYoxg57iCdSuHDVeL6JWmK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 74548,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 74548
      },
      "output_tokens": 7,
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

_source line 122 · 2026-05-17T19:57:45.168Z_

<details><summary>↩ Tool result · `toolu_01SXgAvmervkJXRPiZQbvAai`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "a67ec959-503c-46a8-8ee0-aeaf4fcc6f0c",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex",
    "oldString": "maximum token-level NLL, capturing the most surprising token;",
    "newString": "maximum token-level NLL, which captures the most surprising token;",
    "originalFile": "\\section{Method}\n\\label{sec:method}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{fig2_framework.pdf}\n\\caption{Depth fingerprinting framework. (a)~Recursive generation chains are constructed by iteratively feeding text through a generator $G$. (b)~Seven features are extracted per text: five NLL statistics from a Pythia-410M reference model and two surface diversity measures. Horizontal bars show Spearman $\\rho$ with generation depth and reveal differential depth response: drifting features ($|\\rho| > 0.6$) capture the monotonic location shift, while stationary features ($|\\rho| < 0.1$) provide a stable baseline. (c)~An XGBoost classifier trained under Leave-One-Generator-Out (LOGO) cross-validation predicts depth class (gen-0\\,/\\,gen-1\\,/\\,gen-2+).}\n\\label{fig:framework}\n\\end{figure*}\n\n\\subsection{Task Formulation}\n\\label{sec:task}\n\nGiven a text $x$, the goal is to predict its \\emph{generation depth} $d \\in \\{0, 1, 2{+}\\}$, where $d{=}0$ denotes human-written text, $d{=}1$ denotes first-generation LLM output conditioned on human text, and $d{=}2{+}$ denotes text produced by recursively conditioning an LLM on its own prior output at least twice.\nFormally, let $\\mathcal{C}_0$ be a reference corpus of human-written text.\nA generation chain of depth $k$ is defined recursively: $x^{(0)} \\sim \\mathcal{C}_0$, and $x^{(k)} = G(x^{(k-1)})$ for $k \\geq 1$, where $G$ denotes stochastic LLM generation conditioned on its input.\nWe frame depth estimation as an ordinal classification task over three classes rather than binary real-vs-synthetic detection, which enables finer-grained provenance characterization.\nDepths beyond 2 are merged into a single $2{+}$ class, consistent with monotonic feature convergence that compresses inter-class margins beyond depth 2 (\\S\\ref{sec:results-differential}).\n\n\\subsection{Generation Chain Construction}\n\\label{sec:generation}\n\nWe construct generation chains using eight generators spanning five model families: \\textbf{Pythia} (2.8B, 1B) \\cite{pythia}, \\textbf{OLMo} (OLMo-2-1B) \\cite{olmo}, \\textbf{Qwen} (Qwen3-1.7B, Qwen3-0.6B, Qwen3-8B-Base) \\cite{qwen3}, \\textbf{Llama} (Llama-3.2-3B) \\cite{llama3}, and \\textbf{Mistral} (Mistral-7B-v0.3) \\cite{mistral7b}.\nThis selection covers parameter scales from 0.6B to 8B and diverse pretraining corpora, which enables evaluation of cross-generator and cross-scale generalization.\n\nFor each generator, we sample approximately 1{,}000 seed passages from English Wikipedia as $\\mathcal{C}_0$.\nThe same pool of seed passages serves as gen-0 for all generators.\nWe use shared seeds across generators to ensure that cross-generator comparisons control for input content, which isolates the effect of the generation model from source text variation.\nIn LOGO evaluation, gen-0 samples from the held-out generator's chains also appear (with the same text) in the training generators' chains, creating a potential train--test overlap for the gen-0 class.\nWe address this with a supplementary binary evaluation excluding gen-0 entirely (\\S\\ref{sec:results-baselines}).\nEach seed is iteratively fed through the generator to produce a chain of depth 4 (i.e., gen-0 through gen-4), using the prompt ``\\texttt{Continue the following text: \\{text\\}}''.\nAll generation uses temperature $\\tau{=}0.7$, nucleus sampling with $p{=}0.9$, and maximum length of 256 new tokens.\nThe theoretical yield is $8 \\times {\\sim}1{,}000 \\times 5 = 39{,}815$ texts; after removing 2{,}746 chain breaks (empty or degenerate outputs at intermediate depths that prevented deeper generation) and 11 passages too short for feature extraction, 37{,}058 texts remain (Appendix~\\ref{app:dataset-stats}).\nFor classification, depths 2--4 are collapsed into the $2{+}$ class.\n\n\\subsection{Feature Extraction}\n\\label{sec:features}\n\nThe seven features are motivated by two complementary views of distributional drift.\nReference-model features capture how the text's token-level surprise distribution shifts relative to a fixed model; surface features capture how lexical diversity contracts under recursive generation.\nTogether, they span both the generative mechanism (what the model produces) and the surface manifestation (how the vocabulary changes); Figure~\\ref{fig:framework} provides an overview.\nThis two-pronged design is validated through leave-one-feature-out analysis (Appendix~\\ref{app:lofo}) and cross-group ablation (\\S\\ref{sec:results-differential}), which confirms that both feature groups contribute to depth discrimination.\n\nWe extract seven distributional features per text, organized into two groups based on what they measure rather than how they are computed.\n\n\\paragraph{Reference-model features.}\nA held-out reference model (Pythia-410M, chosen to be smaller than all generators) computes per-token negative log-likelihood (NLL) for each text.\nWe use ``entropy'' as shorthand for token-level NLL throughout, following convention in prior detection work; these are point-wise NLL values, not Shannon entropy of the full distribution.\nAlthough Pythia-410M shares the GPT-NeoX architecture with two of the eight generators, cross-family reference model experiments (\\S\\ref{sec:results-differential}) confirm that depth features are not reference-specific (LOGO F1 varies by $\\leq$0.013 across Pythia, OLMo, and Qwen references).\nFrom the resulting NLL sequence, we extract five statistics:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{entropy\\_mean}: mean token-level NLL, which captures the average predictability of the text under the reference model;\n    \\item \\textbf{entropy\\_std}: standard deviation of token-level NLL, which measures the spread of per-token surprise;\n    \\item \\textbf{entropy\\_max}: maximum token-level NLL, capturing the most surprising token;\n    \\item \\textbf{entropy\\_min}: minimum token-level NLL, capturing the most predictable token. As generation depth increases, the floor of token-level surprise drops, reflecting the model's increasing confidence on its own outputs.\n    Retained because removing it does not improve performance (LOFO $\\Delta$F1\\,=\\,+0.01\\,pp, within bootstrap noise) and it completes the four-number NLL summary (mean, std, max, min), ensuring the classifier has access to the full marginal distribution shape;\n    \\item \\textbf{tail\\_decay}: slope of the vocabulary-level averaged log-probability distribution in the mid-rank region (ranks 100--1000).\n    For each text, we compute the mean log-probability of each vocabulary token across all positions under the reference model, sort tokens in descending order of mean log-probability, and fit a linear regression to ranks 100--1000.\n    The slope captures how steeply the reference model's probability mass decays beyond high-probability tokens, characterizing the shape of the distribution tail.\n    We select ranks 100--1000 because high-frequency tokens (ranks $<$ 100) exhibit minimal discriminative variance across depths, while ranks beyond 1000 are sparsely populated and noisy.\n\\end{itemize}\n\n\\paragraph{Surface features.}\nTwo features capture lexical diversity without requiring a reference model:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{TTR}: type-token ratio (number of unique word types divided by total tokens);\n    \\item \\textbf{hapax\\_ratio}: proportion of words appearing exactly once (\\emph{hapax legomena}).\n\\end{itemize}\n\n\\paragraph{Feature complementarity.}\nThe grouping reflects an empirical pattern we term \\emph{differential depth response}: central-tendency and diversity features (entropy\\_mean, TTR, hapax\\_ratio) show substantial monotonic drift with generation depth ($|\\rho| = 0.60$--$0.63$); entropy\\_min and entropy\\_std show moderate drift ($|\\rho| = 0.17$--$0.41$); and shape features (entropy\\_max, tail\\_decay) remain near-stationary ($|\\rho| < 0.10$).\nThis differential behavior, consistent with recursive generation shifting the location of the NLL distribution while approximately preserving distributional shape, motivates combining both feature types.\nAs shown in \\S\\ref{sec:results}, the full 7-feature set significantly outperforms either group alone.\n\n\\subsection{Evaluation Protocol}\n\\label{sec:evaluation}\n\n\\paragraph{Cross-validation.}\nTo evaluate generalization to unseen generators, we use \\textbf{Leave-One-Generator-Out (LOGO)} cross-validation over all eight generators; \\textbf{Leave-One-Family-Out (LOFO)} holds out entire model families.\nCross-model chains use the original five-generator subset (Pythia-2.8B/1B, OLMo-2-1B, Qwen3-1.7B/0.6B); Llama and Mistral were added subsequently for single-generator LOGO only.\nSome appendix analyses predate this expansion and use six generators (the original five plus Qwen3-8B); each table notes its generator subset.\n\n\\paragraph{Classifier.}\nWe use XGBoost \\cite{xgboost} throughout ($n\\_\\text{estimators}{=}200$, $\\max\\_\\text{depth}{=}6$, learning rate $0.1$), with identical hyperparameters across all methods in Table~\\ref{tab:baselines}.\nLOGO F1 is stable across random seeds (std\\,$<$\\,0.001 over 5 seeds).\nAlternative classifiers and ordinal-specific methods (CORAL \\cite{coral_ordinal}, Frank-Hall \\cite{frank_hall_ordinal}) yield comparable performance (Appendix~\\ref{app:classifier}), confirming that discriminative power resides in the features.\n\n\\paragraph{Metrics and statistical testing.}\nThe primary metric is \\textbf{macro-averaged F1} over the three depth classes.\nWe report 95\\% confidence intervals via percentile bootstrap ($n{=}1{,}000$), McNemar tests for pairwise comparisons, and paired bootstrap for baseline comparisons.\nAll $p$-values are two-sided; Bonferroni correction is applied within each family of simultaneous tests: the 21 distributional comparisons (7 features $\\times$ 3 depth-group pairs, \\S\\ref{sec:results-differential}) and the 4 pairwise baseline comparisons (\\S\\ref{sec:results-baselines}).\nFeature--depth correlations (\\S\\ref{sec:results-differential}) use class-balanced subsamples to control for depth-class imbalance.\n\n\\paragraph{Baselines.}\nWe compare the 7-feature ensemble against four single-score detection methods repurposed as depth predictors: Avg-LogProb, FastDetectGPT \\cite{fast_detectgpt}, Binoculars \\cite{binoculars}, and LD-Score \\cite{ld_score}.\nEach baseline score is used as a univariate feature in the same XGBoost framework under LOGO cross-validation, ensuring a controlled comparison.\n\n\\paragraph{Length confound control.}\nSince TTR and hapax\\_ratio are mechanically length-dependent, we verify depth signal is not a length artifact via length-matched subsampling that equalizes length distributions across depth classes (\\S\\ref{sec:results-classification}; Appendix~\\ref{app:length}).\n",
    "structuredPatch": [
      {
        "oldStart": 51,
        "oldLines": 7,
        "newStart": 51,
        "newLines": 7,
        "lines": [
          " \\begin{itemize}[nosep,leftmargin=*]",
          "     \\item \\textbf{entropy\\_mean}: mean token-level NLL, which captures the average predictability of the text under the reference model;",
          "     \\item \\textbf{entropy\\_std}: standard deviation of token-level NLL, which measures the spread of per-token surprise;",
          "-    \\item \\textbf{entropy\\_max}: maximum token-level NLL, capturing the most surprising token;",
          "+    \\item \\textbf{entropy\\_max}: maximum token-level NLL, which captures the most surprising token;",
          "     \\item \\textbf{entropy\\_min}: minimum token-level NLL, capturing the most predictable token. As generation depth increases, the floor of token-level surprise drops, reflecting the model's increasing confidence on its own outputs.",
          "     Retained because removing it does not improve performance (LOFO $\\Delta$F1\\,=\\,+0.01\\,pp, within bootstrap noise) and it completes the four-number NLL summary (mean, std, max, min), ensuring the classifier has access to the full marginal distribution shape;",
          "     \\item \\textbf{tail\\_decay}: slope of the vocabulary-level averaged log-probability distribution in the mid-rank region (ranks 100--1000)."
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

_source line 123_

<details open><summary>🔧 Tool call — Edit · `toolu_01BhUcAfxnuvCsRFuVyjQVop`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex",
  "old_string": "minimum token-level NLL, capturing the most predictable token. As generation depth increases, the floor of token-level surprise drops, reflecting the model's increasing confidence on its own outputs.",
  "new_string": "minimum token-level NLL, which captures the most predictable token. As generation depth increases, the floor of token-level surprise drops; this reflects the model's increasing confidence on its own outputs."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "c7b8c197-28b2-454f-ae05-c6ca528ce021",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UYoxg57iCdSuHDVeL6JWmK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 74548,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 74548
      },
      "output_tokens": 7,
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

_source line 124 · 2026-05-17T19:57:47.562Z_

<details><summary>↩ Tool result · `toolu_01BhUcAfxnuvCsRFuVyjQVop`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "4c62fde8-5b59-4752-a20c-341c66b3f765",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex",
    "oldString": "minimum token-level NLL, capturing the most predictable token. As generation depth increases, the floor of token-level surprise drops, reflecting the model's increasing confidence on its own outputs.",
    "newString": "minimum token-level NLL, which captures the most predictable token. As generation depth increases, the floor of token-level surprise drops; this reflects the model's increasing confidence on its own outputs.",
    "originalFile": "\\section{Method}\n\\label{sec:method}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{fig2_framework.pdf}\n\\caption{Depth fingerprinting framework. (a)~Recursive generation chains are constructed by iteratively feeding text through a generator $G$. (b)~Seven features are extracted per text: five NLL statistics from a Pythia-410M reference model and two surface diversity measures. Horizontal bars show Spearman $\\rho$ with generation depth and reveal differential depth response: drifting features ($|\\rho| > 0.6$) capture the monotonic location shift, while stationary features ($|\\rho| < 0.1$) provide a stable baseline. (c)~An XGBoost classifier trained under Leave-One-Generator-Out (LOGO) cross-validation predicts depth class (gen-0\\,/\\,gen-1\\,/\\,gen-2+).}\n\\label{fig:framework}\n\\end{figure*}\n\n\\subsection{Task Formulation}\n\\label{sec:task}\n\nGiven a text $x$, the goal is to predict its \\emph{generation depth} $d \\in \\{0, 1, 2{+}\\}$, where $d{=}0$ denotes human-written text, $d{=}1$ denotes first-generation LLM output conditioned on human text, and $d{=}2{+}$ denotes text produced by recursively conditioning an LLM on its own prior output at least twice.\nFormally, let $\\mathcal{C}_0$ be a reference corpus of human-written text.\nA generation chain of depth $k$ is defined recursively: $x^{(0)} \\sim \\mathcal{C}_0$, and $x^{(k)} = G(x^{(k-1)})$ for $k \\geq 1$, where $G$ denotes stochastic LLM generation conditioned on its input.\nWe frame depth estimation as an ordinal classification task over three classes rather than binary real-vs-synthetic detection, which enables finer-grained provenance characterization.\nDepths beyond 2 are merged into a single $2{+}$ class, consistent with monotonic feature convergence that compresses inter-class margins beyond depth 2 (\\S\\ref{sec:results-differential}).\n\n\\subsection{Generation Chain Construction}\n\\label{sec:generation}\n\nWe construct generation chains using eight generators spanning five model families: \\textbf{Pythia} (2.8B, 1B) \\cite{pythia}, \\textbf{OLMo} (OLMo-2-1B) \\cite{olmo}, \\textbf{Qwen} (Qwen3-1.7B, Qwen3-0.6B, Qwen3-8B-Base) \\cite{qwen3}, \\textbf{Llama} (Llama-3.2-3B) \\cite{llama3}, and \\textbf{Mistral} (Mistral-7B-v0.3) \\cite{mistral7b}.\nThis selection covers parameter scales from 0.6B to 8B and diverse pretraining corpora, which enables evaluation of cross-generator and cross-scale generalization.\n\nFor each generator, we sample approximately 1{,}000 seed passages from English Wikipedia as $\\mathcal{C}_0$.\nThe same pool of seed passages serves as gen-0 for all generators.\nWe use shared seeds across generators to ensure that cross-generator comparisons control for input content, which isolates the effect of the generation model from source text variation.\nIn LOGO evaluation, gen-0 samples from the held-out generator's chains also appear (with the same text) in the training generators' chains, creating a potential train--test overlap for the gen-0 class.\nWe address this with a supplementary binary evaluation excluding gen-0 entirely (\\S\\ref{sec:results-baselines}).\nEach seed is iteratively fed through the generator to produce a chain of depth 4 (i.e., gen-0 through gen-4), using the prompt ``\\texttt{Continue the following text: \\{text\\}}''.\nAll generation uses temperature $\\tau{=}0.7$, nucleus sampling with $p{=}0.9$, and maximum length of 256 new tokens.\nThe theoretical yield is $8 \\times {\\sim}1{,}000 \\times 5 = 39{,}815$ texts; after removing 2{,}746 chain breaks (empty or degenerate outputs at intermediate depths that prevented deeper generation) and 11 passages too short for feature extraction, 37{,}058 texts remain (Appendix~\\ref{app:dataset-stats}).\nFor classification, depths 2--4 are collapsed into the $2{+}$ class.\n\n\\subsection{Feature Extraction}\n\\label{sec:features}\n\nThe seven features are motivated by two complementary views of distributional drift.\nReference-model features capture how the text's token-level surprise distribution shifts relative to a fixed model; surface features capture how lexical diversity contracts under recursive generation.\nTogether, they span both the generative mechanism (what the model produces) and the surface manifestation (how the vocabulary changes); Figure~\\ref{fig:framework} provides an overview.\nThis two-pronged design is validated through leave-one-feature-out analysis (Appendix~\\ref{app:lofo}) and cross-group ablation (\\S\\ref{sec:results-differential}), which confirms that both feature groups contribute to depth discrimination.\n\nWe extract seven distributional features per text, organized into two groups based on what they measure rather than how they are computed.\n\n\\paragraph{Reference-model features.}\nA held-out reference model (Pythia-410M, chosen to be smaller than all generators) computes per-token negative log-likelihood (NLL) for each text.\nWe use ``entropy'' as shorthand for token-level NLL throughout, following convention in prior detection work; these are point-wise NLL values, not Shannon entropy of the full distribution.\nAlthough Pythia-410M shares the GPT-NeoX architecture with two of the eight generators, cross-family reference model experiments (\\S\\ref{sec:results-differential}) confirm that depth features are not reference-specific (LOGO F1 varies by $\\leq$0.013 across Pythia, OLMo, and Qwen references).\nFrom the resulting NLL sequence, we extract five statistics:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{entropy\\_mean}: mean token-level NLL, which captures the average predictability of the text under the reference model;\n    \\item \\textbf{entropy\\_std}: standard deviation of token-level NLL, which measures the spread of per-token surprise;\n    \\item \\textbf{entropy\\_max}: maximum token-level NLL, which captures the most surprising token;\n    \\item \\textbf{entropy\\_min}: minimum token-level NLL, capturing the most predictable token. As generation depth increases, the floor of token-level surprise drops, reflecting the model's increasing confidence on its own outputs.\n    Retained because removing it does not improve performance (LOFO $\\Delta$F1\\,=\\,+0.01\\,pp, within bootstrap noise) and it completes the four-number NLL summary (mean, std, max, min), ensuring the classifier has access to the full marginal distribution shape;\n    \\item \\textbf{tail\\_decay}: slope of the vocabulary-level averaged log-probability distribution in the mid-rank region (ranks 100--1000).\n    For each text, we compute the mean log-probability of each vocabulary token across all positions under the reference model, sort tokens in descending order of mean log-probability, and fit a linear regression to ranks 100--1000.\n    The slope captures how steeply the reference model's probability mass decays beyond high-probability tokens, characterizing the shape of the distribution tail.\n    We select ranks 100--1000 because high-frequency tokens (ranks $<$ 100) exhibit minimal discriminative variance across depths, while ranks beyond 1000 are sparsely populated and noisy.\n\\end{itemize}\n\n\\paragraph{Surface features.}\nTwo features capture lexical diversity without requiring a reference model:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{TTR}: type-token ratio (number of unique word types divided by total tokens);\n    \\item \\textbf{hapax\\_ratio}: proportion of words appearing exactly once (\\emph{hapax legomena}).\n\\end{itemize}\n\n\\paragraph{Feature complementarity.}\nThe grouping reflects an empirical pattern we term \\emph{differential depth response}: central-tendency and diversity features (entropy\\_mean, TTR, hapax\\_ratio) show substantial monotonic drift with generation depth ($|\\rho| = 0.60$--$0.63$); entropy\\_min and entropy\\_std show moderate drift ($|\\rho| = 0.17$--$0.41$); and shape features (entropy\\_max, tail\\_decay) remain near-stationary ($|\\rho| < 0.10$).\nThis differential behavior, consistent with recursive generation shifting the location of the NLL distribution while approximately preserving distributional shape, motivates combining both feature types.\nAs shown in \\S\\ref{sec:results}, the full 7-feature set significantly outperforms either group alone.\n\n\\subsection{Evaluation Protocol}\n\\label{sec:evaluation}\n\n\\paragraph{Cross-validation.}\nTo evaluate generalization to unseen generators, we use \\textbf{Leave-One-Generator-Out (LOGO)} cross-validation over all eight generators; \\textbf{Leave-One-Family-Out (LOFO)} holds out entire model families.\nCross-model chains use the original five-generator subset (Pythia-2.8B/1B, OLMo-2-1B, Qwen3-1.7B/0.6B); Llama and Mistral were added subsequently for single-generator LOGO only.\nSome appendix analyses predate this expansion and use six generators (the original five plus Qwen3-8B); each table notes its generator subset.\n\n\\paragraph{Classifier.}\nWe use XGBoost \\cite{xgboost} throughout ($n\\_\\text{estimators}{=}200$, $\\max\\_\\text{depth}{=}6$, learning rate $0.1$), with identical hyperparameters across all methods in Table~\\ref{tab:baselines}.\nLOGO F1 is stable across random seeds (std\\,$<$\\,0.001 over 5 seeds).\nAlternative classifiers and ordinal-specific methods (CORAL \\cite{coral_ordinal}, Frank-Hall \\cite{frank_hall_ordinal}) yield comparable performance (Appendix~\\ref{app:classifier}), confirming that discriminative power resides in the features.\n\n\\paragraph{Metrics and statistical testing.}\nThe primary metric is \\textbf{macro-averaged F1} over the three depth classes.\nWe report 95\\% confidence intervals via percentile bootstrap ($n{=}1{,}000$), McNemar tests for pairwise comparisons, and paired bootstrap for baseline comparisons.\nAll $p$-values are two-sided; Bonferroni correction is applied within each family of simultaneous tests: the 21 distributional comparisons (7 features $\\times$ 3 depth-group pairs, \\S\\ref{sec:results-differential}) and the 4 pairwise baseline comparisons (\\S\\ref{sec:results-baselines}).\nFeature--depth correlations (\\S\\ref{sec:results-differential}) use class-balanced subsamples to control for depth-class imbalance.\n\n\\paragraph{Baselines.}\nWe compare the 7-feature ensemble against four single-score detection methods repurposed as depth predictors: Avg-LogProb, FastDetectGPT \\cite{fast_detectgpt}, Binoculars \\cite{binoculars}, and LD-Score \\cite{ld_score}.\nEach baseline score is used as a univariate feature in the same XGBoost framework under LOGO cross-validation, ensuring a controlled comparison.\n\n\\paragraph{Length confound control.}\nSince TTR and hapax\\_ratio are mechanically length-dependent, we verify depth signal is not a length artifact via length-matched subsampling that equalizes length distributions across depth classes (\\S\\ref{sec:results-classification}; Appendix~\\ref{app:length}).\n",
    "structuredPatch": [
      {
        "oldStart": 52,
        "oldLines": 7,
        "newStart": 52,
        "newLines": 7,
        "lines": [
          "     \\item \\textbf{entropy\\_mean}: mean token-level NLL, which captures the average predictability of the text under the reference model;",
          "     \\item \\textbf{entropy\\_std}: standard deviation of token-level NLL, which measures the spread of per-token surprise;",
          "     \\item \\textbf{entropy\\_max}: maximum token-level NLL, which captures the most surprising token;",
          "-    \\item \\textbf{entropy\\_min}: minimum token-level NLL, capturing the most predictable token. As generation depth increases, the floor of token-level surprise drops, reflecting the model's increasing confidence on its own outputs.",
          "+    \\item \\textbf{entropy\\_min}: minimum token-level NLL, which captures the most predictable token. As generation depth increases, the floor of token-level surprise drops; this reflects the model's increasing confidence on its own outputs.",
          "     Retained because removing it does not improve performance (LOFO $\\Delta$F1\\,=\\,+0.01\\,pp, within bootstrap noise) and it completes the four-number NLL summary (mean, std, max, min), ensuring the classifier has access to the full marginal distribution shape;",
          "     \\item \\textbf{tail\\_decay}: slope of the vocabulary-level averaged log-probability distribution in the mid-rank region (ranks 100--1000).",
          "     For each text, we compute the mean log-probability of each vocabulary token across all positions under the reference model, sort tokens in descending order of mean log-probability, and fit a linear regression to ranks 100--1000."
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

_source line 125_

<details open><summary>🔧 Tool call — Edit · `toolu_01QC8N7eMAsk47WDbx6AHo2q`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex",
  "old_string": "summary (mean, std, max, min), ensuring the classifier has access to the full marginal distribution shape;",
  "new_string": "summary (mean, std, max, min), which ensures the classifier has access to the full marginal distribution shape;"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "0155f4ec-f420-4c77-bd8e-55190a7f4eb2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UYoxg57iCdSuHDVeL6JWmK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 74548,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 74548
      },
      "output_tokens": 7,
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

_source line 126 · 2026-05-17T19:57:49.436Z_

<details><summary>↩ Tool result · `toolu_01QC8N7eMAsk47WDbx6AHo2q`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "49c54bcf-891f-423c-8cca-087d6bf95691",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex",
    "oldString": "summary (mean, std, max, min), ensuring the classifier has access to the full marginal distribution shape;",
    "newString": "summary (mean, std, max, min), which ensures the classifier has access to the full marginal distribution shape;",
    "originalFile": "\\section{Method}\n\\label{sec:method}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{fig2_framework.pdf}\n\\caption{Depth fingerprinting framework. (a)~Recursive generation chains are constructed by iteratively feeding text through a generator $G$. (b)~Seven features are extracted per text: five NLL statistics from a Pythia-410M reference model and two surface diversity measures. Horizontal bars show Spearman $\\rho$ with generation depth and reveal differential depth response: drifting features ($|\\rho| > 0.6$) capture the monotonic location shift, while stationary features ($|\\rho| < 0.1$) provide a stable baseline. (c)~An XGBoost classifier trained under Leave-One-Generator-Out (LOGO) cross-validation predicts depth class (gen-0\\,/\\,gen-1\\,/\\,gen-2+).}\n\\label{fig:framework}\n\\end{figure*}\n\n\\subsection{Task Formulation}\n\\label{sec:task}\n\nGiven a text $x$, the goal is to predict its \\emph{generation depth} $d \\in \\{0, 1, 2{+}\\}$, where $d{=}0$ denotes human-written text, $d{=}1$ denotes first-generation LLM output conditioned on human text, and $d{=}2{+}$ denotes text produced by recursively conditioning an LLM on its own prior output at least twice.\nFormally, let $\\mathcal{C}_0$ be a reference corpus of human-written text.\nA generation chain of depth $k$ is defined recursively: $x^{(0)} \\sim \\mathcal{C}_0$, and $x^{(k)} = G(x^{(k-1)})$ for $k \\geq 1$, where $G$ denotes stochastic LLM generation conditioned on its input.\nWe frame depth estimation as an ordinal classification task over three classes rather than binary real-vs-synthetic detection, which enables finer-grained provenance characterization.\nDepths beyond 2 are merged into a single $2{+}$ class, consistent with monotonic feature convergence that compresses inter-class margins beyond depth 2 (\\S\\ref{sec:results-differential}).\n\n\\subsection{Generation Chain Construction}\n\\label{sec:generation}\n\nWe construct generation chains using eight generators spanning five model families: \\textbf{Pythia} (2.8B, 1B) \\cite{pythia}, \\textbf{OLMo} (OLMo-2-1B) \\cite{olmo}, \\textbf{Qwen} (Qwen3-1.7B, Qwen3-0.6B, Qwen3-8B-Base) \\cite{qwen3}, \\textbf{Llama} (Llama-3.2-3B) \\cite{llama3}, and \\textbf{Mistral} (Mistral-7B-v0.3) \\cite{mistral7b}.\nThis selection covers parameter scales from 0.6B to 8B and diverse pretraining corpora, which enables evaluation of cross-generator and cross-scale generalization.\n\nFor each generator, we sample approximately 1{,}000 seed passages from English Wikipedia as $\\mathcal{C}_0$.\nThe same pool of seed passages serves as gen-0 for all generators.\nWe use shared seeds across generators to ensure that cross-generator comparisons control for input content, which isolates the effect of the generation model from source text variation.\nIn LOGO evaluation, gen-0 samples from the held-out generator's chains also appear (with the same text) in the training generators' chains, creating a potential train--test overlap for the gen-0 class.\nWe address this with a supplementary binary evaluation excluding gen-0 entirely (\\S\\ref{sec:results-baselines}).\nEach seed is iteratively fed through the generator to produce a chain of depth 4 (i.e., gen-0 through gen-4), using the prompt ``\\texttt{Continue the following text: \\{text\\}}''.\nAll generation uses temperature $\\tau{=}0.7$, nucleus sampling with $p{=}0.9$, and maximum length of 256 new tokens.\nThe theoretical yield is $8 \\times {\\sim}1{,}000 \\times 5 = 39{,}815$ texts; after removing 2{,}746 chain breaks (empty or degenerate outputs at intermediate depths that prevented deeper generation) and 11 passages too short for feature extraction, 37{,}058 texts remain (Appendix~\\ref{app:dataset-stats}).\nFor classification, depths 2--4 are collapsed into the $2{+}$ class.\n\n\\subsection{Feature Extraction}\n\\label{sec:features}\n\nThe seven features are motivated by two complementary views of distributional drift.\nReference-model features capture how the text's token-level surprise distribution shifts relative to a fixed model; surface features capture how lexical diversity contracts under recursive generation.\nTogether, they span both the generative mechanism (what the model produces) and the surface manifestation (how the vocabulary changes); Figure~\\ref{fig:framework} provides an overview.\nThis two-pronged design is validated through leave-one-feature-out analysis (Appendix~\\ref{app:lofo}) and cross-group ablation (\\S\\ref{sec:results-differential}), which confirms that both feature groups contribute to depth discrimination.\n\nWe extract seven distributional features per text, organized into two groups based on what they measure rather than how they are computed.\n\n\\paragraph{Reference-model features.}\nA held-out reference model (Pythia-410M, chosen to be smaller than all generators) computes per-token negative log-likelihood (NLL) for each text.\nWe use ``entropy'' as shorthand for token-level NLL throughout, following convention in prior detection work; these are point-wise NLL values, not Shannon entropy of the full distribution.\nAlthough Pythia-410M shares the GPT-NeoX architecture with two of the eight generators, cross-family reference model experiments (\\S\\ref{sec:results-differential}) confirm that depth features are not reference-specific (LOGO F1 varies by $\\leq$0.013 across Pythia, OLMo, and Qwen references).\nFrom the resulting NLL sequence, we extract five statistics:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{entropy\\_mean}: mean token-level NLL, which captures the average predictability of the text under the reference model;\n    \\item \\textbf{entropy\\_std}: standard deviation of token-level NLL, which measures the spread of per-token surprise;\n    \\item \\textbf{entropy\\_max}: maximum token-level NLL, which captures the most surprising token;\n    \\item \\textbf{entropy\\_min}: minimum token-level NLL, which captures the most predictable token. As generation depth increases, the floor of token-level surprise drops; this reflects the model's increasing confidence on its own outputs.\n    Retained because removing it does not improve performance (LOFO $\\Delta$F1\\,=\\,+0.01\\,pp, within bootstrap noise) and it completes the four-number NLL summary (mean, std, max, min), ensuring the classifier has access to the full marginal distribution shape;\n    \\item \\textbf{tail\\_decay}: slope of the vocabulary-level averaged log-probability distribution in the mid-rank region (ranks 100--1000).\n    For each text, we compute the mean log-probability of each vocabulary token across all positions under the reference model, sort tokens in descending order of mean log-probability, and fit a linear regression to ranks 100--1000.\n    The slope captures how steeply the reference model's probability mass decays beyond high-probability tokens, characterizing the shape of the distribution tail.\n    We select ranks 100--1000 because high-frequency tokens (ranks $<$ 100) exhibit minimal discriminative variance across depths, while ranks beyond 1000 are sparsely populated and noisy.\n\\end{itemize}\n\n\\paragraph{Surface features.}\nTwo features capture lexical diversity without requiring a reference model:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{TTR}: type-token ratio (number of unique word types divided by total tokens);\n    \\item \\textbf{hapax\\_ratio}: proportion of words appearing exactly once (\\emph{hapax legomena}).\n\\end{itemize}\n\n\\paragraph{Feature complementarity.}\nThe grouping reflects an empirical pattern we term \\emph{differential depth response}: central-tendency and diversity features (entropy\\_mean, TTR, hapax\\_ratio) show substantial monotonic drift with generation depth ($|\\rho| = 0.60$--$0.63$); entropy\\_min and entropy\\_std show moderate drift ($|\\rho| = 0.17$--$0.41$); and shape features (entropy\\_max, tail\\_decay) remain near-stationary ($|\\rho| < 0.10$).\nThis differential behavior, consistent with recursive generation shifting the location of the NLL distribution while approximately preserving distributional shape, motivates combining both feature types.\nAs shown in \\S\\ref{sec:results}, the full 7-feature set significantly outperforms either group alone.\n\n\\subsection{Evaluation Protocol}\n\\label{sec:evaluation}\n\n\\paragraph{Cross-validation.}\nTo evaluate generalization to unseen generators, we use \\textbf{Leave-One-Generator-Out (LOGO)} cross-validation over all eight generators; \\textbf{Leave-One-Family-Out (LOFO)} holds out entire model families.\nCross-model chains use the original five-generator subset (Pythia-2.8B/1B, OLMo-2-1B, Qwen3-1.7B/0.6B); Llama and Mistral were added subsequently for single-generator LOGO only.\nSome appendix analyses predate this expansion and use six generators (the original five plus Qwen3-8B); each table notes its generator subset.\n\n\\paragraph{Classifier.}\nWe use XGBoost \\cite{xgboost} throughout ($n\\_\\text{estimators}{=}200$, $\\max\\_\\text{depth}{=}6$, learning rate $0.1$), with identical hyperparameters across all methods in Table~\\ref{tab:baselines}.\nLOGO F1 is stable across random seeds (std\\,$<$\\,0.001 over 5 seeds).\nAlternative classifiers and ordinal-specific methods (CORAL \\cite{coral_ordinal}, Frank-Hall \\cite{frank_hall_ordinal}) yield comparable performance (Appendix~\\ref{app:classifier}), confirming that discriminative power resides in the features.\n\n\\paragraph{Metrics and statistical testing.}\nThe primary metric is \\textbf{macro-averaged F1} over the three depth classes.\nWe report 95\\% confidence intervals via percentile bootstrap ($n{=}1{,}000$), McNemar tests for pairwise comparisons, and paired bootstrap for baseline comparisons.\nAll $p$-values are two-sided; Bonferroni correction is applied within each family of simultaneous tests: the 21 distributional comparisons (7 features $\\times$ 3 depth-group pairs, \\S\\ref{sec:results-differential}) and the 4 pairwise baseline comparisons (\\S\\ref{sec:results-baselines}).\nFeature--depth correlations (\\S\\ref{sec:results-differential}) use class-balanced subsamples to control for depth-class imbalance.\n\n\\paragraph{Baselines.}\nWe compare the 7-feature ensemble against four single-score detection methods repurposed as depth predictors: Avg-LogProb, FastDetectGPT \\cite{fast_detectgpt}, Binoculars \\cite{binoculars}, and LD-Score \\cite{ld_score}.\nEach baseline score is used as a univariate feature in the same XGBoost framework under LOGO cross-validation, ensuring a controlled comparison.\n\n\\paragraph{Length confound control.}\nSince TTR and hapax\\_ratio are mechanically length-dependent, we verify depth signal is not a length artifact via length-matched subsampling that equalizes length distributions across depth classes (\\S\\ref{sec:results-classification}; Appendix~\\ref{app:length}).\n",
    "structuredPatch": [
      {
        "oldStart": 53,
        "oldLines": 7,
        "newStart": 53,
        "newLines": 7,
        "lines": [
          "     \\item \\textbf{entropy\\_std}: standard deviation of token-level NLL, which measures the spread of per-token surprise;",
          "     \\item \\textbf{entropy\\_max}: maximum token-level NLL, which captures the most surprising token;",
          "     \\item \\textbf{entropy\\_min}: minimum token-level NLL, which captures the most predictable token. As generation depth increases, the floor of token-level surprise drops; this reflects the model's increasing confidence on its own outputs.",
          "-    Retained because removing it does not improve performance (LOFO $\\Delta$F1\\,=\\,+0.01\\,pp, within bootstrap noise) and it completes the four-number NLL summary (mean, std, max, min), ensuring the classifier has access to the full marginal distribution shape;",
          "+    Retained because removing it does not improve performance (LOFO $\\Delta$F1\\,=\\,+0.01\\,pp, within bootstrap noise) and it completes the four-number NLL summary (mean, std, max, min), which ensures the classifier has access to the full marginal distribution shape;",
          "     \\item \\textbf{tail\\_decay}: slope of the vocabulary-level averaged log-probability distribution in the mid-rank region (ranks 100--1000).",
          "     For each text, we compute the mean log-probability of each vocabulary token across all positions under the reference model, sort tokens in descending order of mean log-probability, and fit a linear regression to ranks 100--1000.",
          "     The slope captures how steeply the reference model's probability mass decays beyond high-probability tokens, characterizing the shape of the distribution tail."
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

_source line 127_

<details open><summary>🔧 Tool call — Edit · `toolu_01S7R2qMGQU2rRyVZVLHrqvS`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex",
  "old_string": ", characterizing the shape of the distribution tail.",
  "new_string": " and characterizes the shape of the distribution tail."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "4c56adc9-c006-4705-8d9a-a700e4e1d4ee",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UYoxg57iCdSuHDVeL6JWmK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 74548,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 74548
      },
      "output_tokens": 7,
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

_source line 128 · 2026-05-17T19:57:50.315Z_

<details><summary>↩ Tool result · `toolu_01S7R2qMGQU2rRyVZVLHrqvS`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "57e31edc-e433-4d2e-8da6-7c29bff8da45",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex",
    "oldString": ", characterizing the shape of the distribution tail.",
    "newString": " and characterizes the shape of the distribution tail.",
    "originalFile": "\\section{Method}\n\\label{sec:method}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{fig2_framework.pdf}\n\\caption{Depth fingerprinting framework. (a)~Recursive generation chains are constructed by iteratively feeding text through a generator $G$. (b)~Seven features are extracted per text: five NLL statistics from a Pythia-410M reference model and two surface diversity measures. Horizontal bars show Spearman $\\rho$ with generation depth and reveal differential depth response: drifting features ($|\\rho| > 0.6$) capture the monotonic location shift, while stationary features ($|\\rho| < 0.1$) provide a stable baseline. (c)~An XGBoost classifier trained under Leave-One-Generator-Out (LOGO) cross-validation predicts depth class (gen-0\\,/\\,gen-1\\,/\\,gen-2+).}\n\\label{fig:framework}\n\\end{figure*}\n\n\\subsection{Task Formulation}\n\\label{sec:task}\n\nGiven a text $x$, the goal is to predict its \\emph{generation depth} $d \\in \\{0, 1, 2{+}\\}$, where $d{=}0$ denotes human-written text, $d{=}1$ denotes first-generation LLM output conditioned on human text, and $d{=}2{+}$ denotes text produced by recursively conditioning an LLM on its own prior output at least twice.\nFormally, let $\\mathcal{C}_0$ be a reference corpus of human-written text.\nA generation chain of depth $k$ is defined recursively: $x^{(0)} \\sim \\mathcal{C}_0$, and $x^{(k)} = G(x^{(k-1)})$ for $k \\geq 1$, where $G$ denotes stochastic LLM generation conditioned on its input.\nWe frame depth estimation as an ordinal classification task over three classes rather than binary real-vs-synthetic detection, which enables finer-grained provenance characterization.\nDepths beyond 2 are merged into a single $2{+}$ class, consistent with monotonic feature convergence that compresses inter-class margins beyond depth 2 (\\S\\ref{sec:results-differential}).\n\n\\subsection{Generation Chain Construction}\n\\label{sec:generation}\n\nWe construct generation chains using eight generators spanning five model families: \\textbf{Pythia} (2.8B, 1B) \\cite{pythia}, \\textbf{OLMo} (OLMo-2-1B) \\cite{olmo}, \\textbf{Qwen} (Qwen3-1.7B, Qwen3-0.6B, Qwen3-8B-Base) \\cite{qwen3}, \\textbf{Llama} (Llama-3.2-3B) \\cite{llama3}, and \\textbf{Mistral} (Mistral-7B-v0.3) \\cite{mistral7b}.\nThis selection covers parameter scales from 0.6B to 8B and diverse pretraining corpora, which enables evaluation of cross-generator and cross-scale generalization.\n\nFor each generator, we sample approximately 1{,}000 seed passages from English Wikipedia as $\\mathcal{C}_0$.\nThe same pool of seed passages serves as gen-0 for all generators.\nWe use shared seeds across generators to ensure that cross-generator comparisons control for input content, which isolates the effect of the generation model from source text variation.\nIn LOGO evaluation, gen-0 samples from the held-out generator's chains also appear (with the same text) in the training generators' chains, creating a potential train--test overlap for the gen-0 class.\nWe address this with a supplementary binary evaluation excluding gen-0 entirely (\\S\\ref{sec:results-baselines}).\nEach seed is iteratively fed through the generator to produce a chain of depth 4 (i.e., gen-0 through gen-4), using the prompt ``\\texttt{Continue the following text: \\{text\\}}''.\nAll generation uses temperature $\\tau{=}0.7$, nucleus sampling with $p{=}0.9$, and maximum length of 256 new tokens.\nThe theoretical yield is $8 \\times {\\sim}1{,}000 \\times 5 = 39{,}815$ texts; after removing 2{,}746 chain breaks (empty or degenerate outputs at intermediate depths that prevented deeper generation) and 11 passages too short for feature extraction, 37{,}058 texts remain (Appendix~\\ref{app:dataset-stats}).\nFor classification, depths 2--4 are collapsed into the $2{+}$ class.\n\n\\subsection{Feature Extraction}\n\\label{sec:features}\n\nThe seven features are motivated by two complementary views of distributional drift.\nReference-model features capture how the text's token-level surprise distribution shifts relative to a fixed model; surface features capture how lexical diversity contracts under recursive generation.\nTogether, they span both the generative mechanism (what the model produces) and the surface manifestation (how the vocabulary changes); Figure~\\ref{fig:framework} provides an overview.\nThis two-pronged design is validated through leave-one-feature-out analysis (Appendix~\\ref{app:lofo}) and cross-group ablation (\\S\\ref{sec:results-differential}), which confirms that both feature groups contribute to depth discrimination.\n\nWe extract seven distributional features per text, organized into two groups based on what they measure rather than how they are computed.\n\n\\paragraph{Reference-model features.}\nA held-out reference model (Pythia-410M, chosen to be smaller than all generators) computes per-token negative log-likelihood (NLL) for each text.\nWe use ``entropy'' as shorthand for token-level NLL throughout, following convention in prior detection work; these are point-wise NLL values, not Shannon entropy of the full distribution.\nAlthough Pythia-410M shares the GPT-NeoX architecture with two of the eight generators, cross-family reference model experiments (\\S\\ref{sec:results-differential}) confirm that depth features are not reference-specific (LOGO F1 varies by $\\leq$0.013 across Pythia, OLMo, and Qwen references).\nFrom the resulting NLL sequence, we extract five statistics:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{entropy\\_mean}: mean token-level NLL, which captures the average predictability of the text under the reference model;\n    \\item \\textbf{entropy\\_std}: standard deviation of token-level NLL, which measures the spread of per-token surprise;\n    \\item \\textbf{entropy\\_max}: maximum token-level NLL, which captures the most surprising token;\n    \\item \\textbf{entropy\\_min}: minimum token-level NLL, which captures the most predictable token. As generation depth increases, the floor of token-level surprise drops; this reflects the model's increasing confidence on its own outputs.\n    Retained because removing it does not improve performance (LOFO $\\Delta$F1\\,=\\,+0.01\\,pp, within bootstrap noise) and it completes the four-number NLL summary (mean, std, max, min), which ensures the classifier has access to the full marginal distribution shape;\n    \\item \\textbf{tail\\_decay}: slope of the vocabulary-level averaged log-probability distribution in the mid-rank region (ranks 100--1000).\n    For each text, we compute the mean log-probability of each vocabulary token across all positions under the reference model, sort tokens in descending order of mean log-probability, and fit a linear regression to ranks 100--1000.\n    The slope captures how steeply the reference model's probability mass decays beyond high-probability tokens, characterizing the shape of the distribution tail.\n    We select ranks 100--1000 because high-frequency tokens (ranks $<$ 100) exhibit minimal discriminative variance across depths, while ranks beyond 1000 are sparsely populated and noisy.\n\\end{itemize}\n\n\\paragraph{Surface features.}\nTwo features capture lexical diversity without requiring a reference model:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{TTR}: type-token ratio (number of unique word types divided by total tokens);\n    \\item \\textbf{hapax\\_ratio}: proportion of words appearing exactly once (\\emph{hapax legomena}).\n\\end{itemize}\n\n\\paragraph{Feature complementarity.}\nThe grouping reflects an empirical pattern we term \\emph{differential depth response}: central-tendency and diversity features (entropy\\_mean, TTR, hapax\\_ratio) show substantial monotonic drift with generation depth ($|\\rho| = 0.60$--$0.63$); entropy\\_min and entropy\\_std show moderate drift ($|\\rho| = 0.17$--$0.41$); and shape features (entropy\\_max, tail\\_decay) remain near-stationary ($|\\rho| < 0.10$).\nThis differential behavior, consistent with recursive generation shifting the location of the NLL distribution while approximately preserving distributional shape, motivates combining both feature types.\nAs shown in \\S\\ref{sec:results}, the full 7-feature set significantly outperforms either group alone.\n\n\\subsection{Evaluation Protocol}\n\\label{sec:evaluation}\n\n\\paragraph{Cross-validation.}\nTo evaluate generalization to unseen generators, we use \\textbf{Leave-One-Generator-Out (LOGO)} cross-validation over all eight generators; \\textbf{Leave-One-Family-Out (LOFO)} holds out entire model families.\nCross-model chains use the original five-generator subset (Pythia-2.8B/1B, OLMo-2-1B, Qwen3-1.7B/0.6B); Llama and Mistral were added subsequently for single-generator LOGO only.\nSome appendix analyses predate this expansion and use six generators (the original five plus Qwen3-8B); each table notes its generator subset.\n\n\\paragraph{Classifier.}\nWe use XGBoost \\cite{xgboost} throughout ($n\\_\\text{estimators}{=}200$, $\\max\\_\\text{depth}{=}6$, learning rate $0.1$), with identical hyperparameters across all methods in Table~\\ref{tab:baselines}.\nLOGO F1 is stable across random seeds (std\\,$<$\\,0.001 over 5 seeds).\nAlternative classifiers and ordinal-specific methods (CORAL \\cite{coral_ordinal}, Frank-Hall \\cite{frank_hall_ordinal}) yield comparable performance (Appendix~\\ref{app:classifier}), confirming that discriminative power resides in the features.\n\n\\paragraph{Metrics and statistical testing.}\nThe primary metric is \\textbf{macro-averaged F1} over the three depth classes.\nWe report 95\\% confidence intervals via percentile bootstrap ($n{=}1{,}000$), McNemar tests for pairwise comparisons, and paired bootstrap for baseline comparisons.\nAll $p$-values are two-sided; Bonferroni correction is applied within each family of simultaneous tests: the 21 distributional comparisons (7 features $\\times$ 3 depth-group pairs, \\S\\ref{sec:results-differential}) and the 4 pairwise baseline comparisons (\\S\\ref{sec:results-baselines}).\nFeature--depth correlations (\\S\\ref{sec:results-differential}) use class-balanced subsamples to control for depth-class imbalance.\n\n\\paragraph{Baselines.}\nWe compare the 7-feature ensemble against four single-score detection methods repurposed as depth predictors: Avg-LogProb, FastDetectGPT \\cite{fast_detectgpt}, Binoculars \\cite{binoculars}, and LD-Score \\cite{ld_score}.\nEach baseline score is used as a univariate feature in the same XGBoost framework under LOGO cross-validation, ensuring a controlled comparison.\n\n\\paragraph{Length confound control.}\nSince TTR and hapax\\_ratio are mechanically length-dependent, we verify depth signal is not a length artifact via length-matched subsampling that equalizes length distributions across depth classes (\\S\\ref{sec:results-classification}; Appendix~\\ref{app:length}).\n",
    "structuredPatch": [
      {
        "oldStart": 56,
        "oldLines": 7,
        "newStart": 56,
        "newLines": 7,
        "lines": [
          "     Retained because removing it does not improve performance (LOFO $\\Delta$F1\\,=\\,+0.01\\,pp, within bootstrap noise) and it completes the four-number NLL summary (mean, std, max, min), which ensures the classifier has access to the full marginal distribution shape;",
          "     \\item \\textbf{tail\\_decay}: slope of the vocabulary-level averaged log-probability distribution in the mid-rank region (ranks 100--1000).",
          "     For each text, we compute the mean log-probability of each vocabulary token across all positions under the reference model, sort tokens in descending order of mean log-probability, and fit a linear regression to ranks 100--1000.",
          "-    The slope captures how steeply the reference model's probability mass decays beyond high-probability tokens, characterizing the shape of the distribution tail.",
          "+    The slope captures how steeply the reference model's probability mass decays beyond high-probability tokens and characterizes the shape of the distribution tail.",
          "     We select ranks 100--1000 because high-frequency tokens (ranks $<$ 100) exhibit minimal discriminative variance across depths, while ranks beyond 1000 are sparsely populated and noisy.",
          " \\end{itemize}",
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


### Tool call

_source line 129_

<details open><summary>🔧 Tool call — Edit · `toolu_01RWCAfZPxnyWVHT2UYiNgop`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex",
  "old_string": "yield comparable performance (Appendix~\\ref{app:classifier}), confirming that discriminative power resides in the features.",
  "new_string": "yield comparable performance (Appendix~\\ref{app:classifier}), which confirms that discriminative power resides in the features."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "db9b4f31-d38a-4284-ae0c-2b753b18a2a9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UYoxg57iCdSuHDVeL6JWmK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 74548,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 74548
      },
      "output_tokens": 7,
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

_source line 130 · 2026-05-17T19:57:52.327Z_

<details><summary>↩ Tool result · `toolu_01RWCAfZPxnyWVHT2UYiNgop`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "01cfb11e-ae0c-4ba6-87b8-eb608132df98",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex",
    "oldString": "yield comparable performance (Appendix~\\ref{app:classifier}), confirming that discriminative power resides in the features.",
    "newString": "yield comparable performance (Appendix~\\ref{app:classifier}), which confirms that discriminative power resides in the features.",
    "originalFile": "\\section{Method}\n\\label{sec:method}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{fig2_framework.pdf}\n\\caption{Depth fingerprinting framework. (a)~Recursive generation chains are constructed by iteratively feeding text through a generator $G$. (b)~Seven features are extracted per text: five NLL statistics from a Pythia-410M reference model and two surface diversity measures. Horizontal bars show Spearman $\\rho$ with generation depth and reveal differential depth response: drifting features ($|\\rho| > 0.6$) capture the monotonic location shift, while stationary features ($|\\rho| < 0.1$) provide a stable baseline. (c)~An XGBoost classifier trained under Leave-One-Generator-Out (LOGO) cross-validation predicts depth class (gen-0\\,/\\,gen-1\\,/\\,gen-2+).}\n\\label{fig:framework}\n\\end{figure*}\n\n\\subsection{Task Formulation}\n\\label{sec:task}\n\nGiven a text $x$, the goal is to predict its \\emph{generation depth} $d \\in \\{0, 1, 2{+}\\}$, where $d{=}0$ denotes human-written text, $d{=}1$ denotes first-generation LLM output conditioned on human text, and $d{=}2{+}$ denotes text produced by recursively conditioning an LLM on its own prior output at least twice.\nFormally, let $\\mathcal{C}_0$ be a reference corpus of human-written text.\nA generation chain of depth $k$ is defined recursively: $x^{(0)} \\sim \\mathcal{C}_0$, and $x^{(k)} = G(x^{(k-1)})$ for $k \\geq 1$, where $G$ denotes stochastic LLM generation conditioned on its input.\nWe frame depth estimation as an ordinal classification task over three classes rather than binary real-vs-synthetic detection, which enables finer-grained provenance characterization.\nDepths beyond 2 are merged into a single $2{+}$ class, consistent with monotonic feature convergence that compresses inter-class margins beyond depth 2 (\\S\\ref{sec:results-differential}).\n\n\\subsection{Generation Chain Construction}\n\\label{sec:generation}\n\nWe construct generation chains using eight generators spanning five model families: \\textbf{Pythia} (2.8B, 1B) \\cite{pythia}, \\textbf{OLMo} (OLMo-2-1B) \\cite{olmo}, \\textbf{Qwen} (Qwen3-1.7B, Qwen3-0.6B, Qwen3-8B-Base) \\cite{qwen3}, \\textbf{Llama} (Llama-3.2-3B) \\cite{llama3}, and \\textbf{Mistral} (Mistral-7B-v0.3) \\cite{mistral7b}.\nThis selection covers parameter scales from 0.6B to 8B and diverse pretraining corpora, which enables evaluation of cross-generator and cross-scale generalization.\n\nFor each generator, we sample approximately 1{,}000 seed passages from English Wikipedia as $\\mathcal{C}_0$.\nThe same pool of seed passages serves as gen-0 for all generators.\nWe use shared seeds across generators to ensure that cross-generator comparisons control for input content, which isolates the effect of the generation model from source text variation.\nIn LOGO evaluation, gen-0 samples from the held-out generator's chains also appear (with the same text) in the training generators' chains, creating a potential train--test overlap for the gen-0 class.\nWe address this with a supplementary binary evaluation excluding gen-0 entirely (\\S\\ref{sec:results-baselines}).\nEach seed is iteratively fed through the generator to produce a chain of depth 4 (i.e., gen-0 through gen-4), using the prompt ``\\texttt{Continue the following text: \\{text\\}}''.\nAll generation uses temperature $\\tau{=}0.7$, nucleus sampling with $p{=}0.9$, and maximum length of 256 new tokens.\nThe theoretical yield is $8 \\times {\\sim}1{,}000 \\times 5 = 39{,}815$ texts; after removing 2{,}746 chain breaks (empty or degenerate outputs at intermediate depths that prevented deeper generation) and 11 passages too short for feature extraction, 37{,}058 texts remain (Appendix~\\ref{app:dataset-stats}).\nFor classification, depths 2--4 are collapsed into the $2{+}$ class.\n\n\\subsection{Feature Extraction}\n\\label{sec:features}\n\nThe seven features are motivated by two complementary views of distributional drift.\nReference-model features capture how the text's token-level surprise distribution shifts relative to a fixed model; surface features capture how lexical diversity contracts under recursive generation.\nTogether, they span both the generative mechanism (what the model produces) and the surface manifestation (how the vocabulary changes); Figure~\\ref{fig:framework} provides an overview.\nThis two-pronged design is validated through leave-one-feature-out analysis (Appendix~\\ref{app:lofo}) and cross-group ablation (\\S\\ref{sec:results-differential}), which confirms that both feature groups contribute to depth discrimination.\n\nWe extract seven distributional features per text, organized into two groups based on what they measure rather than how they are computed.\n\n\\paragraph{Reference-model features.}\nA held-out reference model (Pythia-410M, chosen to be smaller than all generators) computes per-token negative log-likelihood (NLL) for each text.\nWe use ``entropy'' as shorthand for token-level NLL throughout, following convention in prior detection work; these are point-wise NLL values, not Shannon entropy of the full distribution.\nAlthough Pythia-410M shares the GPT-NeoX architecture with two of the eight generators, cross-family reference model experiments (\\S\\ref{sec:results-differential}) confirm that depth features are not reference-specific (LOGO F1 varies by $\\leq$0.013 across Pythia, OLMo, and Qwen references).\nFrom the resulting NLL sequence, we extract five statistics:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{entropy\\_mean}: mean token-level NLL, which captures the average predictability of the text under the reference model;\n    \\item \\textbf{entropy\\_std}: standard deviation of token-level NLL, which measures the spread of per-token surprise;\n    \\item \\textbf{entropy\\_max}: maximum token-level NLL, which captures the most surprising token;\n    \\item \\textbf{entropy\\_min}: minimum token-level NLL, which captures the most predictable token. As generation depth increases, the floor of token-level surprise drops; this reflects the model's increasing confidence on its own outputs.\n    Retained because removing it does not improve performance (LOFO $\\Delta$F1\\,=\\,+0.01\\,pp, within bootstrap noise) and it completes the four-number NLL summary (mean, std, max, min), which ensures the classifier has access to the full marginal distribution shape;\n    \\item \\textbf{tail\\_decay}: slope of the vocabulary-level averaged log-probability distribution in the mid-rank region (ranks 100--1000).\n    For each text, we compute the mean log-probability of each vocabulary token across all positions under the reference model, sort tokens in descending order of mean log-probability, and fit a linear regression to ranks 100--1000.\n    The slope captures how steeply the reference model's probability mass decays beyond high-probability tokens and characterizes the shape of the distribution tail.\n    We select ranks 100--1000 because high-frequency tokens (ranks $<$ 100) exhibit minimal discriminative variance across depths, while ranks beyond 1000 are sparsely populated and noisy.\n\\end{itemize}\n\n\\paragraph{Surface features.}\nTwo features capture lexical diversity without requiring a reference model:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{TTR}: type-token ratio (number of unique word types divided by total tokens);\n    \\item \\textbf{hapax\\_ratio}: proportion of words appearing exactly once (\\emph{hapax legomena}).\n\\end{itemize}\n\n\\paragraph{Feature complementarity.}\nThe grouping reflects an empirical pattern we term \\emph{differential depth response}: central-tendency and diversity features (entropy\\_mean, TTR, hapax\\_ratio) show substantial monotonic drift with generation depth ($|\\rho| = 0.60$--$0.63$); entropy\\_min and entropy\\_std show moderate drift ($|\\rho| = 0.17$--$0.41$); and shape features (entropy\\_max, tail\\_decay) remain near-stationary ($|\\rho| < 0.10$).\nThis differential behavior, consistent with recursive generation shifting the location of the NLL distribution while approximately preserving distributional shape, motivates combining both feature types.\nAs shown in \\S\\ref{sec:results}, the full 7-feature set significantly outperforms either group alone.\n\n\\subsection{Evaluation Protocol}\n\\label{sec:evaluation}\n\n\\paragraph{Cross-validation.}\nTo evaluate generalization to unseen generators, we use \\textbf{Leave-One-Generator-Out (LOGO)} cross-validation over all eight generators; \\textbf{Leave-One-Family-Out (LOFO)} holds out entire model families.\nCross-model chains use the original five-generator subset (Pythia-2.8B/1B, OLMo-2-1B, Qwen3-1.7B/0.6B); Llama and Mistral were added subsequently for single-generator LOGO only.\nSome appendix analyses predate this expansion and use six generators (the original five plus Qwen3-8B); each table notes its generator subset.\n\n\\paragraph{Classifier.}\nWe use XGBoost \\cite{xgboost} throughout ($n\\_\\text{estimators}{=}200$, $\\max\\_\\text{depth}{=}6$, learning rate $0.1$), with identical hyperparameters across all methods in Table~\\ref{tab:baselines}.\nLOGO F1 is stable across random seeds (std\\,$<$\\,0.001 over 5 seeds).\nAlternative classifiers and ordinal-specific methods (CORAL \\cite{coral_ordinal}, Frank-Hall \\cite{frank_hall_ordinal}) yield comparable performance (Appendix~\\ref{app:classifier}), confirming that discriminative power resides in the features.\n\n\\paragraph{Metrics and statistical testing.}\nThe primary metric is \\textbf{macro-averaged F1} over the three depth classes.\nWe report 95\\% confidence intervals via percentile bootstrap ($n{=}1{,}000$), McNemar tests for pairwise comparisons, and paired bootstrap for baseline comparisons.\nAll $p$-values are two-sided; Bonferroni correction is applied within each family of simultaneous tests: the 21 distributional comparisons (7 features $\\times$ 3 depth-group pairs, \\S\\ref{sec:results-differential}) and the 4 pairwise baseline comparisons (\\S\\ref{sec:results-baselines}).\nFeature--depth correlations (\\S\\ref{sec:results-differential}) use class-balanced subsamples to control for depth-class imbalance.\n\n\\paragraph{Baselines.}\nWe compare the 7-feature ensemble against four single-score detection methods repurposed as depth predictors: Avg-LogProb, FastDetectGPT \\cite{fast_detectgpt}, Binoculars \\cite{binoculars}, and LD-Score \\cite{ld_score}.\nEach baseline score is used as a univariate feature in the same XGBoost framework under LOGO cross-validation, ensuring a controlled comparison.\n\n\\paragraph{Length confound control.}\nSince TTR and hapax\\_ratio are mechanically length-dependent, we verify depth signal is not a length artifact via length-matched subsampling that equalizes length distributions across depth classes (\\S\\ref{sec:results-classification}; Appendix~\\ref{app:length}).\n",
    "structuredPatch": [
      {
        "oldStart": 83,
        "oldLines": 7,
        "newStart": 83,
        "newLines": 7,
        "lines": [
          " \\paragraph{Classifier.}",
          " We use XGBoost \\cite{xgboost} throughout ($n\\_\\text{estimators}{=}200$, $\\max\\_\\text{depth}{=}6$, learning rate $0.1$), with identical hyperparameters across all methods in Table~\\ref{tab:baselines}.",
          " LOGO F1 is stable across random seeds (std\\,$<$\\,0.001 over 5 seeds).",
          "-Alternative classifiers and ordinal-specific methods (CORAL \\cite{coral_ordinal}, Frank-Hall \\cite{frank_hall_ordinal}) yield comparable performance (Appendix~\\ref{app:classifier}), confirming that discriminative power resides in the features.",
          "+Alternative classifiers and ordinal-specific methods (CORAL \\cite{coral_ordinal}, Frank-Hall \\cite{frank_hall_ordinal}) yield comparable performance (Appendix~\\ref{app:classifier}), which confirms that discriminative power resides in the features.",
          " ",
          " \\paragraph{Metrics and statistical testing.}",
          " The primary metric is \\textbf{macro-averaged F1} over the three depth classes."
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

_source line 131_

<details open><summary>🔧 Tool call — Edit · `toolu_01VoMNGFkNowahjHK4tAoUjT`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex",
  "old_string": ", ensuring a controlled comparison.",
  "new_string": " to ensure a controlled comparison."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "c1c09ee8-1541-4a0a-9d0d-9a3d08f55f26",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UYoxg57iCdSuHDVeL6JWmK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 74548,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 74548
      },
      "output_tokens": 7,
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

_source line 132 · 2026-05-17T19:57:53.587Z_

<details><summary>↩ Tool result · `toolu_01VoMNGFkNowahjHK4tAoUjT`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "bf4e143f-44b0-4799-9757-0121bc012b05",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex",
    "oldString": ", ensuring a controlled comparison.",
    "newString": " to ensure a controlled comparison.",
    "originalFile": "\\section{Method}\n\\label{sec:method}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{fig2_framework.pdf}\n\\caption{Depth fingerprinting framework. (a)~Recursive generation chains are constructed by iteratively feeding text through a generator $G$. (b)~Seven features are extracted per text: five NLL statistics from a Pythia-410M reference model and two surface diversity measures. Horizontal bars show Spearman $\\rho$ with generation depth and reveal differential depth response: drifting features ($|\\rho| > 0.6$) capture the monotonic location shift, while stationary features ($|\\rho| < 0.1$) provide a stable baseline. (c)~An XGBoost classifier trained under Leave-One-Generator-Out (LOGO) cross-validation predicts depth class (gen-0\\,/\\,gen-1\\,/\\,gen-2+).}\n\\label{fig:framework}\n\\end{figure*}\n\n\\subsection{Task Formulation}\n\\label{sec:task}\n\nGiven a text $x$, the goal is to predict its \\emph{generation depth} $d \\in \\{0, 1, 2{+}\\}$, where $d{=}0$ denotes human-written text, $d{=}1$ denotes first-generation LLM output conditioned on human text, and $d{=}2{+}$ denotes text produced by recursively conditioning an LLM on its own prior output at least twice.\nFormally, let $\\mathcal{C}_0$ be a reference corpus of human-written text.\nA generation chain of depth $k$ is defined recursively: $x^{(0)} \\sim \\mathcal{C}_0$, and $x^{(k)} = G(x^{(k-1)})$ for $k \\geq 1$, where $G$ denotes stochastic LLM generation conditioned on its input.\nWe frame depth estimation as an ordinal classification task over three classes rather than binary real-vs-synthetic detection, which enables finer-grained provenance characterization.\nDepths beyond 2 are merged into a single $2{+}$ class, consistent with monotonic feature convergence that compresses inter-class margins beyond depth 2 (\\S\\ref{sec:results-differential}).\n\n\\subsection{Generation Chain Construction}\n\\label{sec:generation}\n\nWe construct generation chains using eight generators spanning five model families: \\textbf{Pythia} (2.8B, 1B) \\cite{pythia}, \\textbf{OLMo} (OLMo-2-1B) \\cite{olmo}, \\textbf{Qwen} (Qwen3-1.7B, Qwen3-0.6B, Qwen3-8B-Base) \\cite{qwen3}, \\textbf{Llama} (Llama-3.2-3B) \\cite{llama3}, and \\textbf{Mistral} (Mistral-7B-v0.3) \\cite{mistral7b}.\nThis selection covers parameter scales from 0.6B to 8B and diverse pretraining corpora, which enables evaluation of cross-generator and cross-scale generalization.\n\nFor each generator, we sample approximately 1{,}000 seed passages from English Wikipedia as $\\mathcal{C}_0$.\nThe same pool of seed passages serves as gen-0 for all generators.\nWe use shared seeds across generators to ensure that cross-generator comparisons control for input content, which isolates the effect of the generation model from source text variation.\nIn LOGO evaluation, gen-0 samples from the held-out generator's chains also appear (with the same text) in the training generators' chains, creating a potential train--test overlap for the gen-0 class.\nWe address this with a supplementary binary evaluation excluding gen-0 entirely (\\S\\ref{sec:results-baselines}).\nEach seed is iteratively fed through the generator to produce a chain of depth 4 (i.e., gen-0 through gen-4), using the prompt ``\\texttt{Continue the following text: \\{text\\}}''.\nAll generation uses temperature $\\tau{=}0.7$, nucleus sampling with $p{=}0.9$, and maximum length of 256 new tokens.\nThe theoretical yield is $8 \\times {\\sim}1{,}000 \\times 5 = 39{,}815$ texts; after removing 2{,}746 chain breaks (empty or degenerate outputs at intermediate depths that prevented deeper generation) and 11 passages too short for feature extraction, 37{,}058 texts remain (Appendix~\\ref{app:dataset-stats}).\nFor classification, depths 2--4 are collapsed into the $2{+}$ class.\n\n\\subsection{Feature Extraction}\n\\label{sec:features}\n\nThe seven features are motivated by two complementary views of distributional drift.\nReference-model features capture how the text's token-level surprise distribution shifts relative to a fixed model; surface features capture how lexical diversity contracts under recursive generation.\nTogether, they span both the generative mechanism (what the model produces) and the surface manifestation (how the vocabulary changes); Figure~\\ref{fig:framework} provides an overview.\nThis two-pronged design is validated through leave-one-feature-out analysis (Appendix~\\ref{app:lofo}) and cross-group ablation (\\S\\ref{sec:results-differential}), which confirms that both feature groups contribute to depth discrimination.\n\nWe extract seven distributional features per text, organized into two groups based on what they measure rather than how they are computed.\n\n\\paragraph{Reference-model features.}\nA held-out reference model (Pythia-410M, chosen to be smaller than all generators) computes per-token negative log-likelihood (NLL) for each text.\nWe use ``entropy'' as shorthand for token-level NLL throughout, following convention in prior detection work; these are point-wise NLL values, not Shannon entropy of the full distribution.\nAlthough Pythia-410M shares the GPT-NeoX architecture with two of the eight generators, cross-family reference model experiments (\\S\\ref{sec:results-differential}) confirm that depth features are not reference-specific (LOGO F1 varies by $\\leq$0.013 across Pythia, OLMo, and Qwen references).\nFrom the resulting NLL sequence, we extract five statistics:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{entropy\\_mean}: mean token-level NLL, which captures the average predictability of the text under the reference model;\n    \\item \\textbf{entropy\\_std}: standard deviation of token-level NLL, which measures the spread of per-token surprise;\n    \\item \\textbf{entropy\\_max}: maximum token-level NLL, which captures the most surprising token;\n    \\item \\textbf{entropy\\_min}: minimum token-level NLL, which captures the most predictable token. As generation depth increases, the floor of token-level surprise drops; this reflects the model's increasing confidence on its own outputs.\n    Retained because removing it does not improve performance (LOFO $\\Delta$F1\\,=\\,+0.01\\,pp, within bootstrap noise) and it completes the four-number NLL summary (mean, std, max, min), which ensures the classifier has access to the full marginal distribution shape;\n    \\item \\textbf{tail\\_decay}: slope of the vocabulary-level averaged log-probability distribution in the mid-rank region (ranks 100--1000).\n    For each text, we compute the mean log-probability of each vocabulary token across all positions under the reference model, sort tokens in descending order of mean log-probability, and fit a linear regression to ranks 100--1000.\n    The slope captures how steeply the reference model's probability mass decays beyond high-probability tokens and characterizes the shape of the distribution tail.\n    We select ranks 100--1000 because high-frequency tokens (ranks $<$ 100) exhibit minimal discriminative variance across depths, while ranks beyond 1000 are sparsely populated and noisy.\n\\end{itemize}\n\n\\paragraph{Surface features.}\nTwo features capture lexical diversity without requiring a reference model:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{TTR}: type-token ratio (number of unique word types divided by total tokens);\n    \\item \\textbf{hapax\\_ratio}: proportion of words appearing exactly once (\\emph{hapax legomena}).\n\\end{itemize}\n\n\\paragraph{Feature complementarity.}\nThe grouping reflects an empirical pattern we term \\emph{differential depth response}: central-tendency and diversity features (entropy\\_mean, TTR, hapax\\_ratio) show substantial monotonic drift with generation depth ($|\\rho| = 0.60$--$0.63$); entropy\\_min and entropy\\_std show moderate drift ($|\\rho| = 0.17$--$0.41$); and shape features (entropy\\_max, tail\\_decay) remain near-stationary ($|\\rho| < 0.10$).\nThis differential behavior, consistent with recursive generation shifting the location of the NLL distribution while approximately preserving distributional shape, motivates combining both feature types.\nAs shown in \\S\\ref{sec:results}, the full 7-feature set significantly outperforms either group alone.\n\n\\subsection{Evaluation Protocol}\n\\label{sec:evaluation}\n\n\\paragraph{Cross-validation.}\nTo evaluate generalization to unseen generators, we use \\textbf{Leave-One-Generator-Out (LOGO)} cross-validation over all eight generators; \\textbf{Leave-One-Family-Out (LOFO)} holds out entire model families.\nCross-model chains use the original five-generator subset (Pythia-2.8B/1B, OLMo-2-1B, Qwen3-1.7B/0.6B); Llama and Mistral were added subsequently for single-generator LOGO only.\nSome appendix analyses predate this expansion and use six generators (the original five plus Qwen3-8B); each table notes its generator subset.\n\n\\paragraph{Classifier.}\nWe use XGBoost \\cite{xgboost} throughout ($n\\_\\text{estimators}{=}200$, $\\max\\_\\text{depth}{=}6$, learning rate $0.1$), with identical hyperparameters across all methods in Table~\\ref{tab:baselines}.\nLOGO F1 is stable across random seeds (std\\,$<$\\,0.001 over 5 seeds).\nAlternative classifiers and ordinal-specific methods (CORAL \\cite{coral_ordinal}, Frank-Hall \\cite{frank_hall_ordinal}) yield comparable performance (Appendix~\\ref{app:classifier}), which confirms that discriminative power resides in the features.\n\n\\paragraph{Metrics and statistical testing.}\nThe primary metric is \\textbf{macro-averaged F1} over the three depth classes.\nWe report 95\\% confidence intervals via percentile bootstrap ($n{=}1{,}000$), McNemar tests for pairwise comparisons, and paired bootstrap for baseline comparisons.\nAll $p$-values are two-sided; Bonferroni correction is applied within each family of simultaneous tests: the 21 distributional comparisons (7 features $\\times$ 3 depth-group pairs, \\S\\ref{sec:results-differential}) and the 4 pairwise baseline comparisons (\\S\\ref{sec:results-baselines}).\nFeature--depth correlations (\\S\\ref{sec:results-differential}) use class-balanced subsamples to control for depth-class imbalance.\n\n\\paragraph{Baselines.}\nWe compare the 7-feature ensemble against four single-score detection methods repurposed as depth predictors: Avg-LogProb, FastDetectGPT \\cite{fast_detectgpt}, Binoculars \\cite{binoculars}, and LD-Score \\cite{ld_score}.\nEach baseline score is used as a univariate feature in the same XGBoost framework under LOGO cross-validation, ensuring a controlled comparison.\n\n\\paragraph{Length confound control.}\nSince TTR and hapax\\_ratio are mechanically length-dependent, we verify depth signal is not a length artifact via length-matched subsampling that equalizes length distributions across depth classes (\\S\\ref{sec:results-classification}; Appendix~\\ref{app:length}).\n",
    "structuredPatch": [
      {
        "oldStart": 93,
        "oldLines": 7,
        "newStart": 93,
        "newLines": 7,
        "lines": [
          " ",
          " \\paragraph{Baselines.}",
          " We compare the 7-feature ensemble against four single-score detection methods repurposed as depth predictors: Avg-LogProb, FastDetectGPT \\cite{fast_detectgpt}, Binoculars \\cite{binoculars}, and LD-Score \\cite{ld_score}.",
          "-Each baseline score is used as a univariate feature in the same XGBoost framework under LOGO cross-validation, ensuring a controlled comparison.",
          "+Each baseline score is used as a univariate feature in the same XGBoost framework under LOGO cross-validation to ensure a controlled comparison.",
          " ",
          " \\paragraph{Length confound control.}",
          " Since TTR and hapax\\_ratio are mechanically length-dependent, we verify depth signal is not a length artifact via length-matched subsampling that equalizes length distributions across depth classes (\\S\\ref{sec:results-classification}; Appendix~\\ref{app:length})."
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

_source line 133_

**Batch 4**: Appendix files (part 1).

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "03414307-7b22-45bf-b4d4-9f7b4785486a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013q18Aghms1EWZEu26keWFv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 77674,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 77674
      },
      "output_tokens": 7,
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

_source line 134_

<details open><summary>🔧 Tool call — Edit · `toolu_01QUBCayAFNGnaXPxCWWA7gN`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_prompt_type.tex",
  "old_string": "F1\\,=\\,0.753, confirming that depth signal transfers across prompt types.",
  "new_string": "F1\\,=\\,0.753, which confirms that depth signal transfers across prompt types."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "1fce49a1-a6f2-4970-aec3-eb743df0b3c0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013q18Aghms1EWZEu26keWFv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 77674,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 77674
      },
      "output_tokens": 7,
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

_source line 135 · 2026-05-17T19:57:58.719Z_

<details><summary>↩ Tool result · `toolu_01QUBCayAFNGnaXPxCWWA7gN`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_prompt_type.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "7eb2f78a-aabb-404d-80f0-e9773a60d342",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_prompt_type.tex",
    "oldString": "F1\\,=\\,0.753, confirming that depth signal transfers across prompt types.",
    "newString": "F1\\,=\\,0.753, which confirms that depth signal transfers across prompt types.",
    "originalFile": "We evaluate depth fingerprinting under three prompt types using Pythia-2.8B: \\emph{continuation} (``Continue the following text''), \\emph{elaboration} (``Elaborate on the following text''), and \\emph{inspired rewriting} (``Write a new passage inspired by the following text''). Each uses 995 seeds $\\times$ 5 depths.\n\n\\paragraph{Within-prompt-type classification.}\n5-fold CV macro-F1: continuation 0.78, rewriting 0.74, elaboration 0.73. All three prompt types exhibit the same differential depth response pattern: drifting features (hapax ratio, TTR, entropy mean) show consistent monotonic trends, while stationary features (entropy std, tail decay) change by less than 5\\%.\n\n\\paragraph{Cross-prompt-type transfer (LOPTO).}\nLeave-one-prompt-type-out evaluation yields average F1\\,=\\,0.753, confirming that depth signal transfers across prompt types. Feature decay rates differ: continuation shows the strongest drift (16.9\\% per depth step), followed by rewriting (6.1\\%) and elaboration (1.4\\%), consistent with continuation chains applying less semantic constraint on the output.\n",
    "structuredPatch": [
      {
        "oldStart": 4,
        "oldLines": 4,
        "newStart": 4,
        "newLines": 4,
        "lines": [
          " 5-fold CV macro-F1: continuation 0.78, rewriting 0.74, elaboration 0.73. All three prompt types exhibit the same differential depth response pattern: drifting features (hapax ratio, TTR, entropy mean) show consistent monotonic trends, while stationary features (entropy std, tail decay) change by less than 5\\%.",
          " ",
          " \\paragraph{Cross-prompt-type transfer (LOPTO).}",
          "-Leave-one-prompt-type-out evaluation yields average F1\\,=\\,0.753, confirming that depth signal transfers across prompt types. Feature decay rates differ: continuation shows the strongest drift (16.9\\% per depth step), followed by rewriting (6.1\\%) and elaboration (1.4\\%), consistent with continuation chains applying less semantic constraint on the output.",
          "+Leave-one-prompt-type-out evaluation yields average F1\\,=\\,0.753, which confirms that depth signal transfers across prompt types. Feature decay rates differ: continuation shows the strongest drift (16.9\\% per depth step), followed by rewriting (6.1\\%) and elaboration (1.4\\%), consistent with continuation chains applying less semantic constraint on the output."
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

_source line 136_

<details open><summary>🔧 Tool call — Edit · `toolu_01B5Xq6KmjFQdp5yjrkSGsYE`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_qlora.tex",
  "old_string": "($\\pm$0.004), confirming stability across hyperparameter and seed variation",
  "new_string": "($\\pm$0.004), which confirms stability across hyperparameter and seed variation"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "dde67178-1092-4b4a-aa29-25f5f4a407c1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013q18Aghms1EWZEu26keWFv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 77674,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 77674
      },
      "output_tokens": 7,
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

_source line 137 · 2026-05-17T19:58:00.662Z_

<details><summary>↩ Tool result · `toolu_01B5Xq6KmjFQdp5yjrkSGsYE`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_qlora.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "3097de9f-3311-4af1-9ac8-3e7a5d727089",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_qlora.tex",
    "oldString": "($\\pm$0.004), confirming stability across hyperparameter and seed variation",
    "newString": "($\\pm$0.004), which confirms stability across hyperparameter and seed variation",
    "originalFile": "To assess whether depth signal extends beyond handcrafted features, we fine-tune a pretrained language model end-to-end as a depth classifier using QLoRA \\cite{qlora}.\n\n\\paragraph{Setup.}\nWe fine-tune Qwen3-0.6B-Base with LoRA rank 16, learning rate $2 \\times 10^{-4}$, and 3 epochs, framing depth estimation as 5-class sequence classification (gen-0 through gen-4).\\footnote{Evaluated on the original 6-generator subset; XGBoost 3-class F1\\,=\\,0.789. We expect 8-generator training to further improve given additional diversity; the comparison direction is preserved.}\nFor 3-class evaluation, we collapse predictions into gen-0\\,/\\,gen-1\\,/\\,gen-2+ post hoc.\nAll results use the same LOGO protocol as the main experiments.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{QLoRA end-to-end depth classification vs.\\ XGBoost on handcrafted features, under LOGO evaluation.}\n\\label{tab:qlora}\n\\resizebox{\\linewidth}{!}{%\n\\begin{tabular}{lccc}\n\\toprule\n\\textbf{Method} & \\textbf{5-class F1} & \\textbf{3-class F1} & \\textbf{Per-class F1 (5-class)} \\\\\n\\midrule\nXGBoost (7 features) & 0.501 $\\pm$ 0.038 & 0.789 & --- \\\\\nQLoRA (Qwen3-0.6B)   & 0.583 $\\pm$ 0.010 & 0.905 $\\pm$ 0.003 & 0.999\\,/\\,0.796\\,/\\,0.413\\,/\\,0.259\\,/\\,0.447 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Results.}\nQLoRA achieves 3-class LOGO F1\\,=\\,0.905 ($\\pm$0.003), a +11.6\\,pp improvement over the XGBoost baseline (0.789).\nOn 5-class evaluation, QLoRA reaches F1\\,=\\,0.583 ($\\pm$0.010) vs.\\ 0.501 for XGBoost (+8.2\\,pp), with the largest gains at gen-1 (0.796 vs.\\ 0.634) and gen-2 (0.413 vs.\\ 0.268).\nThe gen-2/gen-3 boundary remains the primary failure mode (gen-3 F1\\,=\\,0.259), consistent with the feature-level analysis in \\S\\ref{sec:discussion}.\n\n\\paragraph{Hyperparameter robustness.}\nA second run with LoRA rank 32 and seed 123 yields 5-class F1\\,=\\,0.587 ($\\pm$0.005) and 3-class F1\\,=\\,0.905 ($\\pm$0.004), confirming stability across hyperparameter and seed variation ($\\Delta < 1$\\,pp on both metrics).\n\n\\paragraph{Implications.}\nThe substantial 3-class improvement demonstrates that raw token embeddings contain depth signal beyond what summary statistics capture; the seven handcrafted features are a strong but lossy compression of the full distributional information.\nEnd-to-end fine-tuning exploits token-level patterns (e.g., positional regularities, n-gram repetitions) that aggregate features cannot represent.\nThis confirms that the depth signal documented in our main analysis is real and exploitable beyond engineered features, while the handcrafted approach retains practical advantages: interpretability, computational efficiency (no GPU inference), and the ability to reveal the differential depth response pattern that motivates the task formulation.\n",
    "structuredPatch": [
      {
        "oldStart": 27,
        "oldLines": 7,
        "newStart": 27,
        "newLines": 7,
        "lines": [
          " The gen-2/gen-3 boundary remains the primary failure mode (gen-3 F1\\,=\\,0.259), consistent with the feature-level analysis in \\S\\ref{sec:discussion}.",
          " ",
          " \\paragraph{Hyperparameter robustness.}",
          "-A second run with LoRA rank 32 and seed 123 yields 5-class F1\\,=\\,0.587 ($\\pm$0.005) and 3-class F1\\,=\\,0.905 ($\\pm$0.004), confirming stability across hyperparameter and seed variation ($\\Delta < 1$\\,pp on both metrics).",
          "+A second run with LoRA rank 32 and seed 123 yields 5-class F1\\,=\\,0.587 ($\\pm$0.005) and 3-class F1\\,=\\,0.905 ($\\pm$0.004), which confirms stability across hyperparameter and seed variation ($\\Delta < 1$\\,pp on both metrics).",
          " ",
          " \\paragraph{Implications.}",
          " The substantial 3-class improvement demonstrates that raw token embeddings contain depth signal beyond what summary statistics capture; the seven handcrafted features are a strong but lossy compression of the full distributional information."
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

_source line 138_

<details open><summary>🔧 Tool call — Edit · `toolu_011zFMo3gjfzuGvT6Zc1zQ5K`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_cross_temp.tex",
  "old_string": "while other generators remain stable, indicating the temperature mismatch disproportionately affects the generator whose data was regenerated.}",
  "new_string": "while other generators remain stable. The temperature mismatch disproportionately affects the generator whose data was regenerated.}"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "631e566d-8bcd-418a-a190-8976fda30649",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013q18Aghms1EWZEu26keWFv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 77674,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 77674
      },
      "output_tokens": 7,
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

_source line 139 · 2026-05-17T19:58:02.578Z_

<details><summary>↩ Tool result · `toolu_011zFMo3gjfzuGvT6Zc1zQ5K`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_cross_temp.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "921c36f3-6b0f-4520-a690-cbc9c0cce679",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_cross_temp.tex",
    "oldString": "while other generators remain stable, indicating the temperature mismatch disproportionately affects the generator whose data was regenerated.}",
    "newString": "while other generators remain stable. The temperature mismatch disproportionately affects the generator whose data was regenerated.}",
    "originalFile": "Figure~\\ref{fig:cross-temp} shows cross-temperature transfer results for the 6-generator LOGO pipeline.\nWe evaluate four train$\\rightarrow$test temperature conditions using Qwen3-1.7B data regenerated at $t{=}1.0$ (remaining five generators retain $t{=}0.7$).\n\n\\begin{figure*}[ht]\n\\centering\n\\includegraphics[width=\\textwidth]{fig_appendix_cross_temp.pdf}\n\\caption{Cross-temperature transfer evaluation (6-gen LOGO). (a) Overall F1 by train$\\rightarrow$test temperature condition. Matched conditions (0.7$\\rightarrow$0.7, 1.0$\\rightarrow$1.0) outperform cross-temperature transfer, with 0.7$\\rightarrow$1.0 showing the largest degradation ($-6.6$\\,pp in 3-class F1). (b) Per-generator 3-class F1 heatmap: Qwen3-1.7B shows dramatic degradation under cross-temperature conditions (0.418) while other generators remain stable, indicating the temperature mismatch disproportionately affects the generator whose data was regenerated.}\n\\label{fig:cross-temp}\n\\end{figure*}\n\nKey observations from the cross-temperature analysis:\n\n\\begin{enumerate}[nosep]\n\\item \\textbf{Matched-temperature robustness}: Both $t{=}0.7$ and $t{=}1.0$ matched conditions yield comparable performance (3-class F1: 0.789 vs.\\ 0.726), with the gap attributable to weaker depth signal at high temperature rather than classifier degradation.\n\n\\item \\textbf{Asymmetric transfer}: Training at $t{=}1.0$ and testing at $t{=}0.7$ (F1\\,=\\,0.791) transfers well, but the reverse (0.7$\\rightarrow$1.0, F1\\,=\\,0.723) degrades. This asymmetry reflects the information structure: features learned from high-variance (high-temperature) data generalize to low-variance settings, but not vice versa.\n\n\\item \\textbf{Generator-specific vulnerability}: Qwen3-1.7B, the only generator with temperature-mismatched test data, drops to F1\\,=\\,0.418 under cross-temperature conditions while all other generators maintain F1 $>$ 0.76. This confirms that depth features are calibrated to the specific decoding regime.\n\n\\item \\textbf{Binary robustness}: Binary classification (gen-0/1 vs.\\ gen-2+) is more robust to temperature mismatch (0.900--0.958 across all conditions) than 3-class, suggesting the coarser gen-0 vs.\\ machine boundary is less sensitive to decoding parameters than fine-grained depth discrimination.\n\\end{enumerate}\n",
    "structuredPatch": [
      {
        "oldStart": 4,
        "oldLines": 7,
        "newStart": 4,
        "newLines": 7,
        "lines": [
          " \\begin{figure*}[ht]",
          " \\centering",
          " \\includegraphics[width=\\textwidth]{fig_appendix_cross_temp.pdf}",
          "-\\caption{Cross-temperature transfer evaluation (6-gen LOGO). (a) Overall F1 by train$\\rightarrow$test temperature condition. Matched conditions (0.7$\\rightarrow$0.7, 1.0$\\rightarrow$1.0) outperform cross-temperature transfer, with 0.7$\\rightarrow$1.0 showing the largest degradation ($-6.6$\\,pp in 3-class F1). (b) Per-generator 3-class F1 heatmap: Qwen3-1.7B shows dramatic degradation under cross-temperature conditions (0.418) while other generators remain stable, indicating the temperature mismatch disproportionately affects the generator whose data was regenerated.}",
          "+\\caption{Cross-temperature transfer evaluation (6-gen LOGO). (a) Overall F1 by train$\\rightarrow$test temperature condition. Matched conditions (0.7$\\rightarrow$0.7, 1.0$\\rightarrow$1.0) outperform cross-temperature transfer, with 0.7$\\rightarrow$1.0 showing the largest degradation ($-6.6$\\,pp in 3-class F1). (b) Per-generator 3-class F1 heatmap: Qwen3-1.7B shows dramatic degradation under cross-temperature conditions (0.418) while other generators remain stable. The temperature mismatch disproportionately affects the generator whose data was regenerated.}",
          " \\label{fig:cross-temp}",
          " \\end{figure*}",
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


### Tool call

_source line 140_

<details open><summary>🔧 Tool call — Edit · `toolu_016RciAjAGcgnF4f7eaGFQ3E`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_cross_temp.tex",
  "old_string": ") than 3-class, suggesting the coarser gen-0 vs.\\ machine boundary is less sensitive to decoding parameters than fine-grained depth discrimination.",
  "new_string": ") than 3-class. The coarser gen-0 vs.\\ machine boundary appears less sensitive to decoding parameters than fine-grained depth discrimination."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "d8539dae-cea4-4fbb-aa8a-c8dc800bb1ee",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013q18Aghms1EWZEu26keWFv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 77674,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 77674
      },
      "output_tokens": 7,
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

_source line 141 · 2026-05-17T19:58:05.394Z_

<details><summary>↩ Tool result · `toolu_016RciAjAGcgnF4f7eaGFQ3E`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_cross_temp.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "46feb7d4-e655-4448-8d8c-1e99f6e321ac",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_cross_temp.tex",
    "oldString": ") than 3-class, suggesting the coarser gen-0 vs.\\ machine boundary is less sensitive to decoding parameters than fine-grained depth discrimination.",
    "newString": ") than 3-class. The coarser gen-0 vs.\\ machine boundary appears less sensitive to decoding parameters than fine-grained depth discrimination.",
    "originalFile": "Figure~\\ref{fig:cross-temp} shows cross-temperature transfer results for the 6-generator LOGO pipeline.\nWe evaluate four train$\\rightarrow$test temperature conditions using Qwen3-1.7B data regenerated at $t{=}1.0$ (remaining five generators retain $t{=}0.7$).\n\n\\begin{figure*}[ht]\n\\centering\n\\includegraphics[width=\\textwidth]{fig_appendix_cross_temp.pdf}\n\\caption{Cross-temperature transfer evaluation (6-gen LOGO). (a) Overall F1 by train$\\rightarrow$test temperature condition. Matched conditions (0.7$\\rightarrow$0.7, 1.0$\\rightarrow$1.0) outperform cross-temperature transfer, with 0.7$\\rightarrow$1.0 showing the largest degradation ($-6.6$\\,pp in 3-class F1). (b) Per-generator 3-class F1 heatmap: Qwen3-1.7B shows dramatic degradation under cross-temperature conditions (0.418) while other generators remain stable. The temperature mismatch disproportionately affects the generator whose data was regenerated.}\n\\label{fig:cross-temp}\n\\end{figure*}\n\nKey observations from the cross-temperature analysis:\n\n\\begin{enumerate}[nosep]\n\\item \\textbf{Matched-temperature robustness}: Both $t{=}0.7$ and $t{=}1.0$ matched conditions yield comparable performance (3-class F1: 0.789 vs.\\ 0.726), with the gap attributable to weaker depth signal at high temperature rather than classifier degradation.\n\n\\item \\textbf{Asymmetric transfer}: Training at $t{=}1.0$ and testing at $t{=}0.7$ (F1\\,=\\,0.791) transfers well, but the reverse (0.7$\\rightarrow$1.0, F1\\,=\\,0.723) degrades. This asymmetry reflects the information structure: features learned from high-variance (high-temperature) data generalize to low-variance settings, but not vice versa.\n\n\\item \\textbf{Generator-specific vulnerability}: Qwen3-1.7B, the only generator with temperature-mismatched test data, drops to F1\\,=\\,0.418 under cross-temperature conditions while all other generators maintain F1 $>$ 0.76. This confirms that depth features are calibrated to the specific decoding regime.\n\n\\item \\textbf{Binary robustness}: Binary classification (gen-0/1 vs.\\ gen-2+) is more robust to temperature mismatch (0.900--0.958 across all conditions) than 3-class, suggesting the coarser gen-0 vs.\\ machine boundary is less sensitive to decoding parameters than fine-grained depth discrimination.\n\\end{enumerate}\n",
    "structuredPatch": [
      {
        "oldStart": 17,
        "oldLines": 5,
        "newStart": 17,
        "newLines": 5,
        "lines": [
          " ",
          " \\item \\textbf{Generator-specific vulnerability}: Qwen3-1.7B, the only generator with temperature-mismatched test data, drops to F1\\,=\\,0.418 under cross-temperature conditions while all other generators maintain F1 $>$ 0.76. This confirms that depth features are calibrated to the specific decoding regime.",
          " ",
          "-\\item \\textbf{Binary robustness}: Binary classification (gen-0/1 vs.\\ gen-2+) is more robust to temperature mismatch (0.900--0.958 across all conditions) than 3-class, suggesting the coarser gen-0 vs.\\ machine boundary is less sensitive to decoding parameters than fine-grained depth discrimination.",
          "+\\item \\textbf{Binary robustness}: Binary classification (gen-0/1 vs.\\ gen-2+) is more robust to temperature mismatch (0.900--0.958 across all conditions) than 3-class. The coarser gen-0 vs.\\ machine boundary appears less sensitive to decoding parameters than fine-grained depth discrimination.",
          " \\end{enumerate}"
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

_source line 142_

<details open><summary>🔧 Tool call — Edit · `toolu_018mgcV32s4sWyW63cqMyrkQ`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_confusion_matrix.tex",
  "old_string": "as gen-0 (6.2\\%), indicating that gen-1 text already carries detectable recursive distortion.}",
  "new_string": "as gen-0 (6.2\\%). Gen-1 text already carries detectable recursive distortion.}"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "11596cd2-5a73-431a-b6af-34d917bf4e1c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013q18Aghms1EWZEu26keWFv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 77674,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 77674
      },
      "output_tokens": 7,
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

_source line 143 · 2026-05-17T19:58:07.709Z_

<details><summary>↩ Tool result · `toolu_018mgcV32s4sWyW63cqMyrkQ`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_confusion_matrix.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "1af3ef31-51ef-4c65-8f76-b14bbd16a70d",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_confusion_matrix.tex",
    "oldString": "as gen-0 (6.2\\%), indicating that gen-1 text already carries detectable recursive distortion.}",
    "newString": "as gen-0 (6.2\\%). Gen-1 text already carries detectable recursive distortion.}",
    "originalFile": "Table~\\ref{tab:confusion} reports the aggregated confusion matrix from the original six-generator subset (Pythia-2.8B, Pythia-1B, OLMo-2-1B, Qwen3-1.7B, Qwen3-0.6B, Qwen3-8B) under leave-one-generator-out (LOGO) evaluation, collapsed to three ordinal classes: gen-0 (human), gen-1 (first-generation), and gen-2+ (depth $\\geq$ 2).\nThe later-added Llama-3.2-3B and Mistral-7B-v0.3 are evaluated in the full 8-generator LOGO results (Table~\\ref{tab:logo-results}).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\linewidth}{!}{%\n\\begin{tabular}{lccc}\n\\toprule\n& \\textbf{Pred gen-0} & \\textbf{Pred gen-1} & \\textbf{Pred gen-2+} \\\\\n\\midrule\n\\textbf{True gen-0} & 5{,}937 (99.4\\%) & 35 (0.6\\%) & 0 (0.0\\%) \\\\\n\\textbf{True gen-1} & 368 (6.2\\%) & 4{,}437 (75.0\\%) & 1{,}113 (18.8\\%) \\\\\n\\textbf{True gen-2+} & 464 (3.0\\%) & 3{,}646 (23.3\\%) & 11{,}529 (73.7\\%) \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Aggregated 3-class confusion matrix from 6-generator LOGO evaluation ($N=27{,}529$). Each cell shows count and row-normalized percentage. Gen-0 is near-perfectly identified. Gen-1 errors are asymmetric: misclassification as gen-2+ (18.8\\%) is 3$\\times$ more frequent than as gen-0 (6.2\\%), indicating that gen-1 text already carries detectable recursive distortion.}\n\\label{tab:confusion}\n\\end{table}\n\nFigure~\\ref{fig:confusion-heatmap} provides a heatmap visualization of the confusion matrix.\nThe row-normalized view highlights near-perfect gen-0 classification (99.4\\% recall), gen-1 confusion primarily with gen-2+ (18.8\\%) rather than gen-0 (6.2\\%), and gen-2+ misclassification predominantly into gen-1 (23.3\\%), consistent with DDR predictions.\n\n\\begin{figure*}[ht]\n\\centering\n\\includegraphics[width=0.85\\textwidth]{fig_appendix_confusion.pdf}\n\\caption{3-class LOGO confusion matrix ($N$\\,=\\,27{,}529). (a) Raw counts. (b) Row-normalized recall percentages. Gen-0 achieves near-perfect classification; the primary confusion axis is gen-1 $\\leftrightarrow$ gen-2+.}\n\\label{fig:confusion-heatmap}\n\\end{figure*}\n",
    "structuredPatch": [
      {
        "oldStart": 14,
        "oldLines": 7,
        "newStart": 14,
        "newLines": 7,
        "lines": [
          " \\textbf{True gen-2+} & 464 (3.0\\%) & 3{,}646 (23.3\\%) & 11{,}529 (73.7\\%) \\\\",
          " \\bottomrule",
          " \\end{tabular}}",
          "-\\caption{Aggregated 3-class confusion matrix from 6-generator LOGO evaluation ($N=27{,}529$). Each cell shows count and row-normalized percentage. Gen-0 is near-perfectly identified. Gen-1 errors are asymmetric: misclassification as gen-2+ (18.8\\%) is 3$\\times$ more frequent than as gen-0 (6.2\\%), indicating that gen-1 text already carries detectable recursive distortion.}",
          "+\\caption{Aggregated 3-class confusion matrix from 6-generator LOGO evaluation ($N=27{,}529$). Each cell shows count and row-normalized percentage. Gen-0 is near-perfectly identified. Gen-1 errors are asymmetric: misclassification as gen-2+ (18.8\\%) is 3$\\times$ more frequent than as gen-0 (6.2\\%). Gen-1 text already carries detectable recursive distortion.}",
          " \\label{tab:confusion}",
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


### Tool call

_source line 144_

<details open><summary>🔧 Tool call — Edit · `toolu_01M1pQZ3NbLtocu9uwY79rqE`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_downstream.tex",
  "old_string": "across all variants, confirming the robustness of this null result.",
  "new_string": "across all variants, which confirms the robustness of this null result."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "baa0a925-0513-4e10-b9d4-38788468fdc0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013q18Aghms1EWZEu26keWFv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 77674,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 77674
      },
      "output_tokens": 7,
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

_source line 145 · 2026-05-17T19:58:09.086Z_

<details><summary>↩ Tool result · `toolu_01M1pQZ3NbLtocu9uwY79rqE`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_downstream.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "b0916df6-6868-4812-87ac-d1daa6cbff11",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_downstream.tex",
    "oldString": "across all variants, confirming the robustness of this null result.",
    "newString": "across all variants, which confirms the robustness of this null result.",
    "originalFile": "Can depth-aware data curation improve downstream language model quality?\nWe fine-tune OLMo-2-0425-1B on five data variants (3 seeds each) and evaluate perplexity on a held-out test set (Table~\\ref{tab:downstream}).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{lrc}\n\\toprule\n\\textbf{Variant} & \\textbf{$n$} & \\textbf{Test PPL} \\\\\n\\midrule\nAll depths            & 12{,}299 & 2.335 $\\pm$ 0.000 \\\\\nSize-matched (random) & 3{,}951  & 2.367 $\\pm$ 0.000 \\\\\nDepth 0--1 only       & 3{,}951  & 2.387 $\\pm$ 0.001 \\\\\nBinary-filtered       & 3{,}951  & 2.389 $\\pm$ 0.000 \\\\\nDepth 0 only          & 797      & 2.681 $\\pm$ 0.001 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Downstream fine-tuning perplexity (OLMo-2-0425-1B, mean $\\pm$ std across 3 seeds). At equal sample count, random subsampling (2.367) outperforms depth-aware curation (depth 0--1: 2.387, binary-filtered: 2.389).}\n\\label{tab:downstream}\n\\end{table}\n\nThe results are unambiguous: data quantity dominates depth composition.\nTraining on all 12{,}299 samples yields the lowest perplexity (2.335).\nAt equal sample count ($n$\\,=\\,3{,}951), random subsampling (2.367) \\emph{outperforms} both depth-stratified selection (depth 0--1: 2.387) and binary detection filtering (2.389).\nCross-seed variance is below 0.002 across all variants, confirming the robustness of this null result.\n\nRestricting training to human-only text (depth 0, $n$\\,=\\,797) produces a sharp perplexity increase to 2.681, driven primarily by the 5$\\times$ reduction in data volume rather than depth composition per se.\n\n\\paragraph{Equivalence testing.}\nWe apply a two one-sided $t$-test (TOST) with a $\\pm$2\\% relative margin (equivalence bounds $\\pm$0.047 on the ppl scale) to formally assess whether the depth-aware and random subsampling conditions produce practically indistinguishable perplexity.\nAt equal sample count ($n$\\,=\\,3{,}951): size-matched (random) ppl\\,=\\,2.367 vs.\\ depth 0--1 ppl\\,=\\,2.387, $\\Delta$\\,=\\,0.020.\nTOST confirms equivalence ($p = 1.1 \\times 10^{-4}$), indicating the two curation strategies yield practically indistinguishable downstream quality within the $\\pm$2\\% margin.\nCross-seed standard deviation is below 0.001 for both variants.\n\nComparing the full dataset ($n$\\,=\\,12{,}299, ppl\\,=\\,2.335) against the depth-filtered subset ($n$\\,=\\,3{,}951, ppl\\,=\\,2.387): TOST \\emph{rejects} equivalence (minimum equivalence margin\\,=\\,0.053, exceeding the $\\pm$2\\% bound), confirming that data quantity drives perplexity reduction beyond what depth-aware selection can recover.\n\nKnowing the generation depth of a document does not, by itself, make it more or less useful for training; at fixed sample count, depth-aware curation is statistically equivalent to uninformed random subsampling.\n\n\\subsection*{Margin Sensitivity Analysis}\n\nTo assess the robustness of the equivalence conclusion to margin choice, we repeat the TOST procedure across multiple equivalence margins \\cite{lakens_equivalence}, following the recommendation to report sensitivity across plausible bounds rather than relying on a single threshold (Table~\\ref{tab:tost-margins}).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\linewidth}{!}{%\n\\begin{tabular}{llcc}\n\\toprule\n\\textbf{Comparison} & \\textbf{Margin} & \\textbf{Equiv?} & \\textbf{TOST $p$} \\\\\n\\midrule\nFull (12{,}299) vs.\\ Random (3{,}951) & $\\pm$1\\% & No & 1.0 \\\\\n                                        & $\\pm$2\\% & Yes & $1 \\times 10^{-6}$ \\\\\n                                        & $\\pm$3\\% & Yes & $< 10^{-10}$ \\\\\n                                        & $\\pm$5\\% & Yes & $< 10^{-10}$ \\\\\n\\midrule\nFull (12{,}299) vs.\\ Depth 0--1 (3{,}951) & $\\pm$1\\% & No & 1.0 \\\\\n                                            & $\\pm$2\\% & No & 1.0 \\\\\n                                            & $\\pm$3\\% & Yes & $< 10^{-10}$ \\\\\n                                            & $\\pm$5\\% & Yes & $< 10^{-10}$ \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{TOST equivalence testing across multiple margins. ``Equiv?'' indicates whether equivalence is established at $\\alpha = 0.05$.}\n\\label{tab:tost-margins}\n\\end{table}\n\nThe full dataset vs.\\ random subsample comparison passes equivalence at the $\\pm$2\\% margin ($p = 10^{-6}$), while the full vs.\\ depth 0--1 comparison requires a $\\pm$3\\% margin.\nIn absolute terms, perplexity differences are small: $\\Delta$\\,=\\,0.032 (full vs.\\ random, 1.4\\% of baseline) and $\\Delta$\\,=\\,0.052 (full vs.\\ depth 0--1, 2.2\\% of baseline).\n\nCohen's $d$ values are 86.0 (full vs.\\ random) and 119.7 (full vs.\\ depth 0--1).\nThese appear large but are unreliable: with only $n$\\,=\\,3 seeds per condition, the pooled standard deviation is extremely small ($<$0.001), artificially inflating $d$.\nThe inflated effect sizes reflect low seed-level variance (confirming reproducibility) rather than practically meaningful perplexity differences.\nThe TOST framework with pre-specified relative margins provides a more appropriate assessment than Cohen's $d$ in this low-seed regime.\n",
    "structuredPatch": [
      {
        "oldStart": 22,
        "oldLines": 7,
        "newStart": 22,
        "newLines": 7,
        "lines": [
          " The results are unambiguous: data quantity dominates depth composition.",
          " Training on all 12{,}299 samples yields the lowest perplexity (2.335).",
          " At equal sample count ($n$\\,=\\,3{,}951), random subsampling (2.367) \\emph{outperforms} both depth-stratified selection (depth 0--1: 2.387) and binary detection filtering (2.389).",
          "-Cross-seed variance is below 0.002 across all variants, confirming the robustness of this null result.",
          "+Cross-seed variance is below 0.002 across all variants, which confirms the robustness of this null result.",
          " ",
          " Restricting training to human-only text (depth 0, $n$\\,=\\,797) produces a sharp perplexity increase to 2.681, driven primarily by the 5$\\times$ reduction in data volume rather than depth composition per se.",
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


### Tool call

_source line 146_

<details open><summary>🔧 Tool call — Edit · `toolu_01GKSKVSgR5a5fPtaafPag4M`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_downstream.tex",
  "old_string": "10^{-4}$), indicating the two curation strategies yield practically indistinguishable downstream quality within the $\\pm$2\\% margin.",
  "new_string": "10^{-4}$); the two curation strategies yield practically indistinguishable downstream quality within the $\\pm$2\\% margin."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4bdb13b7-b460-45f7-96ee-c950b3a16070",
  "uuid": "10e5207a-8eec-4231-8b0c-e4a1a416c742",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013q18Aghms1EWZEu26keWFv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 77674,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 77674
      },
      "output_tokens": 7,
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
