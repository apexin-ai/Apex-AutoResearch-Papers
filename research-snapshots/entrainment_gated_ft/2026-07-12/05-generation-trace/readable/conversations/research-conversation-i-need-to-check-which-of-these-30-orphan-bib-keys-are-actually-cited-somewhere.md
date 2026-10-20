# Research conversation: I need to check which of these 30 "orphan" bib keys are actually cited somewhere in the paper's .tex files. The paper di

**Aggregate Equivalence̸=Behavioral Equivalence: Per-Example Multiplicity in Hybrid Linear Recurrent Models (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 20
- **Recorded user turns:** 1
- **Tool calls:** 6
- **Original source:** `logs/chats/exported-trajectories/account-3/agent-a5d47b67d0fecf656.jsonl`
- **Structured JSON:** [`3d03947417c3db6520eb.json`](../../sessions/3d/3d03947417c3db6520eb.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Round 1

20 recorded events

### User

_source line 1 · 2026-05-21T17:56:09.548Z_

I need to check which of these 30 "orphan" bib keys are actually cited somewhere in the paper's .tex files. The paper directory is /home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/docs/paper/

The orphan bib keys reported by consistency checker are:
ali2025hidden, arora2024based, arora2024zoology, basu2026routing, botev2024recurrentgemma, clark2018arc, damour2022underspecification, dao2024mamba2, de2024griffin, dong2024hymba, du2025reconciling, fehlauer2025convergence, gorbett2026crossmodel, gu2022s4, gu2024mamba, haghighat2026resolving, hsu2022rashomon, katharopoulos2020transformers, lahoti2026mamba3, lieber2024jamba, mccoy2020berts, paperno2016lambada, peng2024eagle, qin2024hgrn2, ren2024samba, sellam2022multiberts, sun2023retnet, waleffe2024empirical, watson2023predictive, yang2024gateddeltanet

Search ALL .tex files in the paper directory (main.tex, sections/*.tex, author_response.tex, arr_checklist.tex) for any \cite or \citep or \citet commands that reference these keys. For each key, report whether it's truly orphan (not cited anywhere) or actually used. Be thorough - search breadth "very thorough".

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": true,
  "promptId": "aeac6180-ae00-4058-bb9d-97b85fb92ee8",
  "agentId": "a5d47b67d0fecf656",
  "type": "user",
  "uuid": "db4ebe58-f403-4c22-842a-3ae840d16e6b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/.claude/sessions/director_63b8b789",
  "sessionId": "765154e5-66a9-4450-b7d7-710330a17dfd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 2 · 2026-05-21T17:56:11.345Z_

I'll search all .tex files in the paper directory for citations of these orphan bib keys. Let me start by exploring the directory structure and then systematically search for each key.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "db4ebe58-f403-4c22-842a-3ae840d16e6b",
  "isSidechain": true,
  "agentId": "a5d47b67d0fecf656",
  "requestId": "req_011CbG9N3oVMWaFLRNkGVXQQ",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "f53e591f-c1fa-4784-aff5-a2c1de4054d1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/.claude/sessions/director_63b8b789",
  "sessionId": "765154e5-66a9-4450-b7d7-710330a17dfd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_012okgNLmo6JcQBAv2xkb5Ky",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 39906,
      "cache_read_input_tokens": 0,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 39906,
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

_source line 3 · 2026-05-21T17:56:11.521Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01APxVctfcXWjgoqcFqHceCX`</summary>

```json
{
  "command": "find /home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/docs/paper -type f -name \"*.tex\" | head -20"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f53e591f-c1fa-4784-aff5-a2c1de4054d1",
  "isSidechain": true,
  "agentId": "a5d47b67d0fecf656",
  "requestId": "req_011CbG9N3oVMWaFLRNkGVXQQ",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "0066d7f3-a551-475e-87ce-a939ca4ac31a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/.claude/sessions/director_63b8b789",
  "sessionId": "765154e5-66a9-4450-b7d7-710330a17dfd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_012okgNLmo6JcQBAv2xkb5Ky",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 39906,
      "cache_read_input_tokens": 0,
      "output_tokens": 138,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 39906
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 138,
          "cache_read_input_tokens": 0,
          "cache_creation_input_tokens": 39906,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 39906,
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

_source line 4 · 2026-05-21T17:56:11.680Z_

<details><summary>↩ Tool result · `toolu_01APxVctfcXWjgoqcFqHceCX`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/docs/paper/arr_checklist.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/docs/paper/author_response.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/docs/paper/sections/introduction.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/docs/paper/sections/appendix.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/docs/paper/sections/method.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/docs/paper/sections/conclusion.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/docs/paper/sections/experiments.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/docs/paper/sections/related_work.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/docs/paper/main.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "0066d7f3-a551-475e-87ce-a939ca4ac31a",
  "isSidechain": true,
  "promptId": "aeac6180-ae00-4058-bb9d-97b85fb92ee8",
  "agentId": "a5d47b67d0fecf656",
  "type": "user",
  "uuid": "f9fb76b8-9ab0-4fbd-b307-dfd84040a1f7",
  "sourceToolAssistantUUID": "0066d7f3-a551-475e-87ce-a939ca4ac31a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/.claude/sessions/director_63b8b789",
  "sessionId": "765154e5-66a9-4450-b7d7-710330a17dfd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 5 · 2026-05-21T17:56:13.382Z_

Good! Now let me search for all citations of these orphan keys across all .tex files. I'll use grep to search for each key in citation commands.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f9fb76b8-9ab0-4fbd-b307-dfd84040a1f7",
  "isSidechain": true,
  "agentId": "a5d47b67d0fecf656",
  "requestId": "req_011CbG9NCsSjWmXWxuZsygrF",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "32bd43b4-dbb3-418a-8cb9-f2c646dfc7c0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/.claude/sessions/director_63b8b789",
  "sessionId": "765154e5-66a9-4450-b7d7-710330a17dfd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01Dwb3g8SLxSLZVscXkxwaVG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 5,
      "cache_creation_input_tokens": 1354,
      "cache_read_input_tokens": 39906,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1354,
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

_source line 6 · 2026-05-21T17:56:13.830Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01TaFSzjxshkNr62WQpkH32K`</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/docs/paper && grep -rE \"\\\\\\\\cite(p|t)?\\\\{[^}]*\\}\" --include=\"*.tex\" | head -100"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "32bd43b4-dbb3-418a-8cb9-f2c646dfc7c0",
  "isSidechain": true,
  "agentId": "a5d47b67d0fecf656",
  "requestId": "req_011CbG9NCsSjWmXWxuZsygrF",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "bd19dbde-3993-48b3-826e-7a5afdcf1845",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/.claude/sessions/director_63b8b789",
  "sessionId": "765154e5-66a9-4450-b7d7-710330a17dfd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01Dwb3g8SLxSLZVscXkxwaVG",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 5,
      "cache_creation_input_tokens": 1354,
      "cache_read_input_tokens": 39906,
      "output_tokens": 152,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 1354
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 5,
          "output_tokens": 152,
          "cache_read_input_tokens": 39906,
          "cache_creation_input_tokens": 1354,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 1354,
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

_source line 7 · 2026-05-21T17:56:13.896Z_

<details><summary>↩ Tool result · `toolu_01TaFSzjxshkNr62WQpkH32K`</summary>

```text
arr_checklist.tex:\textit{Yes. We cite the model zoo \citep{wang2025hybrid}, the evaluation framework \citep{gao2024lmeval}, and all individual architecture papers (GatedDeltaNet, RetNet, HGRN2).}
arr_checklist.tex:\textit{The model zoo of \citet{wang2025hybrid} is publicly released. The lm-evaluation-harness \citep{gao2024lmeval} is open-source (MIT license). We do not release new artifacts.}
arr_checklist.tex:\textit{Yes. We report model sizes (340M and 1.3B parameters) and the number of configurations evaluated (30 models $\times$ 11 benchmarks). All evaluation was inference-only using the pretrained checkpoints of \citet{wang2025hybrid}; no model training was performed. Inference was conducted on a single NVIDIA RTX PRO 6000 GPU with a total computational budget of approximately 5 GPU-hours.}
arr_checklist.tex:\textit{Yes. We report exact permutation tests, BCa bootstrap confidence intervals, Bonferroni and Benjamini--Hochberg corrections, effect sizes (Cohen's $d$, Jaccard similarity, normalized ES), and the ambiguity metric $\alpha$ of \citet{marx2020predictive}.}
sections/introduction.tex:This tension arises in the context of a rapid architectural shift toward hybrid recurrent-attention models, which interleave attention layers within linear recurrent backbones. Jamba \citep{lieber2024jamba}, Griffin \citep{de2024griffin}, RWKV-6 \citep{peng2024eagle}, and RecurrentGemma \citep{botev2024recurrentgemma} each combine recurrence with attention using different mixing strategies. These systems now serve as production-grade alternatives to pure Transformers, and the practical question of how much attention to include is typically answered by comparing aggregate benchmark numbers. \citet{wang2025hybrid} provide a controlled model zoo spanning three recurrent architectures, five attention ratios, and two parameter scales, which enables systematic study of how attention allocation affects these hybrid designs.
sections/introduction.tex:Most evaluations of hybrid architectures compare aggregate benchmark scores and report that a given attention ratio achieves a certain accuracy averaged across tasks or averaged across architectures. This practice can mask substantial per-example behavioral diversity. \citet{marx2020predictive} formalized this risk as predictive multiplicity: a prediction problem admits competing models with conflicting predictions on individual inputs. \citet{damour2022underspecification} documented a related phenomenon, underspecification, showing that models trained from the same pipeline with different random seeds can disagree on individual predictions despite equivalent aggregate performance. \citet{mccoy2020berts} demonstrated a concrete NLP instance: BERT models trained from different random seeds diverge on specific linguistic constructions. These studies examine variation from initialization or training noise within a single architecture. Whether predictive multiplicity extends to hybrid recurrent architectures, where the source of variation is the recurrent backbone itself, remains unquantified. The question matters because practitioners increasingly choose between recurrent backbones based on aggregate benchmarks; if architectures that score identically in aggregate behave differently on individual inputs, such choices carry hidden consequences for deployment reliability and ensemble construction.
sections/introduction.tex:We present the first systematic per-example analysis of how attention affects cross-architecture agreement in hybrid recurrent models. Using the model zoo of \citet{wang2025hybrid}, we compare three architectures (GatedDeltaNet, RetNet, HGRN2) at five attention ratios (0\% to 25\%) and two scales (340M and 1.3B parameters). These three architectures represent distinct approaches to linear recurrence: gated delta rules, multi-scale exponential decay, and gated state expansion. We evaluate all 30 configurations on 10 benchmarks spanning retrieval, comprehension, reasoning, and mixed task categories. On four benchmarks---LAMBADA ($N = 5{,}153$), HellaSwag ($N = 10{,}042$), PIQA ($N = 1{,}838$), and ARC-Easy ($N = 2{,}376$)---we conduct per-example decompositions, classifying each example as helped, hurt, or unchanged when attention is added, and measure cross-architecture overlap using Jaccard similarity. Figure~\ref{fig:decoupling} previews our central result: aggregate convergence and per-example divergence follow different trajectories as attention ratio increases.
sections/introduction.tex:Our analysis yields three findings. First, per-example predictive multiplicity varies in magnitude across tasks, forming a task-dependent spectrum. The ambiguity $\alpha$ \citep{marx2020predictive} ranges from 0.14 (PIQA) through 0.15 (HellaSwag) and 0.21 (ARC-Easy) to 0.30 (LAMBADA), while pairwise Jaccard remains uniformly low ($\leq 0.10$, all $p < .01$). Within each benchmark, $\alpha$ is stable across attention ratios (variation $< 0.03$), but differs substantially across task types, ranging from 0.14 (reasoning) to 0.30 (retrieval). Second, attention-driven aggregate convergence is task-specific. Of 10 benchmarks, only LAMBADA exhibits monotonic reduction in cross-architecture variance ($\rho = -1.0$, BCa 95\% CI $[-1.0,\,-0.7]$; cross-architecture $\sigma$ drops 79\%). LAMBADA \citep{paperno2016lambada} is a pure context-retrieval task that requires predicting the final word of a passage from long-range dependencies; attention provides direct token-level access to the full context, which offers a natural explanation for why convergence occurs on this task and not others. Benchmarks that involve reasoning or comprehension show no convergence, with all $|\rho| \leq 0.7$ and $p \geq .233$. The Bonferroni-adjusted $p = .100$ does not survive strict correction at $\alpha = 0.05$; the confidence interval, which excludes zero, provides a complementary characterization of the effect. This convergence is scale-dependent: monotonic at 1.3B but non-monotonic at 340M (Appendix~\ref{app:scale_convergence}). On LAMBADA, aggregate $\sigma$ decreases gradually ($0.024 \to 0.005$) while per-example Jaccard saturates at 4\% attention (${\sim}0.09$)---the two quantities are decoupled. The experiments that follow begin with convergence (\S\ref{ssec:task_convergence}) because it establishes the aggregate backdrop against which per-example divergence (\S\ref{ssec:per_example}) and decoupling (\S\ref{ssec:decoupling}) are measured.
sections/introduction.tex:    \item Unlike prior studies of seed-driven disagreement within a single architecture \citep{mccoy2020berts, damour2022underspecification}, we show that architectural variation---under matched training conditions---produces structured per-example predictive multiplicity with a task-dependent spectrum ($\alpha = 0.14$--$0.30$) across four benchmarks in three recurrent backbones. This multiplicity is not addressable by seed averaging: the source of variation is the recurrent backbone itself, and its magnitude is independent of aggregate convergence (\S\ref{ssec:per_example}, \S\ref{ssec:decoupling}, Table~\ref{tab:multiplicity}).
sections/appendix.tex:Several benchmarks show positive or near-zero $\rho$ (BoolQ: $+0.2$; ARC-C: $+0.6$; HellaSwag: $+0.4$; WinoGrande: $+0.1$; SciQ: $+0.1$), indicating that attention does not systematically reduce cross-architecture variance on reasoning or comprehension tasks. The contrast with LAMBADA is consistent with attention's convergence benefit being specific to tasks requiring direct token-level recall \citep{arora2024zoology,arora2024based} rather than multi-step inference.
sections/appendix.tex:In the \citet{wang2025hybrid} model zoo, the GDN h3-1 configuration at 1.3B scale uses 16 attention heads per attention layer, while all other hybrid configurations (across GDN, RetNet, and HGRN2) use 32 attention heads. This is a design choice in the original model zoo, not an error. The reduced head count changes the per-head dimension and may affect the attention capacity of GDN h3-1 relative to other configurations.
sections/appendix.tex:We extract attention weight matrices from the 1.3B h3-1 models of all three architectures using forward hooks on each attention layer. While \citet{ali2025hidden} show that SSM layers learn implicit attention patterns, our analysis focuses on the explicit attention layers interleaved within the hybrid architecture. For each layer, we compute the mean attention distribution across all 5{,}153 LAMBADA examples and measure cross-architecture similarity via cosine similarity.
sections/appendix.tex:Table~\ref{tab:arceasy_ambiguity} reports the ambiguity $\alpha$ \citep{marx2020predictive} at each attention ratio for all four main benchmarks. Within-benchmark ranges are 0.004 (HellaSwag), 0.011 (PIQA), 0.025 (ARC-Easy), and 0.022 (LAMBADA), all below the 0.03 threshold reported in \S\ref{ssec:per_example}.
sections/method.tex:We use the pretrained model zoo of \citet{wang2025hybrid}, which provides controlled comparisons across architectures and attention ratios. The zoo contains three linear recurrent architectures: GatedDeltaNet \citep{yang2024gateddeltanet}, RetNet \citep{sun2023retnet}, and HGRN2 \citep{qin2024hgrn2}. These three architectures represent distinct approaches to linear recurrence: GatedDeltaNet uses gated delta rules, RetNet uses multi-scale exponential decay, and HGRN2 uses gated linear recurrence with state expansion. Each architecture is trained at five attention ratios: 0\% (pure recurrent), 4\%, 7.7\%, 14.3\%, and 25\%. We adopt the h$k$-1 notation from the original work, where one attention layer is interleaved per every $k{+}1$ total layers: h3-1 corresponds to 25\% attention, h6-1 to 14.3\%, h12-1 to 7.7\%, and h24-1 to 4\%. All configurations are available at two scales: 340M and 1.3B parameters. Within each scale, all models share identical training data, tokenizer, and hyperparameters; they differ only in architecture and attention configuration. This controlled design isolates the effect of attention from confounds such as training data or optimization differences. The zoo also includes a Transformer baseline (pure attention) at both scales.
sections/method.tex:    \item \textbf{Retrieval}: LAMBADA \citep{paperno2016lambada}, which requires predicting a final word from long-range context without reasoning or world knowledge.
sections/method.tex:    \item \textbf{Reasoning}: HellaSwag, ARC-Challenge \citep{clark2018arc}, WinoGrande, and PIQA. COPA ($n = 100$) serves as a supplementary reasoning benchmark; its small sample size renders $\alpha$ estimation unreliable (CI width 0.13--0.18; Appendix~\ref{app:subsample_sensitivity}).
sections/method.tex:All evaluations use the lm-evaluation-harness framework \citep{gao2024lmeval} with default prompts; accuracy serves as the primary metric for all benchmarks.
sections/experiments.tex:We analyze how attention affects cross-architecture performance variance using models from the hybrid recurrent model zoo of \citet{wang2025hybrid}. Our analysis spans three architectures (GatedDeltaNet, RetNet, HGRN2), five attention ratios (0\% pure recurrent, 4\%, 7.7\%, 14.3\%, 25\%), and two scales (340M and 1.3B parameters). In the h$k$-1 notation used throughout, one attention layer is interleaved per every $k{+}1$ layers; h3-1 denotes 25\% attention. All models within each scale share identical training data and hyperparameters; they differ only in architecture and attention configuration. We evaluate on 10 benchmarks spanning retrieval, comprehension, reasoning, and mixed task categories, plus one supplementary benchmark (COPA, $n = 100$).
sections/experiments.tex:Table~\ref{tab:convergence} reports cross-architecture $\sigma$ at each attention ratio for all benchmarks at 1.3B scale. LAMBADA is the only benchmark exhibiting monotonic convergence: $\rho = -1.0$ ($p = .017$; BCa 95\% CI $[-1.0,\,-0.7]$; $\sigma$ drops 79\%; Bonferroni-adjusted $p = .100$). This is consistent with attention compensating for differences in how recurrent architectures retrieve from context \citep{arora2024zoology}---LAMBADA requires predicting a final word from long-range dependencies, and attention provides direct token-level access that narrows architectural differences in recall capacity \citep{arora2024based}. No other benchmark shows significant convergence (all $|\rho| \leq 0.7$, $p \geq .233$; Figure~\ref{fig:task_specificity}). Full convergence discussion appears in Appendix~\ref{app:convergence_detail}. Scale analysis (Appendix~\ref{app:scale_convergence}) shows this convergence is monotonic at 1.3B but non-monotonic at 340M.
sections/experiments.tex:No surface-level feature (token count, word frequency, syntactic complexity) reliably separates helped from hurt examples. However, pure-model confidence on the target token is strongly predictive within each architecture: hurt examples have lower target-token probability among pure-correct examples ($d = 0.83$--$0.92$), and helped examples have higher probability among pure-wrong examples ($d = 0.73$--$0.77$); see Appendix~\ref{app:confidence_margin}. A Kruskal-Wallis test confirms cross-architecture structure in both hurt ($p = .0005$) and helped ($p = .020$) distributions. The confidence margin thus identifies a per-example predictor of which examples will be affected: attention disrupts marginally correct predictions and rescues near-miss errors, but with architecture-specific thresholds that produce the observed cross-architecture divergence. The rescue pattern generalizes: across all three architectures on LAMBADA, HellaSwag, and ARC-Easy, helped examples have significantly higher pure-model target probability than stayed-wrong examples (9/9 tests, $d = 0.13$--$0.60$; Appendix~\ref{app:cm_cross}). The disruption pattern is weaker on ARC-Easy ($d = 0.13$--$0.26$), absent on HellaSwag under \texttt{acc\_norm}, and absent on binary classification (Appendix~\ref{app:boolq}), likely reflecting structural properties of constrained-choice formats that limit the discriminative power of confidence margins. This structured per-example disagreement despite similar aggregate performance constitutes predictive multiplicity \citep{marx2020predictive} arising from architectural variation rather than random initialization \citep{damour2022underspecification}.
sections/experiments.tex:\paragraph{Multiplicity spectrum.} Extending the per-example analysis to HellaSwag ($N = 10{,}042$) and PIQA ($N = 1{,}838$) reveals that predictive multiplicity varies systematically across tasks (Table~\ref{tab:multiplicity}). The ambiguity $\alpha$ \citep{marx2020predictive} ranges from 0.14 (PIQA) through 0.15 (HellaSwag) and 0.21 (ARC-Easy) to 0.30 (LAMBADA), forming a task-dependent spectrum. Evaluation format does not drive multiplicity: HellaSwag (four-way, $\alpha = 0.15$) and PIQA (two-choice, $\alpha = 0.14$) produce nearly identical multiplicity despite different formats; among two-choice benchmarks alone, $\alpha$ spans $3\times$ from 0.14 (PIQA) to 0.41 (WinoGrande; Appendix~\ref{app:winogrande}) to 0.45 (BoolQ; Appendix~\ref{app:boolq}), covering the full six-benchmark range within a single format. Bootstrap 95\% CIs confirm the spectrum ordering: all adjacent-benchmark CIs are non-overlapping except PIQA and HellaSwag, whose CIs overlap substantially ($[.127,\,.159]$ vs.\ $[.141,\,.155]$; Appendix, Table~\ref{tab:arceasy_ambiguity}). Moreover, $\alpha$ does not significantly correlate with task accuracy (Spearman $\rho = -0.60$, $p = .24$). Pairwise Jaccard remains uniformly low ($\bar{J} \leq 0.10$, all $p < .01$ across four benchmarks), indicating that architectures affect different examples regardless of how many examples are affected. Within each benchmark, $\alpha$ is stable across attention ratios (variation $< 0.03$), but differs $2\times$ across task types (from reasoning to retrieval), confirming that multiplicity magnitude depends on task, not attention dose \citep[cf.][]{gorbett2026crossmodel}.
sections/experiments.tex:\caption{Predictive multiplicity at 1.3B. $\alpha$: ambiguity at h3-1 \citep{marx2020predictive}. $\bar{J}$: mean pairwise Jaccard of helped~(h) and hurt~(u) sets, averaged across four hybrid attention ratios and three architecture pairs. $\rho_\alpha$: Spearman $\rho$ between attention ratio and $\alpha$. Benchmarks ordered by $\alpha$.}
sections/related_work.tex:The design space for combining attention with recurrence spans layer-level interleaving \citep[Jamba;][]{lieber2024jamba}, local attention pairing \citep[Griffin, RecurrentGemma;][]{de2024griffin,botev2024recurrentgemma}, matrix-valued recurrence \citep[RWKV-6;][]{peng2024eagle}, within-head mixing \citep[Hymba;][]{dong2024hymba}, and unbounded-context hybrid SSMs \citep[Samba;][]{ren2024samba}. Mamba-2 \citep{dao2024mamba2} establishes a duality between structured state spaces and attention; Mamba-3 \citep{lahoti2026mamba3} extends the design further, while \citet{ali2025hidden} reveal implicit attention within Mamba. Comparative evaluations confirm that hybrids outperform pure Transformers and SSMs at scale \citep{waleffe2024empirical}, and that even one attention layer enables content-based routing \citep{basu2026routing}. \citet{wang2025hybrid} provide the controlled model zoo we use, holding training conditions constant while varying architecture and attention ratio.
sections/related_work.tex:Our three recurrent backbones represent distinct gating strategies within the linear recurrence family: RetNet \citep{sun2023retnet} uses multi-scale exponential decay, HGRN2 \citep{qin2024hgrn2} applies gated state expansion, and GatedDeltaNet \citep{yang2024gateddeltanet} combines gated updates with delta rules. These descend from S4 \citep{gu2022s4} and Mamba \citep{gu2024mamba}, which introduced structured state spaces and input-dependent selection, respectively, and connect to linear attention \citep{katharopoulos2020transformers} through the state-space--attention duality of Mamba-2.
sections/related_work.tex:\citet{damour2022underspecification} formalized underspecification: equivalent aggregate performance can mask per-prediction divergence. Concrete NLP instances include seed-dependent BERT disagreement \citep{mccoy2020berts,sellam2022multiberts} and the four-phase convergence pattern of autoregressive LMs \citep{fehlauer2025convergence}. \citet{marx2020predictive} introduced predictive multiplicity as a complementary lens, showing that near-optimal models produce conflicting per-example predictions; extensions address probabilistic classification \citep{watson2023predictive}, Rashomon capacity \citep{hsu2022rashomon}, reconciliation \citep{du2025reconciling,haghighat2026resolving}, and cross-model disagreement as a correctness signal \citep{gorbett2026crossmodel}. These studies attribute divergence to initialization noise or the near-optimal set within a single architecture. We show that architectural variation in hybrid recurrent models produces analogous per-example multiplicity under matched training conditions.
main.tex:Hybrid recurrent architectures that interleave attention with linear recurrence are increasingly deployed, yet how attention affects per-example behavior across backbones remains unquantified. Using the controlled model zoo of \citet{wang2025hybrid}---three architectures, five attention ratios, two scales (340M/1.3B)---we evaluate 10 benchmarks and decompose per-example effects on four (LAMBADA, HellaSwag, PIQA, ARC-Easy). Per-example predictive multiplicity \citep{marx2020predictive} varies across tasks ($\alpha = 0.14$--$0.30$) while pairwise Jaccard of helped/hurt sets remains uniformly low ($\leq 0.10$); multiplicity magnitude depends on task type, not attention dose. Aggregate convergence, by contrast, is task-specific: only LAMBADA shows monotonic variance reduction (79\%), consistent with attention compensating for retrieval differences across recurrent backbones. On LAMBADA, aggregate variance decreases gradually while per-example overlap saturates at the first attention level---the two are decoupled.
main.tex:This work analyzes publicly available pretrained language models from the model zoo of \citet{wang2025hybrid}. No new data collection, human subjects research, or model training is involved. We identify per-example behavioral differences across architectures, which may inform practitioners about the limitations of aggregate benchmark comparisons but does not introduce new risks.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "bd19dbde-3993-48b3-826e-7a5afdcf1845",
  "isSidechain": true,
  "promptId": "aeac6180-ae00-4058-bb9d-97b85fb92ee8",
  "agentId": "a5d47b67d0fecf656",
  "type": "user",
  "uuid": "7a4ef4da-0106-4a34-afda-cc7b5806981e",
  "sourceToolAssistantUUID": "bd19dbde-3993-48b3-826e-7a5afdcf1845",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/.claude/sessions/director_63b8b789",
  "sessionId": "765154e5-66a9-4450-b7d7-710330a17dfd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 8 · 2026-05-21T17:56:15.282Z_

Now let me systematically search for each orphan key to determine if it's actually cited:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7a4ef4da-0106-4a34-afda-cc7b5806981e",
  "isSidechain": true,
  "agentId": "a5d47b67d0fecf656",
  "requestId": "req_011CbG9NNLDH2zX527TRGpKj",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "22e0265f-da8e-4d2c-8984-233182964647",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/.claude/sessions/director_63b8b789",
  "sessionId": "765154e5-66a9-4450-b7d7-710330a17dfd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01NQ3eFX25uV4LxqYSSe6YFh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 4,
      "cache_creation_input_tokens": 5684,
      "cache_read_input_tokens": 41260,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 5684,
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

_source line 9 · 2026-05-21T17:56:18.327Z_

<details open><summary>🔧 Tool call — Bash · `toolu_019hggW7FL9F6aHJ6KpRoAiL`</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/docs/paper && for key in ali2025hidden arora2024based arora2024zoology basu2026routing botev2024recurrentgemma clark2018arc damour2022underspecification dao2024mamba2 de2024griffin dong2024hymba du2025reconciling fehlauer2025convergence gorbett2026crossmodel gu2022s4 gu2024mamba haghighat2026resolving hsu2022rashomon katharopoulos2020transformers lahoti2026mamba3 lieber2024jamba mccoy2020berts paperno2016lambada peng2024eagle qin2024hgrn2 ren2024samba sellam2022multiberts sun2023retnet waleffe2024empirical watson2023predictive yang2024gateddeltanet; do count=$(grep -r \"\\\\\\\\cite\\(p\\|t\\)?{[^}]*$key\" --include=\"*.tex\" 2>/dev/null | wc -l); if [ $count -gt 0 ]; then echo \"$key: CITED ($count)\"; else echo \"$key: ORPHAN\"; fi; done"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "22e0265f-da8e-4d2c-8984-233182964647",
  "isSidechain": true,
  "agentId": "a5d47b67d0fecf656",
  "requestId": "req_011CbG9NNLDH2zX527TRGpKj",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "9aa3a5ee-0701-4660-b6aa-12426437be92",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/.claude/sessions/director_63b8b789",
  "sessionId": "765154e5-66a9-4450-b7d7-710330a17dfd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01NQ3eFX25uV4LxqYSSe6YFh",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 4,
      "cache_creation_input_tokens": 5684,
      "cache_read_input_tokens": 41260,
      "output_tokens": 377,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 5684
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 4,
          "output_tokens": 377,
          "cache_read_input_tokens": 41260,
          "cache_creation_input_tokens": 5684,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 5684,
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

_source line 10 · 2026-05-21T17:56:18.625Z_

<details><summary>↩ Tool result · `toolu_019hggW7FL9F6aHJ6KpRoAiL`</summary>

```text
ali2025hidden: ORPHAN
arora2024based: ORPHAN
arora2024zoology: ORPHAN
basu2026routing: ORPHAN
botev2024recurrentgemma: ORPHAN
clark2018arc: ORPHAN
damour2022underspecification: ORPHAN
dao2024mamba2: ORPHAN
de2024griffin: ORPHAN
dong2024hymba: ORPHAN
du2025reconciling: ORPHAN
fehlauer2025convergence: ORPHAN
gorbett2026crossmodel: ORPHAN
gu2022s4: ORPHAN
gu2024mamba: ORPHAN
haghighat2026resolving: ORPHAN
hsu2022rashomon: ORPHAN
katharopoulos2020transformers: ORPHAN
lahoti2026mamba3: ORPHAN
lieber2024jamba: ORPHAN
mccoy2020berts: ORPHAN
paperno2016lambada: ORPHAN
peng2024eagle: ORPHAN
qin2024hgrn2: ORPHAN
ren2024samba: ORPHAN
sellam2022multiberts: ORPHAN
sun2023retnet: ORPHAN
waleffe2024empirical: ORPHAN
watson2023predictive: ORPHAN
yang2024gateddeltanet: ORPHAN
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "9aa3a5ee-0701-4660-b6aa-12426437be92",
  "isSidechain": true,
  "promptId": "aeac6180-ae00-4058-bb9d-97b85fb92ee8",
  "agentId": "a5d47b67d0fecf656",
  "type": "user",
  "uuid": "ee55332c-6bdd-4581-8179-b38b6da1ea54",
  "sourceToolAssistantUUID": "9aa3a5ee-0701-4660-b6aa-12426437be92",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/.claude/sessions/director_63b8b789",
  "sessionId": "765154e5-66a9-4450-b7d7-710330a17dfd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 11 · 2026-05-21T17:56:20.415Z_

Interesting! The grep pattern didn't match. Let me try a different approach with looser regex:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ee55332c-6bdd-4581-8179-b38b6da1ea54",
  "isSidechain": true,
  "agentId": "a5d47b67d0fecf656",
  "requestId": "req_011CbG9NiasLU5z7yTUGhS8c",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "416b2f87-fc24-44ff-a90c-32de258ffe2f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/.claude/sessions/director_63b8b789",
  "sessionId": "765154e5-66a9-4450-b7d7-710330a17dfd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_0191fWCjS6f8njPjHj4xPocD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 4,
      "cache_creation_input_tokens": 722,
      "cache_read_input_tokens": 46944,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 722,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 2,
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

_source line 12 · 2026-05-21T17:56:21.524Z_

<details open><summary>🔧 Tool call — Bash · `toolu_0194D2y3p2nPinGRLLPwJBnC`</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/docs/paper && for key in ali2025hidden arora2024based arora2024zoology basu2026routing botev2024recurrentgemma clark2018arc damour2022underspecification dao2024mamba2 de2024griffin dong2024hymba du2025reconciling fehlauer2025convergence gorbett2026crossmodel gu2022s4 gu2024mamba haghighat2026resolving hsu2022rashomon katharopoulos2020transformers lahoti2026mamba3 lieber2024jamba mccoy2020berts paperno2016lambada peng2024eagle qin2024hgrn2 ren2024samba sellam2022multiberts sun2023retnet waleffe2024empirical watson2023predictive yang2024gateddeltanet; do count=$(grep -r \"$key\" --include=\"*.tex\" 2>/dev/null | wc -l); if [ $count -gt 0 ]; then echo \"$key: FOUND\"; fi; done"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "416b2f87-fc24-44ff-a90c-32de258ffe2f",
  "isSidechain": true,
  "agentId": "a5d47b67d0fecf656",
  "requestId": "req_011CbG9NiasLU5z7yTUGhS8c",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "40d27f35-0629-462f-ab09-f13e6dc62c5a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/.claude/sessions/director_63b8b789",
  "sessionId": "765154e5-66a9-4450-b7d7-710330a17dfd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_0191fWCjS6f8njPjHj4xPocD",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 4,
      "cache_creation_input_tokens": 722,
      "cache_read_input_tokens": 46944,
      "output_tokens": 350,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 722
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 4,
          "output_tokens": 350,
          "cache_read_input_tokens": 46944,
          "cache_creation_input_tokens": 722,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 722,
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

_source line 13 · 2026-05-21T17:56:21.729Z_

<details><summary>↩ Tool result · `toolu_0194D2y3p2nPinGRLLPwJBnC`</summary>

```text
ali2025hidden: FOUND
arora2024based: FOUND
arora2024zoology: FOUND
basu2026routing: FOUND
botev2024recurrentgemma: FOUND
clark2018arc: FOUND
damour2022underspecification: FOUND
dao2024mamba2: FOUND
de2024griffin: FOUND
dong2024hymba: FOUND
du2025reconciling: FOUND
fehlauer2025convergence: FOUND
gorbett2026crossmodel: FOUND
gu2022s4: FOUND
gu2024mamba: FOUND
haghighat2026resolving: FOUND
hsu2022rashomon: FOUND
katharopoulos2020transformers: FOUND
lahoti2026mamba3: FOUND
lieber2024jamba: FOUND
mccoy2020berts: FOUND
paperno2016lambada: FOUND
peng2024eagle: FOUND
qin2024hgrn2: FOUND
ren2024samba: FOUND
sellam2022multiberts: FOUND
sun2023retnet: FOUND
waleffe2024empirical: FOUND
watson2023predictive: FOUND
yang2024gateddeltanet: FOUND
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "40d27f35-0629-462f-ab09-f13e6dc62c5a",
  "isSidechain": true,
  "promptId": "aeac6180-ae00-4058-bb9d-97b85fb92ee8",
  "agentId": "a5d47b67d0fecf656",
  "type": "user",
  "uuid": "3ad9136b-f075-4da9-950c-b5858d14b9c3",
  "sourceToolAssistantUUID": "40d27f35-0629-462f-ab09-f13e6dc62c5a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/.claude/sessions/director_63b8b789",
  "sessionId": "765154e5-66a9-4450-b7d7-710330a17dfd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 14 · 2026-05-21T17:56:22.989Z_

Excellent! All keys are found. Now let me get the exact context for each one to verify they're in cite commands:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3ad9136b-f075-4da9-950c-b5858d14b9c3",
  "isSidechain": true,
  "agentId": "a5d47b67d0fecf656",
  "requestId": "req_011CbG9NwtZbetgkSxSmH7Rr",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "c432393a-0807-4f7d-88df-9c2cd4caad7a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/.claude/sessions/director_63b8b789",
  "sessionId": "765154e5-66a9-4450-b7d7-710330a17dfd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01Xhb9gzKDdEVqnSq4p4NDmi",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 4,
      "cache_creation_input_tokens": 665,
      "cache_read_input_tokens": 47666,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 665,
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

_source line 15 · 2026-05-21T17:56:24.081Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01CjXFAJU6EkjpFtsYRFByHA`</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/docs/paper && for key in ali2025hidden arora2024based arora2024zoology basu2026routing botev2024recurrentgemma clark2018arc damour2022underspecification dao2024mamba2 de2024griffin dong2024hymba du2025reconciling fehlauer2025convergence gorbett2026crossmodel gu2022s4 gu2024mamba haghighat2026resolving hsu2022rashomon katharopoulos2020transformers lahoti2026mamba3 lieber2024jamba mccoy2020berts paperno2016lambada peng2024eagle qin2024hgrn2 ren2024samba sellam2022multiberts sun2023retnet waleffe2024empirical watson2023predictive yang2024gateddeltanet; do echo \"=== $key ===\"; grep -B2 -A2 \"$key\" --include=\"*.tex\" -r 2>/dev/null | head -15; done"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c432393a-0807-4f7d-88df-9c2cd4caad7a",
  "isSidechain": true,
  "agentId": "a5d47b67d0fecf656",
  "requestId": "req_011CbG9NwtZbetgkSxSmH7Rr",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "b08bdf08-a937-47fb-a260-f2312208a057",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/.claude/sessions/director_63b8b789",
  "sessionId": "765154e5-66a9-4450-b7d7-710330a17dfd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01Xhb9gzKDdEVqnSq4p4NDmi",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 4,
      "cache_creation_input_tokens": 665,
      "cache_read_input_tokens": 47666,
      "output_tokens": 348,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 665
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 4,
          "output_tokens": 348,
          "cache_read_input_tokens": 47666,
          "cache_creation_input_tokens": 665,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 665,
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

_source line 16 · 2026-05-21T17:56:24.257Z_

<details><summary>↩ Tool result · `toolu_01CjXFAJU6EkjpFtsYRFByHA`</summary>

```text
&lt;persisted-output>
Output too large (70.3KB). Full output saved to: /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-2-projects-entrainment-gated-ft--claude-sessions-director-63b8b789/765154e5-66a9-4450-b7d7-710330a17dfd/tool-results/b6yy12jp6.txt

Preview (first 2KB):
=== ali2025hidden ===
sections/appendix.tex-\section{Attention Weight Analysis}\label{app:attention_patterns}
sections/appendix.tex-
sections/appendix.tex:We extract attention weight matrices from the 1.3B h3-1 models of all three architectures using forward hooks on each attention layer. While \citet{ali2025hidden} show that SSM layers learn implicit attention patterns, our analysis focuses on the explicit attention layers interleaved within the hybrid architecture. For each layer, we compute the mean attention distribution across all 5{,}153 LAMBADA examples and measure cross-architecture similarity via cosine similarity.
sections/appendix.tex-
sections/appendix.tex-\subsection{Cross-Architecture Cosine Similarity}
--
sections/related_work.tex-
sections/related_work.tex-\paragraph{Hybrid Recurrent Architectures.}
sections/related_work.tex:The design space for combining attention with recurrence spans layer-level interleaving \citep[Jamba;][]{lieber2024jamba}, local attention pairing \citep[Griffin, RecurrentGemma;][]{de2024griffin,botev2024recurrentgemma}, matrix-valued recurrence \citep[RWKV-6;][]{peng2024eagle}, within-head mixing \citep[Hymba;][]{dong2024hymba}, and unbounded-context hybrid SSMs \citep[Samba;][]{ren2024samba}. Mamba-2 \citep{dao2024mamba2} establishes a duality between structured state spaces and attention; Mamba-3 \citep{lahoti2026mamba3} extends the design further, while \citet{ali2025hidden} reveal implicit attention within Mamba. Comparative evaluations confirm that hybrids outperform pure Transformers and SSMs at scale \citep{waleffe2024empirical}, and that even one attention layer enables content-based routing \citep{basu2026routing}. \citet{wang2025hybrid} provide the controlled model zoo we use, holding training conditions constant while varying architecture and attention ratio.
sections/related_work.tex-
sections/related_work.tex-\paragraph{Linear Recurrent Models.}
=== arora2024based ===
...
&lt;/persisted-output>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b08bdf08-a937-47fb-a260-f2312208a057",
  "isSidechain": true,
  "promptId": "aeac6180-ae00-4058-bb9d-97b85fb92ee8",
  "agentId": "a5d47b67d0fecf656",
  "type": "user",
  "uuid": "0cff1c31-1890-4987-9108-cfdd163b6af5",
  "sourceToolAssistantUUID": "b08bdf08-a937-47fb-a260-f2312208a057",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/.claude/sessions/director_63b8b789",
  "sessionId": "765154e5-66a9-4450-b7d7-710330a17dfd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 17 · 2026-05-21T17:56:25.583Z_

Perfect! Let me read the full output and compile a detailed report:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0cff1c31-1890-4987-9108-cfdd163b6af5",
  "isSidechain": true,
  "agentId": "a5d47b67d0fecf656",
  "requestId": "req_011CbG9P8fDBDcayhuu6Bxfp",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "eec5fb9a-d0f0-482f-b3fc-ffb0f208f4b8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/.claude/sessions/director_63b8b789",
  "sessionId": "765154e5-66a9-4450-b7d7-710330a17dfd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01DuQXhjegdAYw1nNc1SR1C3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1140,
      "cache_read_input_tokens": 48331,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1140,
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

_source line 18 · 2026-05-21T17:56:25.891Z_

<details open><summary>🔧 Tool call — Read · `toolu_01XypjSyxbRFtLQvSS6Q1bXb`</summary>

```json
{
  "file_path": "/home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-2-projects-entrainment-gated-ft--claude-sessions-director-63b8b789/765154e5-66a9-4450-b7d7-710330a17dfd/tool-results/b6yy12jp6.txt"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "eec5fb9a-d0f0-482f-b3fc-ffb0f208f4b8",
  "isSidechain": true,
  "agentId": "a5d47b67d0fecf656",
  "requestId": "req_011CbG9P8fDBDcayhuu6Bxfp",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "47d4ebea-3a48-4c06-8a6d-af5fe97c7af8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/.claude/sessions/director_63b8b789",
  "sessionId": "765154e5-66a9-4450-b7d7-710330a17dfd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01DuQXhjegdAYw1nNc1SR1C3",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1140,
      "cache_read_input_tokens": 48331,
      "output_tokens": 159,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 1140
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 159,
          "cache_read_input_tokens": 48331,
          "cache_creation_input_tokens": 1140,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 1140,
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

_source line 19 · 2026-05-21T17:56:26.160Z_

<details><summary>↩ Tool result · `toolu_01XypjSyxbRFtLQvSS6Q1bXb`</summary>

```text
1	=== ali2025hidden ===
2	sections/appendix.tex-\section{Attention Weight Analysis}\label{app:attention_patterns}
3	sections/appendix.tex-
4	sections/appendix.tex:We extract attention weight matrices from the 1.3B h3-1 models of all three architectures using forward hooks on each attention layer. While \citet{ali2025hidden} show that SSM layers learn implicit attention patterns, our analysis focuses on the explicit attention layers interleaved within the hybrid architecture. For each layer, we compute the mean attention distribution across all 5{,}153 LAMBADA examples and measure cross-architecture similarity via cosine similarity.
5	sections/appendix.tex-
6	sections/appendix.tex-\subsection{Cross-Architecture Cosine Similarity}
7	--
8	sections/related_work.tex-
9	sections/related_work.tex-\paragraph{Hybrid Recurrent Architectures.}
10	sections/related_work.tex:The design space for combining attention with recurrence spans layer-level interleaving \citep[Jamba;][]{lieber2024jamba}, local attention pairing \citep[Griffin, RecurrentGemma;][]{de2024griffin,botev2024recurrentgemma}, matrix-valued recurrence \citep[RWKV-6;][]{peng2024eagle}, within-head mixing \citep[Hymba;][]{dong2024hymba}, and unbounded-context hybrid SSMs \citep[Samba;][]{ren2024samba}. Mamba-2 \citep{dao2024mamba2} establishes a duality between structured state spaces and attention; Mamba-3 \citep{lahoti2026mamba3} extends the design further, while \citet{ali2025hidden} reveal implicit attention within Mamba. Comparative evaluations confirm that hybrids outperform pure Transformers and SSMs at scale \citep{waleffe2024empirical}, and that even one attention layer enables content-based routing \citep{basu2026routing}. \citet{wang2025hybrid} provide the controlled model zoo we use, holding training conditions constant while varying architecture and attention ratio.
11	sections/related_work.tex-
12	sections/related_work.tex-\paragraph{Linear Recurrent Models.}
13	=== arora2024based ===
14	sections/appendix.tex-Beyond LAMBADA ($\rho = -1.0$), two benchmarks show moderate negative correlations that do not reach significance: ARC-Easy and MMLU (both $\rho = -0.7$, $p = .233$). Both are classified as ``Mixed'' tasks combining retrieval with reasoning demands. The sensitivity analysis (Appendix~\ref{app:sensitivity}) shows that MMLU's correlation reverses upon GDN exclusion ($\rho = +0.6$), indicating dependence on a single architecture; ARC-Easy's correlation is more stable. COPA ($n = 100$; supplementary) shows $\rho = -0.67$ with a large $\sigma$ ratio (5.57), consistent with LAMBADA's pattern but unreliable due to small sample size.
15	sections/appendix.tex-
16	sections/appendix.tex:Several benchmarks show positive or near-zero $\rho$ (BoolQ: $+0.2$; ARC-C: $+0.6$; HellaSwag: $+0.4$; WinoGrande: $+0.1$; SciQ: $+0.1$), indicating that attention does not systematically reduce cross-architecture variance on reasoning or comprehension tasks. The contrast with LAMBADA is consistent with attention's convergence benefit being specific to tasks requiring direct token-level recall \citep{arora2024zoology,arora2024based} rather than multi-step inference.
17	sections/appendix.tex-
18	sections/appendix.tex-\paragraph{Regression to the mean.} The direction of LAMBADA's aggregate convergence is consistent with regression to the mean: GDN (highest pure accuracy, 0.543) declines to 0.513 under h3-1, while HGRN2 (lowest, 0.484) rises to 0.514, yielding a $5\times$ $\sigma$ compression ($0.024 \to 0.005$). However, three observations argue against a purely statistical artifact. First, the $5\times$ reduction in cross-architecture $\sigma$ far exceeds typical regression amplitudes. Second, the direction is entirely determined by architecture identity, not random fluctuation: HGRN2 accuracy increases monotonically across all attention ratios, while GDN decreases monotonically---a pattern inconsistent with noise-driven mean reversion. Third, per-example analysis (\S\ref{ssec:per_example}) reveals architecture-specific mechanisms: GDN's net $-153$ examples and HGRN2's net $+153$ examples reflect distinct helped/hurt profiles with low cross-architecture Jaccard overlap, indicating that the aggregate convergence arises from structured, architecture-dependent per-example changes rather than symmetric regression.
19	--
20	sections/experiments.tex-\subsection{Task-Specific Convergence}\label{ssec:task_convergence}
21	sections/experiments.tex-
22	sections/experiments.tex:Table~\ref{tab:convergence} reports cross-architecture $\sigma$ at each attention ratio for all benchmarks at 1.3B scale. LAMBADA is the only benchmark exhibiting monotonic convergence: $\rho = -1.0$ ($p = .017$; BCa 95\% CI $[-1.0,\,-0.7]$; $\sigma$ drops 79\%; Bonferroni-adjusted $p = .100$). This is consistent with attention compensating for differences in how recurrent architectures retrieve from context \citep{arora2024zoology}---LAMBADA requires predicting a final word from long-range dependencies, and attention provides direct token-level access that narrows architectural differences in recall capacity \citep{arora2024based}. No other benchmark shows significant convergence (all $|\rho| \leq 0.7$, $p \geq .233$; Figure~\ref{fig:task_specificity}). Full convergence discussion appears in Appendix~\ref{app:convergence_detail}. Scale analysis (Appendix~\ref{app:scale_convergence}) shows this convergence is monotonic at 1.3B but non-monotonic at 340M.
23	sections/experiments.tex-
24	sections/experiments.tex-\begin{figure}[t]
25	=== arora2024zoology ===
26	sections/appendix.tex-Beyond LAMBADA ($\rho = -1.0$), two benchmarks show moderate negative correlations that do not reach significance: ARC-Easy and MMLU (both $\rho = -0.7$, $p = .233$). Both are classified as ``Mixed'' tasks combining retrieval with reasoning demands. The sensitivity analysis (Appendix~\ref{app:sensitivity}) shows that MMLU's correlation reverses upon GDN exclusion ($\rho = +0.6$), indicating dependence on a single architecture; ARC-Easy's correlation is more stable. COPA ($n = 100$; supplementary) shows $\rho = -0.67$ with a large $\sigma$ ratio (5.57), consistent with LAMBADA's pattern but unreliable due to small sample size.
27	sections/appendix.tex-
28	sections/appendix.tex:Several benchmarks show positive or near-zero $\rho$ (BoolQ: $+0.2$; ARC-C: $+0.6$; HellaSwag: $+0.4$; WinoGrande: $+0.1$; SciQ: $+0.1$), indicating that attention does not systematically reduce cross-architecture variance on reasoning or comprehension tasks. The contrast with LAMBADA is consistent with attention's convergence benefit being specific to tasks requiring direct token-level recall \citep{arora2024zoology,arora2024based} rather than multi-step inference.
29	sections/appendix.tex-
30	sections/appendix.tex-\paragraph{Regression to the mean.} The direction of LAMBADA's aggregate convergence is consistent with regression to the mean: GDN (highest pure accuracy, 0.543) declines to 0.513 under h3-1, while HGRN2 (lowest, 0.484) rises to 0.514, yielding a $5\times$ $\sigma$ compression ($0.024 \to 0.005$). However, three observations argue against a purely statistical artifact. First, the $5\times$ reduction in cross-architecture $\sigma$ far exceeds typical regression amplitudes. Second, the direction is entirely determined by architecture identity, not random fluctuation: HGRN2 accuracy increases monotonically across all attention ratios, while GDN decreases monotonically---a pattern inconsistent with noise-driven mean reversion. Third, per-example analysis (\S\ref{ssec:per_example}) reveals architecture-specific mechanisms: GDN's net $-153$ examples and HGRN2's net $+153$ examples reflect distinct helped/hurt profiles with low cross-architecture Jaccard overlap, indicating that the aggregate convergence arises from structured, architecture-dependent per-example changes rather than symmetric regression.
31	--
32	sections/experiments.tex-\subsection{Task-Specific Convergence}\label{ssec:task_convergence}
33	sections/experiments.tex-
34	sections/experiments.tex:Table~\ref{tab:convergence} reports cross-architecture $\sigma$ at each attention ratio for all benchmarks at 1.3B scale. LAMBADA is the only benchmark exhibiting monotonic convergence: $\rho = -1.0$ ($p = .017$; BCa 95\% CI $[-1.0,\,-0.7]$; $\sigma$ drops 79\%; Bonferroni-adjusted $p = .100$). This is consistent with attention compensating for differences in how recurrent architectures retrieve from context \citep{arora2024zoology}---LAMBADA requires predicting a final word from long-range dependencies, and attention provides direct token-level access that narrows architectural differences in recall capacity \citep{arora2024based}. No other benchmark shows significant convergence (all $|\rho| \leq 0.7$, $p \geq .233$; Figure~\ref{fig:task_specificity}). Full convergence discussion appears in Appendix~\ref{app:convergence_detail}. Scale analysis (Appendix~\ref{app:scale_convergence}) shows this convergence is monotonic at 1.3B but non-monotonic at 340M.
35	sections/experiments.tex-
36	sections/experiments.tex-\begin{figure}[t]
37	=== basu2026routing ===
38	sections/related_work.tex-
39	sections/related_work.tex-\paragraph{Hybrid Recurrent Architectures.}
40	sections/related_work.tex:The design space for combining attention with recurrence spans layer-level interleaving \citep[Jamba;][]{lieber2024jamba}, local attention pairing \citep[Griffin, RecurrentGemma;][]{de2024griffin,botev2024recurrentgemma}, matrix-valued recurrence \citep[RWKV-6;][]{peng2024eagle}, within-head mixing \citep[Hymba;][]{dong2024hymba}, and unbounded-context hybrid SSMs \citep[Samba;][]{ren2024samba}. Mamba-2 \citep{dao2024mamba2} establishes a duality between structured state spaces and attention; Mamba-3 \citep{lahoti2026mamba3} extends the design further, while \citet{ali2025hidden} reveal implicit attention within Mamba. Comparative evaluations confirm that hybrids outperform pure Transformers and SSMs at scale \citep{waleffe2024empirical}, and that even one attention layer enables content-based routing \citep{basu2026routing}. \citet{wang2025hybrid} provide the controlled model zoo we use, holding training conditions constant while varying architecture and attention ratio.
41	sections/related_work.tex-
42	sections/related_work.tex-\paragraph{Linear Recurrent Models.}
43	=== botev2024recurrentgemma ===
44	sections/introduction.tex-When attention layers are interleaved into recurrent architectures, they help and hurt almost entirely different examples---pairwise Jaccard overlap among three hybrid designs is at most 0.10, approximately twice the independence baseline. This per-example divergence is invisible in aggregate metrics: on LAMBADA, cross-architecture standard deviation drops 79\% as attention increases (Bonferroni-adjusted $p = .100$; the BCa 95\% CI excludes zero), but each architecture reaches similar accuracy by rescuing and disrupting different inputs. Practitioners increasingly choose between recurrent backbones based on aggregate benchmark scores; architectures that score identically in aggregate may thus carry hidden consequences for deployment reliability and ensemble construction.
45	sections/introduction.tex-
46	sections/introduction.tex:This tension arises in the context of a rapid architectural shift toward hybrid recurrent-attention models, which interleave attention layers within linear recurrent backbones. Jamba \citep{lieber2024jamba}, Griffin \citep{de2024griffin}, RWKV-6 \citep{peng2024eagle}, and RecurrentGemma \citep{botev2024recurrentgemma} each combine recurrence with attention using different mixing strategies. These systems now serve as production-grade alternatives to pure Transformers, and the practical question of how much attention to include is typically answered by comparing aggregate benchmark numbers. \citet{wang2025hybrid} provide a controlled model zoo spanning three recurrent architectures, five attention ratios, and two parameter scales, which enables systematic study of how attention allocation affects these hybrid designs.
47	sections/introduction.tex-
48	sections/introduction.tex-Most evaluations of hybrid architectures compare aggregate benchmark scores and report that a given attention ratio achieves a certain accuracy averaged across tasks or averaged across architectures. This practice can mask substantial per-example behavioral diversity. \citet{marx2020predictive} formalized this risk as predictive multiplicity: a prediction problem admits competing models with conflicting predictions on individual inputs. \citet{damour2022underspecification} documented a related phenomenon, underspecification, showing that models trained from the same pipeline with different random seeds can disagree on individual predictions despite equivalent aggregate performance. \citet{mccoy2020berts} demonstrated a concrete NLP instance: BERT models trained from different random seeds diverge on specific linguistic constructions. These studies examine variation from initialization or training noise within a single architecture. Whether predictive multiplicity extends to hybrid recurrent architectures, where the source of variation is the recurrent backbone itself, remains unquantified. The question matters because practitioners increasingly choose between recurrent backbones based on aggregate benchmarks; if architectures that score identically in aggregate behave differently on individual inputs, such choices carry hidden consequences for deployment reliability and ensemble construction.
49	--
50	sections/related_work.tex-
51	sections/related_work.tex-\paragraph{Hybrid Recurrent Architectures.}
52	sections/related_work.tex:The design space for combining attention with recurrence spans layer-level interleaving \citep[Jamba;][]{lieber2024jamba}, local attention pairing \citep[Griffin, RecurrentGemma;][]{de2024griffin,botev2024recurrentgemma}, matrix-valued recurrence \citep[RWKV-6;][]{peng2024eagle}, within-head mixing \citep[Hymba;][]{dong2024hymba}, and unbounded-context hybrid SSMs \citep[Samba;][]{ren2024samba}. Mamba-2 \citep{dao2024mamba2} establishes a duality between structured state spaces and attention; Mamba-3 \citep{lahoti2026mamba3} extends the design further, while \citet{ali2025hidden} reveal implicit attention within Mamba. Comparative evaluations confirm that hybrids outperform pure Transformers and SSMs at scale \citep{waleffe2024empirical}, and that even one attention layer enables content-based routing \citep{basu2026routing}. \citet{wang2025hybrid} provide the controlled model zoo we use, holding training conditions constant while varying architecture and attention ratio.
53	sections/related_work.tex-
54	sections/related_work.tex-\paragraph{Linear Recurrent Models.}
55	=== clark2018arc ===
56	sections/method.tex-    \item \textbf{Retrieval}: LAMBADA \citep{paperno2016lambada}, which requires predicting a final word from long-range context without reasoning or world knowledge.
57	sections/method.tex-    \item \textbf{Comprehension}: BoolQ, a reading comprehension task with yes/no answers.
58	sections/method.tex:    \item \textbf{Reasoning}: HellaSwag, ARC-Challenge \citep{clark2018arc}, WinoGrande, and PIQA. COPA ($n = 100$) serves as a supplementary reasoning benchmark; its small sample size renders $\alpha$ estimation unreliable (CI width 0.13--0.18; Appendix~\ref{app:subsample_sensitivity}).
59	sections/method.tex-    \item \textbf{Mixed}: ARC-Easy, MMLU, SciQ, and XStoryCloze, which combine retrieval, comprehension, and reasoning demands.
60	sections/method.tex-\end{itemize}
61	=== damour2022underspecification ===
62	sections/introduction.tex-This tension arises in the context of a rapid architectural shift toward hybrid recurrent-attention models, which interleave attention layers within linear recurrent backbones. Jamba \citep{lieber2024jamba}, Griffin \citep{de2024griffin}, RWKV-6 \citep{peng2024eagle}, and RecurrentGemma \citep{botev2024recurrentgemma} each combine recurrence with attention using different mixing strategies. These systems now serve as production-grade alternatives to pure Transformers, and the practical question of how much attention to include is typically answered by comparing aggregate benchmark numbers. \citet{wang2025hybrid} provide a controlled model zoo spanning three recurrent architectures, five attention ratios, and two parameter scales, which enables systematic study of how attention allocation affects these hybrid designs.
63	sections/introduction.tex-
64	sections/introduction.tex:Most evaluations of hybrid architectures compare aggregate benchmark scores and report that a given attention ratio achieves a certain accuracy averaged across tasks or averaged across architectures. This practice can mask substantial per-example behavioral diversity. \citet{marx2020predictive} formalized this risk as predictive multiplicity: a prediction problem admits competing models with conflicting predictions on individual inputs. \citet{damour2022underspecification} documented a related phenomenon, underspecification, showing that models trained from the same pipeline with different random seeds can disagree on individual predictions despite equivalent aggregate performance. \citet{mccoy2020berts} demonstrated a concrete NLP instance: BERT models trained from different random seeds diverge on specific linguistic constructions. These studies examine variation from initialization or training noise within a single architecture. Whether predictive multiplicity extends to hybrid recurrent architectures, where the source of variation is the recurrent backbone itself, remains unquantified. The question matters because practitioners increasingly choose between recurrent backbones based on aggregate benchmarks; if architectures that score identically in aggregate behave differently on individual inputs, such choices carry hidden consequences for deployment reliability and ensemble construction.
65	sections/introduction.tex-
66	sections/introduction.tex-We present the first systematic per-example analysis of how attention affects cross-architecture agreement in hybrid recurrent models. Using the model zoo of \citet{wang2025hybrid}, we compare three architectures (GatedDeltaNet, RetNet, HGRN2) at five attention ratios (0\% to 25\%) and two scales (340M and 1.3B parameters). These three architectures represent distinct approaches to linear recurrence: gated delta rules, multi-scale exponential decay, and gated state expansion. We evaluate all 30 configurations on 10 benchmarks spanning retrieval, comprehension, reasoning, and mixed task categories. On four benchmarks---LAMBADA ($N = 5{,}153$), HellaSwag ($N = 10{,}042$), PIQA ($N = 1{,}838$), and ARC-Easy ($N = 2{,}376$)---we conduct per-example decompositions, classifying each example as helped, hurt, or unchanged when attention is added, and measure cross-architecture overlap using Jaccard similarity. Figure~\ref{fig:decoupling} previews our central result: aggregate convergence and per-example divergence follow different trajectories as attention ratio increases.
67	--
68	sections/introduction.tex-Our contributions are as follows:
69	sections/introduction.tex-\begin{itemize}
70	sections/introduction.tex:    \item Unlike prior studies of seed-driven disagreement within a single architecture \citep{mccoy2020berts, damour2022underspecification}, we show that architectural variation---under matched training conditions---produces structured per-example predictive multiplicity with a task-dependent spectrum ($\alpha = 0.14$--$0.30$) across four benchmarks in three recurrent backbones. This multiplicity is not addressable by seed averaging: the source of variation is the recurrent backbone itself, and its magnitude is independent of aggregate convergence (\S\ref{ssec:per_example}, \S\ref{ssec:decoupling}, Table~\ref{tab:multiplicity}).
71	sections/introduction.tex-    \item We quantify task-specific convergence: only retrieval tasks (LAMBADA) show attention-driven cross-architecture convergence, and this pattern is scale-dependent (Appendix~\ref{app:scale_convergence}; \S\ref{ssec:task_convergence}, Table~\ref{tab:convergence}, Figure~\ref{fig:task_specificity}).
72	sections/introduction.tex-\end{itemize}
73	--
74	sections/experiments.tex-Each architecture displays a distinct profile of per-example changes (Table~\ref{tab:per_example}). GDN loses a net 153 examples (462 helped, 615 hurt), RetNet loses 69 (426/495), and HGRN2 gains 153 (548/395). HGRN2 is the only architecture for which attention produces a net per-example benefit. Pairwise Jaccard similarity is low: mean $\bar{J} \leq 0.104$ for helped, $\leq 0.096$ for hurt, indicating ${\sim}90$\% non-overlap. Overlap significantly exceeds the independence baseline ($J_{\text{null}} \approx 0.05$, all $z > 5.9$, $p < .0001$; Appendix~\ref{app:jaccard_permutation}), but normalizing by the theoretical upper bound $J_{\max} = \min(|A|,|B|)/\max(|A|,|B|)$, observed overlap reaches only 5--7\% of the achievable range above chance (normalized ES 0.065 helped, 0.047 hurt; per-pair details in Appendix~\ref{app:normalized_es}), confirming that low Jaccard cannot be attributed to set-size constraints.
75	sections/experiments.tex-
76	sections/experiments.tex:No surface-level feature (token count, word frequency, syntactic complexity) reliably separates helped from hurt examples. However, pure-model confidence on the target token is strongly predictive within each architecture: hurt examples have lower target-token probability among pure-correct examples ($d = 0.83$--$0.92$), and helped examples have higher probability among pure-wrong examples ($d = 0.73$--$0.77$); see Appendix~\ref{app:confidence_margin}. A Kruskal-Wallis test confirms cross-architecture structure in both hurt ($p = .0005$) and helped ($p = .020$) distributions. The confidence margin thus identifies a per-example predictor of which examples will be affected: attention disrupts marginally correct predictions and rescues near-miss errors, but with architecture-specific thresholds that produce the observed cross-architecture divergence. The rescue pattern generalizes: across all three architectures on LAMBADA, HellaSwag, and ARC-Easy, helped examples have significantly higher pure-model target probability than stayed-wrong examples (9/9 tests, $d = 0.13$--$0.60$; Appendix~\ref{app:cm_cross}). The disruption pattern is weaker on ARC-Easy ($d = 0.13$--$0.26$), absent on HellaSwag under \texttt{acc\_norm}, and absent on binary classification (Appendix~\ref{app:boolq}), likely reflecting structural properties of constrained-choice formats that limit the discriminative power of confidence margins. This structured per-example disagreement despite similar aggregate performance constitutes predictive multiplicity \citep{marx2020predictive} arising from architectural variation rather than random initialization \citep{damour2022underspecification}.
77	=== dao2024mamba2 ===
78	sections/related_work.tex-
79	sections/related_work.tex-\paragraph{Hybrid Recurrent Architectures.}
80	sections/related_work.tex:The design space for combining attention with recurrence spans layer-level interleaving \citep[Jamba;][]{lieber2024jamba}, local attention pairing \citep[Griffin, RecurrentGemma;][]{de2024griffin,botev2024recurrentgemma}, matrix-valued recurrence \citep[RWKV-6;][]{peng2024eagle}, within-head mixing \citep[Hymba;][]{dong2024hymba}, and unbounded-context hybrid SSMs \citep[Samba;][]{ren2024samba}. Mamba-2 \citep{dao2024mamba2} establishes a duality between structured state spaces and attention; Mamba-3 \citep{lahoti2026mamba3} extends the design further, while \citet{ali2025hidden} reveal implicit attention within Mamba. Comparative evaluations confirm that hybrids outperform pure Transformers and SSMs at scale \citep{waleffe2024empirical}, and that even one attention layer enables content-based routing \citep{basu2026routing}. \citet{wang2025hybrid} provide the controlled model zoo we use, holding training conditions constant while varying architecture and attention ratio.
81	sections/related_work.tex-
82	sections/related_work.tex-\paragraph{Linear Recurrent Models.}
83	=== de2024griffin ===
84	sections/introduction.tex-When attention layers are interleaved into recurrent architectures, they help and hurt almost entirely different examples---pairwise Jaccard overlap among three hybrid designs is at most 0.10, approximately twice the independence baseline. This per-example divergence is invisible in aggregate metrics: on LAMBADA, cross-architecture standard deviation drops 79\% as attention increases (Bonferroni-adjusted $p = .100$; the BCa 95\% CI excludes zero), but each architecture reaches similar accuracy by rescuing and disrupting different inputs. Practitioners increasingly choose between recurrent backbones based on aggregate benchmark scores; architectures that score identically in aggregate may thus carry hidden consequences for deployment reliability and ensemble construction.
85	sections/introduction.tex-
86	sections/introduction.tex:This tension arises in the context of a rapid architectural shift toward hybrid recurrent-attention models, which interleave attention layers within linear recurrent backbones. Jamba \citep{lieber2024jamba}, Griffin \citep{de2024griffin}, RWKV-6 \citep{peng2024eagle}, and RecurrentGemma \citep{botev2024recurrentgemma} each combine recurrence with attention using different mixing strategies. These systems now serve as production-grade alternatives to pure Transformers, and the practical question of how much attention to include is typically answered by comparing aggregate benchmark numbers. \citet{wang2025hybrid} provide a controlled model zoo spanning three recurrent architectures, five attention ratios, and two parameter scales, which enables systematic study of how attention allocation affects these hybrid designs.
87	sections/introduction.tex-
88	sections/introduction.tex-Most evaluations of hybrid architectures compare aggregate benchmark scores and report that a given attention ratio achieves a certain accuracy averaged across tasks or averaged across architectures. This practice can mask substantial per-example behavioral diversity. \citet{marx2020predictive} formalized this risk as predictive multiplicity: a prediction problem admits competing models with conflicting predictions on individual inputs. \citet{damour2022underspecification} documented a related phenomenon, underspecification, showing that models trained from the same pipeline with different random seeds can disagree on individual predictions despite equivalent aggregate performance. \citet{mccoy2020berts} demonstrated a concrete NLP instance: BERT models trained from different random seeds diverge on specific linguistic constructions. These studies examine variation from initialization or training noise within a single architecture. Whether predictive multiplicity extends to hybrid recurrent architectures, where the source of variation is the recurrent backbone itself, remains unquantified. The question matters because practitioners increasingly choose between recurrent backbones based on aggregate benchmarks; if architectures that score identically in aggregate behave differently on individual inputs, such choices carry hidden consequences for deployment reliability and ensemble construction.
89	--
90	sections/related_work.tex-
91	sections/related_work.tex-\paragraph{Hybrid Recurrent Architectures.}
92	sections/related_work.tex:The design space for combining attention with recurrence spans layer-level interleaving \citep[Jamba;][]{lieber2024jamba}, local attention pairing \citep[Griffin, RecurrentGemma;][]{de2024griffin,botev2024recurrentgemma}, matrix-valued recurrence \citep[RWKV-6;][]{peng2024eagle}, within-head mixing \citep[Hymba;][]{dong2024hymba}, and unbounded-context hybrid SSMs \citep[Samba;][]{ren2024samba}. Mamba-2 \citep{dao2024mamba2} establishes a duality between structured state spaces and attention; Mamba-3 \citep{lahoti2026mamba3} extends the design further, while \citet{ali2025hidden} reveal implicit attention within Mamba. Comparative evaluations confirm that hybrids outperform pure Transformers and SSMs at scale \citep{waleffe2024empirical}, and that even one attention layer enables content-based routing \citep{basu2026routing}. \citet{wang2025hybrid} provide the controlled model zoo we use, holding training conditions constant while varying architecture and attention ratio.
93	sections/related_work.tex-
94	sections/related_work.tex-\paragraph{Linear Recurrent Models.}
95	=== dong2024hymba ===
96	sections/related_work.tex-
97	sections/related_work.tex-\paragraph{Hybrid Recurrent Architectures.}
98	sections/related_work.tex:The design space for combining attention with recurrence spans layer-level interleaving \citep[Jamba;][]{lieber2024jamba}, local attention pairing \citep[Griffin, RecurrentGemma;][]{de2024griffin,botev2024recurrentgemma}, matrix-valued recurrence \citep[RWKV-6;][]{peng2024eagle}, within-head mixing \citep[Hymba;][]{dong2024hymba}, and unbounded-context hybrid SSMs \citep[Samba;][]{ren2024samba}. Mamba-2 \citep{dao2024mamba2} establishes a duality between structured state spaces and attention; Mamba-3 \citep{lahoti2026mamba3} extends the design further, while \citet{ali2025hidden} reveal implicit attention within Mamba. Comparative evaluations confirm that hybrids outperform pure Transformers and SSMs at scale \citep{waleffe2024empirical}, and that even one attention layer enables content-based routing \citep{basu2026routing}. \citet{wang2025hybrid} provide the controlled model zoo we use, holding training conditions constant while varying architecture and attention ratio.
99	sections/related_work.tex-
100	sections/related_work.tex-\paragraph{Linear Recurrent Models.}
101	=== du2025reconciling ===
102	sections/related_work.tex-
103	sections/related_work.tex-\paragraph{Underspecification and Predictive Multiplicity.}
104	sections/related_work.tex:\citet{damour2022underspecification} formalized underspecification: equivalent aggregate performance can mask per-prediction divergence. Concrete NLP instances include seed-dependent BERT disagreement \citep{mccoy2020berts,sellam2022multiberts} and the four-phase convergence pattern of autoregressive LMs \citep{fehlauer2025convergence}. \citet{marx2020predictive} introduced predictive multiplicity as a complementary lens, showing that near-optimal models produce conflicting per-example predictions; extensions address probabilistic classification \citep{watson2023predictive}, Rashomon capacity \citep{hsu2022rashomon}, reconciliation \citep{du2025reconciling,haghighat2026resolving}, and cross-model disagreement as a correctness signal \citep{gorbett2026crossmodel}. These studies attribute divergence to initialization noise or the near-optimal set within a single architecture. We show that architectural variation in hybrid recurrent models produces analogous per-example multiplicity under matched training conditions.
105	=== fehlauer2025convergence ===
106	sections/related_work.tex-
107	sections/related_work.tex-\paragraph{Underspecification and Predictive Multiplicity.}
108	sections/related_work.tex:\citet{damour2022underspecification} formalized underspecification: equivalent aggregate performance can mask per-prediction divergence. Concrete NLP instances include seed-dependent BERT disagreement \citep{mccoy2020berts,sellam2022multiberts} and the four-phase convergence pattern of autoregressive LMs \citep{fehlauer2025convergence}. \citet{marx2020predictive} introduced predictive multiplicity as a complementary lens, showing that near-optimal models produce conflicting per-example predictions; extensions address probabilistic classification \citep{watson2023predictive}, Rashomon capacity \citep{hsu2022rashomon}, reconciliation \citep{du2025reconciling,haghighat2026resolving}, and cross-model disagreement as a correctness signal \citep{gorbett2026crossmodel}. These studies attribute divergence to initialization noise or the near-optimal set within a single architecture. We show that architectural variation in hybrid recurrent models produces analogous per-example multiplicity under matched training conditions.
109	=== gorbett2026crossmodel ===
110	sections/experiments.tex-No surface-level feature (token count, word frequency, syntactic complexity) reliably separates helped from hurt examples. However, pure-model confidence on the target token is strongly predictive within each architecture: hurt examples have lower target-token probability among pure-correct examples ($d = 0.83$--$0.92$), and helped examples have higher probability among pure-wrong examples ($d = 0.73$--$0.77$); see Appendix~\ref{app:confidence_margin}. A Kruskal-Wallis test confirms cross-architecture structure in both hurt ($p = .0005$) and helped ($p = .020$) distributions. The confidence margin thus identifies a per-example predictor of which examples will be affected: attention disrupts marginally correct predictions and rescues near-miss errors, but with architecture-specific thresholds that produce the observed cross-architecture divergence. The rescue pattern generalizes: across all three architectures on LAMBADA, HellaSwag, and ARC-Easy, helped examples have significantly higher pure-model target probability than stayed-wrong examples (9/9 tests, $d = 0.13$--$0.60$; Appendix~\ref{app:cm_cross}). The disruption pattern is weaker on ARC-Easy ($d = 0.13$--$0.26$), absent on HellaSwag under \texttt{acc\_norm}, and absent on binary classification (Appendix~\ref{app:boolq}), likely reflecting structural properties of constrained-choice formats that limit the discriminative power of confidence margins. This structured per-example disagreement despite similar aggregate performance constitutes predictive multiplicity \citep{marx2020predictive} arising from architectural variation rather than random initialization \citep{damour2022underspecification}.
111	sections/experiments.tex-
112	sections/experiments.tex:\paragraph{Multiplicity spectrum.} Extending the per-example analysis to HellaSwag ($N = 10{,}042$) and PIQA ($N = 1{,}838$) reveals that predictive multiplicity varies systematically across tasks (Table~\ref{tab:multiplicity}). The ambiguity $\alpha$ \citep{marx2020predictive} ranges from 0.14 (PIQA) through 0.15 (HellaSwag) and 0.21 (ARC-Easy) to 0.30 (LAMBADA), forming a task-dependent spectrum. Evaluation format does not drive multiplicity: HellaSwag (four-way, $\alpha = 0.15$) and PIQA (two-choice, $\alpha = 0.14$) produce nearly identical multiplicity despite different formats; among two-choice benchmarks alone, $\alpha$ spans $3\times$ from 0.14 (PIQA) to 0.41 (WinoGrande; Appendix~\ref{app:winogrande}) to 0.45 (BoolQ; Appendix~\ref{app:boolq}), covering the full six-benchmark range within a single format. Bootstrap 95\% CIs confirm the spectrum ordering: all adjacent-benchmark CIs are non-overlapping except PIQA and HellaSwag, whose CIs overlap substantially ($[.127,\,.159]$ vs.\ $[.141,\,.155]$; Appendix, Table~\ref{tab:arceasy_ambiguity}). Moreover, $\alpha$ does not significantly correlate with task accuracy (Spearman $\rho = -0.60$, $p = .24$). Pairwise Jaccard remains uniformly low ($\bar{J} \leq 0.10$, all $p < .01$ across four benchmarks), indicating that architectures affect different examples regardless of how many examples are affected. Within each benchmark, $\alpha$ is stable across attention ratios (variation $< 0.03$), but differs $2\times$ across task types (from reasoning to retrieval), confirming that multiplicity magnitude depends on task, not attention dose \citep[cf.][]{gorbett2026crossmodel}.
113	sections/experiments.tex-
114	sections/experiments.tex-\begin{table}[t]
115	--
116	sections/related_work.tex-
117	sections/related_work.tex-\paragraph{Underspecification and Predictive Multiplicity.}
118	sections/related_work.tex:\citet{damour2022underspecification} formalized underspecification: equivalent aggregate performance can mask per-prediction divergence. Concrete NLP instances include seed-dependent BERT disagreement \citep{mccoy2020berts,sellam2022multiberts} and the four-phase convergence pattern of autoregressive LMs \citep{fehlauer2025convergence}. \citet{marx2020predictive} introduced predictive multiplicity as a complementary lens, showing that near-optimal models produce conflicting per-example predictions; extensions address probabilistic classification \citep{watson2023predictive}, Rashomon capacity \citep{hsu2022rashomon}, reconciliation \citep{du2025reconciling,haghighat2026resolving}, and cross-model disagreement as a correctness signal \citep{gorbett2026crossmodel}. These studies attribute divergence to initialization noise or the near-optimal set within a single architecture. We show that architectural variation in hybrid recurrent models produces analogous per-example multiplicity under matched training conditions.
119	=== gu2022s4 ===
120	sections/related_work.tex-
121	sections/related_work.tex-\paragraph{Linear Recurrent Models.}
122	sections/related_work.tex:Our three recurrent backbones represent distinct gating strategies within the linear recurrence family: RetNet \citep{sun2023retnet} uses multi-scale exponential decay, HGRN2 \citep{qin2024hgrn2} applies gated state expansion, and GatedDeltaNet \citep{yang2024gateddeltanet} combines gated updates with delta rules. These descend from S4 \citep{gu2022s4} and Mamba \citep{gu2024mamba}, which introduced structured state spaces and input-dependent selection, respectively, and connect to linear attention \citep{katharopoulos2020transformers} through the state-space--attention duality of Mamba-2.
123	sections/related_work.tex-
124	sections/related_work.tex-\paragraph{Underspecification and Predictive Multiplicity.}
125	=== gu2024mamba ===
126	sections/related_work.tex-
127	sections/related_work.tex-\paragraph{Linear Recurrent Models.}
128	sections/related_work.tex:Our three recurrent backbones represent distinct gating strategies within the linear recurrence family: RetNet \citep{sun2023retnet} uses multi-scale exponential decay, HGRN2 \citep{qin2024hgrn2} applies gated state expansion, and GatedDeltaNet \citep{yang2024gateddeltanet} combines gated updates with delta rules. These descend from S4 \citep{gu2022s4} and Mamba \citep{gu2024mamba}, which introduced structured state spaces and input-dependent selection, respectively, and connect to linear attention \citep{katharopoulos2020transformers} through the state-space--attention duality of Mamba-2.
129	sections/related_work.tex-
130	sections/related_work.tex-\paragraph{Underspecification and Predictive Multiplicity.}
131	=== haghighat2026resolving ===
132	sections/related_work.tex-
133	sections/related_work.tex-\paragraph{Underspecification and Predictive Multiplicity.}
134	sections/related_work.tex:\citet{damour2022underspecification} formalized underspecification: equivalent aggregate performance can mask per-prediction divergence. Concrete NLP instances include seed-dependent BERT disagreement \citep{mccoy2020berts,sellam2022multiberts} and the four-phase convergence pattern of autoregressive LMs \citep{fehlauer2025convergence}. \citet{marx2020predictive} introduced predictive multiplicity as a complementary lens, showing that near-optimal models produce conflicting per-example predictions; extensions address probabilistic classification \citep{watson2023predictive}, Rashomon capacity \citep{hsu2022rashomon}, reconciliation \citep{du2025reconciling,haghighat2026resolving}, and cross-model disagreement as a correctness signal \citep{gorbett2026crossmodel}. These studies attribute divergence to initialization noise or the near-optimal set within a single architecture. We show that architectural variation in hybrid recurrent models produces analogous per-example multiplicity under matched training conditions.
135	=== hsu2022rashomon ===
136	sections/related_work.tex-
137	sections/related_work.tex-\paragraph{Underspecification and Predictive Multiplicity.}
138	sections/related_work.tex:\citet{damour2022underspecification} formalized underspecification: equivalent aggregate performance can mask per-prediction divergence. Concrete NLP instances include seed-dependent BERT disagreement \citep{mccoy2020berts,sellam2022multiberts} and the four-phase convergence pattern of autoregressive LMs \citep{fehlauer2025convergence}. \citet{marx2020predictive} introduced predictive multiplicity as a complementary lens, showing that near-optimal models produce conflicting per-example predictions; extensions address probabilistic classification \citep{watson2023predictive}, Rashomon capacity \citep{hsu2022rashomon}, reconciliation \citep{du2025reconciling,haghighat2026resolving}, and cross-model disagreement as a correctness signal \citep{gorbett2026crossmodel}. These studies attribute divergence to initialization noise or the near-optimal set within a single architecture. We show that architectural variation in hybrid recurrent models produces analogous per-example multiplicity under matched training conditions.
139	=== katharopoulos2020transformers ===
140	sections/related_work.tex-
141	sections/related_work.tex-\paragraph{Linear Recurrent Models.}
142	sections/related_work.tex:Our three recurrent backbones represent distinct gating strategies within the linear recurrence family: RetNet \citep{sun2023retnet} uses multi-scale exponential decay, HGRN2 \citep{qin2024hgrn2} applies gated state expansion, and GatedDeltaNet \citep{yang2024gateddeltanet} combines gated updates with delta rules. These descend from S4 \citep{gu2022s4} and Mamba \citep{gu2024mamba}, which introduced structured state spaces and input-dependent selection, respectively, and connect to linear attention \citep{katharopoulos2020transformers} through the state-space--attention duality of Mamba-2.
143	sections/related_work.tex-
144	sections/related_work.tex-\paragraph{Underspecification and Predictive Multiplicity.}
145	=== lahoti2026mamba3 ===
146	sections/related_work.tex-
147	sections/related_work.tex-\paragraph{Hybrid Recurrent Architectures.}
148	sections/related_work.tex:The design space for combining attention with recurrence spans layer-level interleaving \citep[Jamba;][]{lieber2024jamba}, local attention pairing \citep[Griffin, RecurrentGemma;][]{de2024griffin,botev2024recurrentgemma}, matrix-valued recurrence \citep[RWKV-6;][]{peng2024eagle}, within-head mixing \citep[Hymba;][]{dong2024hymba}, and unbounded-context hybrid SSMs \citep[Samba;][]{ren2024samba}. Mamba-2 \citep{dao2024mamba2} establishes a duality between structured state spaces and attention; Mamba-3 \citep{lahoti2026mamba3} extends the design further, while \citet{ali2025hidden} reveal implicit attention within Mamba. Comparative evaluations confirm that hybrids outperform pure Transformers and SSMs at scale \citep{waleffe2024empirical}, and that even one attention layer enables content-based routing \citep{basu2026routing}. \citet{wang2025hybrid} provide the controlled model zoo we use, holding training conditions constant while varying architecture and attention ratio.
149	sections/related_work.tex-
150	sections/related_work.tex-\paragraph{Linear Recurrent Models.}
151	=== lieber2024jamba ===
152	sections/introduction.tex-When attention layers are interleaved into recurrent architectures, they help and hurt almost entirely different examples---pairwise Jaccard overlap among three hybrid designs is at most 0.10, approximately twice the independence baseline. This per-example divergence is invisible in aggregate metrics: on LAMBADA, cross-architecture standard deviation drops 79\% as attention increases (Bonferroni-adjusted $p = .100$; the BCa 95\% CI excludes zero), but each architecture reaches similar accuracy by rescuing and disrupting different inputs. Practitioners increasingly choose between recurrent backbones based on aggregate benchmark scores; architectures that score identically in aggregate may thus carry hidden consequences for deployment reliability and ensemble construction.
153	sections/introduction.tex-
154	sections/introduction.tex:This tension arises in the context of a rapid architectural shift toward hybrid recurrent-attention models, which interleave attention layers within linear recurrent backbones. Jamba \citep{lieber2024jamba}, Griffin \citep{de2024griffin}, RWKV-6 \citep{peng2024eagle}, and RecurrentGemma \citep{botev2024recurrentgemma} each combine recurrence with attention using different mixing strategies. These systems now serve as production-grade alternatives to pure Transformers, and the practical question of how much attention to include is typically answered by comparing aggregate benchmark numbers. \citet{wang2025hybrid} provide a controlled model zoo spanning three recurrent architectures, five attention ratios, and two parameter scales, which enables systematic study of how attention allocation affects these hybrid designs.
155	sections/introduction.tex-
156	sections/introduction.tex-Most evaluations of hybrid architectures compare aggregate benchmark scores and report that a given attention ratio achieves a certain accuracy averaged across tasks or averaged across architectures. This practice can mask substantial per-example behavioral diversity. \citet{marx2020predictive} formalized this risk as predictive multiplicity: a prediction problem admits competing models with conflicting predictions on individual inputs. \citet{damour2022underspecification} documented a related phenomenon, underspecification, showing that models trained from the same pipeline with different random seeds can disagree on individual predictions despite equivalent aggregate performance. \citet{mccoy2020berts} demonstrated a concrete NLP instance: BERT models trained from different random seeds diverge on specific linguistic constructions. These studies examine variation from initialization or training noise within a single architecture. Whether predictive multiplicity extends to hybrid recurrent architectures, where the source of variation is the recurrent backbone itself, remains unquantified. The question matters because practitioners increasingly choose between recurrent backbones based on aggregate benchmarks; if architectures that score identically in aggregate behave differently on individual inputs, such choices carry hidden consequences for deployment reliability and ensemble construction.
157	--
158	sections/related_work.tex-
159	sections/related_work.tex-\paragraph{Hybrid Recurrent Architectures.}
160	sections/related_work.tex:The design space for combining attention with recurrence spans layer-level interleaving \citep[Jamba;][]{lieber2024jamba}, local attention pairing \citep[Griffin, RecurrentGemma;][]{de2024griffin,botev2024recurrentgemma}, matrix-valued recurrence \citep[RWKV-6;][]{peng2024eagle}, within-head mixing \citep[Hymba;][]{dong2024hymba}, and unbounded-context hybrid SSMs \citep[Samba;][]{ren2024samba}. Mamba-2 \citep{dao2024mamba2} establishes a duality between structured state spaces and attention; Mamba-3 \citep{lahoti2026mamba3} extends the design further, while \citet{ali2025hidden} reveal implicit attention within Mamba. Comparative evaluations confirm that hybrids outperform pure Transformers and SSMs at scale \citep{waleffe2024empirical}, and that even one attention layer enables content-based routing \citep{basu2026routing}. \citet{wang2025hybrid} provide the controlled model zoo we use, holding training conditions constant while varying architecture and attention ratio.
161	sections/related_work.tex-
162	sections/related_work.tex-\paragraph{Linear Recurrent Models.}
163	=== mccoy2020berts ===
164	sections/introduction.tex-This tension arises in the context of a rapid architectural shift toward hybrid recurrent-attention models, which interleave attention layers within linear recurrent backbones. Jamba \citep{lieber2024jamba}, Griffin \citep{de2024griffin}, RWKV-6 \citep{peng2024eagle}, and RecurrentGemma \citep{botev2024recurrentgemma} each combine recurrence with attention using different mixing strategies. These systems now serve as production-grade alternatives to pure Transformers, and the practical question of how much attention to include is typically answered by comparing aggregate benchmark numbers. \citet{wang2025hybrid} provide a controlled model zoo spanning three recurrent architectures, five attention ratios, and two parameter scales, which enables systematic study of how attention allocation affects these hybrid designs.
165	sections/introduction.tex-
166	sections/introduction.tex:Most evaluations of hybrid architectures compare aggregate benchmark scores and report that a given attention ratio achieves a certain accuracy averaged across tasks or averaged across architectures. This practice can mask substantial per-example behavioral diversity. \citet{marx2020predictive} formalized this risk as predictive multiplicity: a prediction problem admits competing models with conflicting predictions on individual inputs. \citet{damour2022underspecification} documented a related phenomenon, underspecification, showing that models trained from the same pipeline with different random seeds can disagree on individual predictions despite equivalent aggregate performance. \citet{mccoy2020berts} demonstrated a concrete NLP instance: BERT models trained from different random seeds diverge on specific linguistic constructions. These studies examine variation from initialization or training noise within a single architecture. Whether predictive multiplicity extends to hybrid recurrent architectures, where the source of variation is the recurrent backbone itself, remains unquantified. The question matters because practitioners increasingly choose between recurrent backbones based on aggregate benchmarks; if architectures that score identically in aggregate behave differently on individual inputs, such choices carry hidden consequences for deployment reliability and ensemble construction.
167	sections/introduction.tex-
168	sections/introduction.tex-We present the first systematic per-example analysis of how attention affects cross-architecture agreement in hybrid recurrent models. Using the model zoo of \citet{wang2025hybrid}, we compare three architectures (GatedDeltaNet, RetNet, HGRN2) at five attention ratios (0\% to 25\%) and two scales (340M and 1.3B parameters). These three architectures represent distinct approaches to linear recurrence: gated delta rules, multi-scale exponential decay, and gated state expansion. We evaluate all 30 configurations on 10 benchmarks spanning retrieval, comprehension, reasoning, and mixed task categories. On four benchmarks---LAMBADA ($N = 5{,}153$), HellaSwag ($N = 10{,}042$), PIQA ($N = 1{,}838$), and ARC-Easy ($N = 2{,}376$)---we conduct per-example decompositions, classifying each example as helped, hurt, or unchanged when attention is added, and measure cross-architecture overlap using Jaccard similarity. Figure~\ref{fig:decoupling} previews our central result: aggregate convergence and per-example divergence follow different trajectories as attention ratio increases.
169	--
170	sections/introduction.tex-Our contributions are as follows:
171	sections/introduction.tex-\begin{itemize}
172	sections/introduction.tex:    \item Unlike prior studies of seed-driven disagreement within a single architecture \citep{mccoy2020berts, damour2022underspecification}, we show that architectural variation---under matched training conditions---produces structured per-example predictive multiplicity with a task-dependent spectrum ($\alpha = 0.14$--$0.30$) across four benchmarks in three recurrent backbones. This multiplicity is not addressable by seed averaging: the source of variation is the recurrent backbone itself, and its magnitude is independent of aggregate convergence (\S\ref{ssec:per_example}, \S\ref{ssec:decoupling}, Table~\ref{tab:multiplicity}).
173	sections/introduction.tex-    \item We quantify task-specific convergence: only retrieval tasks (LAMBADA) show attention-driven cross-architecture convergence, and this pattern is scale-dependent (Appendix~\ref{app:scale_convergence}; \S\ref{ssec:task_convergence}, Table~\ref{tab:convergence}, Figure~\ref{fig:task_specificity}).
174	sections/introduction.tex-\end{itemize}
175	--
176	sections/related_work.tex-
177	sections/related_work.tex-\paragraph{Underspecification and Predictive Multiplicity.}
178	sections/related_work.tex:\citet{damour2022underspecification} formalized underspecification: equivalent aggregate performance can mask per-prediction divergence. Concrete NLP instances include seed-dependent BERT disagreement \citep{mccoy2020berts,sellam2022multiberts} and the four-phase convergence pattern of autoregressive LMs \citep{fehlauer2025convergence}. \citet{marx2020predictive} introduced predictive multiplicity as a complementary lens, showing that near-optimal models produce conflicting per-example predictions; extensions address probabilistic classification \citep{watson2023predictive}, Rashomon capacity \citep{hsu2022rashomon}, reconciliation \citep{du2025reconciling,haghighat2026resolving}, and cross-model disagreement as a correctness signal \citep{gorbett2026crossmodel}. These studies attribute divergence to initialization noise or the near-optimal set within a single architecture. We show that architectural variation in hybrid recurrent models produces analogous per-example multiplicity under matched training conditions.
179	=== paperno2016lambada ===
180	sections/introduction.tex-\end{figure}
181	sections/introduction.tex-
182	sections/introduction.tex:Our analysis yields three findings. First, per-example predictive multiplicity varies in magnitude across tasks, forming a task-dependent spectrum. The ambiguity $\alpha$ \citep{marx2020predictive} ranges from 0.14 (PIQA) through 0.15 (HellaSwag) and 0.21 (ARC-Easy) to 0.30 (LAMBADA), while pairwise Jaccard remains uniformly low ($\leq 0.10$, all $p < .01$). Within each benchmark, $\alpha$ is stable across attention ratios (variation $< 0.03$), but differs substantially across task types, ranging from 0.14 (reasoning) to 0.30 (retrieval). Second, attention-driven aggregate convergence is task-specific. Of 10 benchmarks, only LAMBADA exhibits monotonic reduction in cross-architecture variance ($\rho = -1.0$, BCa 95\% CI $[-1.0,\,-0.7]$; cross-architecture $\sigma$ drops 79\%). LAMBADA \citep{paperno2016lambada} is a pure context-retrieval task that requires predicting the final word of a passage from long-range dependencies; attention provides direct token-level access to the full context, which offers a natural explanation for why convergence occurs on this task and not others. Benchmarks that involve reasoning or comprehension show no convergence, with all $|\rho| \leq 0.7$ and $p \geq .233$. The Bonferroni-adjusted $p = .100$ does not survive strict correction at $\alpha = 0.05$; the confidence interval, which excludes zero, provides a complementary characterization of the effect. This convergence is scale-dependent: monotonic at 1.3B but non-monotonic at 340M (Appendix~\ref{app:scale_convergence}). On LAMBADA, aggregate $\sigma$ decreases gradually ($0.024 \to 0.005$) while per-example Jaccard saturates at 4\% attention (${\sim}0.09$)---the two quantities are decoupled. The experiments that follow begin with convergence (\S\ref{ssec:task_convergence}) because it establishes the aggregate backdrop against which per-example divergence (\S\ref{ssec:per_example}) and decoupling (\S\ref{ssec:decoupling}) are measured.
183	sections/introduction.tex-
184	sections/introduction.tex-Our contributions are as follows:
185	--
186	sections/method.tex-
187	sections/method.tex-\begin{itemize}
188	sections/method.tex:    \item \textbf{Retrieval}: LAMBADA \citep{paperno2016lambada}, which requires predicting a final word from long-range context without reasoning or world knowledge.
189	sections/method.tex-    \item \textbf{Comprehension}: BoolQ, a reading comprehension task with yes/no answers.
190	sections/method.tex-    \item \textbf{Reasoning}: HellaSwag, ARC-Challenge \citep{clark2018arc}, WinoGrande, and PIQA. COPA ($n = 100$) serves as a supplementary reasoning benchmark; its small sample size renders $\alpha$ estimation unreliable (CI width 0.13--0.18; Appendix~\ref{app:subsample_sensitivity}).
191	=== peng2024eagle ===
192	sections/introduction.tex-When attention layers are interleaved into recurrent architectures, they help and hurt almost entirely different examples---pairwise Jaccard overlap among three hybrid designs is at most 0.10, approximately twice the independence baseline. This per-example divergence is invisible in aggregate metrics: on LAMBADA, cross-architecture standard deviation drops 79\% as attention increases (Bonferroni-adjusted $p = .100$; the BCa 95\% CI excludes zero), but each architecture reaches similar accuracy by rescuing and disrupting different inputs. Practitioners increasingly choose between recurrent backbones based on aggregate benchmark scores; architectures that score identically in aggregate may thus carry hidden consequences for deployment reliability and ensemble construction.
193	sections/introduction.tex-
194	sections/introduction.tex:This tension arises in the context of a rapid architectural shift toward hybrid recurrent-attention models, which interleave attention layers within linear recurrent backbones. Jamba \citep{lieber2024jamba}, Griffin \citep{de2024griffin}, RWKV-6 \citep{peng2024eagle}, and RecurrentGemma \citep{botev2024recurrentgemma} each combine recurrence with attention using different mixing strategies. These systems now serve as production-grade alternatives to pure Transformers, and the practical question of how much attention to include is typically answered by comparing aggregate benchmark numbers. \citet{wang2025hybrid} provide a controlled model zoo spanning three recurrent architectures, five attention ratios, and two parameter scales, which enables systematic study of how attention allocation affects these hybrid designs.
195	sections/introduction.tex-
196	sections/introduction.tex-Most evaluations of hybrid architectures compare aggregate benchmark scores and report that a given attention ratio achieves a certain accuracy averaged across tasks or averaged across architectures. This practice can mask substantial per-example behavioral diversity. \citet{marx2020predictive} formalized this risk as predictive multiplicity: a prediction problem admits competing models with conflicting predictions on individual inputs. \citet{damour2022underspecification} documented a related phenomenon, underspecification, showing that models trained from the same pipeline with different random seeds can disagree on individual predictions despite equivalent aggregate performance. \citet{mccoy2020berts} demonstrated a concrete NLP instance: BERT models trained from different random seeds diverge on specific linguistic constructions. These studies examine variation from initialization or training noise within a single architecture. Whether predictive multiplicity extends to hybrid recurrent architectures, where the source of variation is the recurrent backbone itself, remains unquantified. The question matters because practitioners increasingly choose between recurrent backbones based on aggregate benchmarks; if architectures that score identically in aggregate behave differently on individual inputs, such choices carry hidden consequences for deployment reliability and ensemble construction.
197	--
198	sections/related_work.tex-
199	sections/related_work.tex-\paragraph{Hybrid Recurrent Architectures.}
200	sections/related_work.tex:The design space for combining attention with recurrence spans layer-level interleaving \citep[Jamba;][]{lieber2024jamba}, local attention pairing \citep[Griffin, RecurrentGemma;][]{de2024griffin,botev2024recurrentgemma}, matrix-valued recurrence \citep[RWKV-6;][]{peng2024eagle}, within-head mixing \citep[Hymba;][]{dong2024hymba}, and unbounded-context hybrid SSMs \citep[Samba;][]{ren2024samba}. Mamba-2 \citep{dao2024mamba2} establishes a duality between structured state spaces and attention; Mamba-3 \citep{lahoti2026mamba3} extends the design further, while \citet{ali2025hidden} reveal implicit attention within Mamba. Comparative evaluations confirm that hybrids outperform pure Transformers and SSMs at scale \citep{waleffe2024empirical}, and that even one attention layer enables content-based routing \citep{basu2026routing}. \citet{wang2025hybrid} provide the controlled model zoo we use, holding training conditions constant while varying architecture and attention ratio.
201	sections/related_work.tex-
202	sections/related_work.tex-\paragraph{Linear Recurrent Models.}
203	=== qin2024hgrn2 ===
204	sections/method.tex-\subsection{Model Zoo}\label{ssec:model_zoo}
205	sections/method.tex-
206	sections/method.tex:We use the pretrained model zoo of \citet{wang2025hybrid}, which provides controlled comparisons across architectures and attention ratios. The zoo contains three linear recurrent architectures: GatedDeltaNet \citep{yang2024gateddeltanet}, RetNet \citep{sun2023retnet}, and HGRN2 \citep{qin2024hgrn2}. These three architectures represent distinct approaches to linear recurrence: GatedDeltaNet uses gated delta rules, RetNet uses multi-scale exponential decay, and HGRN2 uses gated linear recurrence with state expansion. Each architecture is trained at five attention ratios: 0\% (pure recurrent), 4\%, 7.7\%, 14.3\%, and 25\%. We adopt the h$k$-1 notation from the original work, where one attention layer is interleaved per every $k{+}1$ total layers: h3-1 corresponds to 25\% attention, h6-1 to 14.3\%, h12-1 to 7.7\%, and h24-1 to 4\%. All configurations are available at two scales: 340M and 1.3B parameters. Within each scale, all models share identical training data, tokenizer, and hyperparameters; they differ only in architecture and attention configuration. This controlled design isolates the effect of attention from confounds such as training data or optimization differences. The zoo also includes a Transformer baseline (pure attention) at both scales.
207	sections/method.tex-
208	sections/method.tex-\subsection{Task Taxonomy}\label{ssec:task_taxonomy}
209	--
210	sections/related_work.tex-
211	sections/related_work.tex-\paragraph{Linear Recurrent Models.}
212	sections/related_work.tex:Our three recurrent backbones represent distinct gating strategies within the linear recurrence family: RetNet \citep{sun2023retnet} uses multi-scale exponential decay, HGRN2 \citep{qin2024hgrn2} applies gated state expansion, and GatedDeltaNet \citep{yang2024gateddeltanet} combines gated updates with delta rules. These descend from S4 \citep{gu2022s4} and Mamba \citep{gu2024mamba}, which introduced structured state spaces and input-dependent selection, respectively, and connect to linear attention \citep{katharopoulos2020transformers} through the state-space--attention duality of Mamba-2.
213	sections/related_work.tex-
214	sections/related_work.tex-\paragraph{Underspecification and Predictive Multiplicity.}
215	=== ren2024samba ===
216	sections/related_work.tex-
217	sections/related_work.tex-\paragraph{Hybrid Recurrent Architectures.}
218	sections/related_work.tex:The design space for combining attention with recurrence spans layer-level interleaving \citep[Jamba;][]{lieber2024jamba}, local attention pairing \citep[Griffin, RecurrentGemma;][]{de2024griffin,botev2024recurrentgemma}, matrix-valued recurrence \citep[RWKV-6;][]{peng2024eagle}, within-head mixing \citep[Hymba;][]{dong2024hymba}, and unbounded-context hybrid SSMs \citep[Samba;][]{ren2024samba}. Mamba-2 \citep{dao2024mamba2} establishes a duality between structured state spaces and attention; Mamba-3 \citep{lahoti2026mamba3} extends the design further, while \citet{ali2025hidden} reveal implicit attention within Mamba. Comparative evaluations confirm that hybrids outperform pure Transformers and SSMs at scale \citep{waleffe2024empirical}, and that even one attention layer enables content-based routing \citep{basu2026routing}. \citet{wang2025hybrid} provide the controlled model zoo we use, holding training conditions constant while varying architecture and attention ratio.
219	sections/related_work.tex-
220	sections/related_work.tex-\paragraph{Linear Recurrent Models.}
221	=== sellam2022multiberts ===
222	sections/related_work.tex-
223	sections/related_work.tex-\paragraph{Underspecification and Predictive Multiplicity.}
224	sections/related_work.tex:\citet{damour2022underspecification} formalized underspecification: equivalent aggregate performance can mask per-prediction divergence. Concrete NLP instances include seed-dependent BERT disagreement \citep{mccoy2020berts,sellam2022multiberts} and the four-phase convergence pattern of autoregressive LMs \citep{fehlauer2025convergence}. \citet{marx2020predictive} introduced predictive multiplicity as a complementary lens, showing that near-optimal models produce conflicting per-example predictions; extensions address probabilistic classification \citep{watson2023predictive}, Rashomon capacity \citep{hsu2022rashomon}, reconciliation \citep{du2025reconciling,haghighat2026resolving}, and cross-model disagreement as a correctness signal \citep{gorbett2026crossmodel}. These studies attribute divergence to initialization noise or the near-optimal set within a single architecture. We show that architectural variation in hybrid recurrent models produces analogous per-example multiplicity under matched training conditions.
225	=== sun2023retnet ===
226	sections/method.tex-\subsection{Model Zoo}\label{ssec:model_zoo}
227	sections/method.tex-
228	sections/method.tex:We use the pretrained model zoo of \citet{wang2025hybrid}, which provides controlled comparisons across architectures and attention ratios. The zoo contains three linear recurrent architectures: GatedDeltaNet \citep{yang2024gateddeltanet}, RetNet \citep{sun2023retnet}, and HGRN2 \citep{qin2024hgrn2}. These three architectures represent distinct approaches to linear recurrence: GatedDeltaNet uses gated delta rules, RetNet uses multi-scale exponential decay, and HGRN2 uses gated linear recurrence with state expansion. Each architecture is trained at five attention ratios: 0\% (pure recurrent), 4\%, 7.7\%, 14.3\%, and 25\%. We adopt the h$k$-1 notation from the original work, where one attention layer is interleaved per every $k{+}1$ total layers: h3-1 corresponds to 25\% attention, h6-1 to 14.3\%, h12-1 to 7.7\%, and h24-1 to 4\%. All configurations are available at two scales: 340M and 1.3B parameters. Within each scale, all models share identical training data, tokenizer, and hyperparameters; they differ only in architecture and attention configuration. This controlled design isolates the effect of attention from confounds such as training data or optimization differences. The zoo also includes a Transformer baseline (pure attention) at both scales.
229	sections/method.tex-
230	sections/method.tex-\subsection{Task Taxonomy}\label{ssec:task_taxonomy}
231	--
232	sections/related_work.tex-
233	sections/related_work.tex-\paragraph{Linear Recurrent Models.}
234	sections/related_work.tex:Our three recurrent backbones represent distinct gating strategies within the linear recurrence family: RetNet \citep{sun2023retnet} uses multi-scale exponential decay, HGRN2 \citep{qin2024hgrn2} applies gated state expansion, and GatedDeltaNet \citep{yang2024gateddeltanet} combines gated updates with delta rules. These descend from S4 \citep{gu2022s4} and Mamba \citep{gu2024mamba}, which introduced structured state spaces and input-dependent selection, respectively, and connect to linear attention \citep{katharopoulos2020transformers} through the state-space--attention duality of Mamba-2.
235	sections/related_work.tex-
236	sections/related_work.tex-\paragraph{Underspecification and Predictive Multiplicity.}
237	=== waleffe2024empirical ===
238	sections/related_work.tex-
239	sections/related_work.tex-\paragraph{Hybrid Recurrent Architectures.}
240	sections/related_work.tex:The design space for combining attention with recurrence spans layer-level interleaving \citep[Jamba;][]{lieber2024jamba}, local attention pairing \citep[Griffin, RecurrentGemma;][]{de2024griffin,botev2024recurrentgemma}, matrix-valued recurrence \citep[RWKV-6;][]{peng2024eagle}, within-head mixing \citep[Hymba;][]{dong2024hymba}, and unbounded-context hybrid SSMs \citep[Samba;][]{ren2024samba}. Mamba-2 \citep{dao2024mamba2} establishes a duality between structured state spaces and attention; Mamba-3 \citep{lahoti2026mamba3} extends the design further, while \citet{ali2025hidden} reveal implicit attention within Mamba. Comparative evaluations confirm that hybrids outperform pure Transformers and SSMs at scale \citep{waleffe2024empirical}, and that even one attention layer enables content-based routing \citep{basu2026routing}. \citet{wang2025hybrid} provide the controlled model zoo we use, holding training conditions constant while varying architecture and attention ratio.
241	sections/related_work.tex-
242	sections/related_work.tex-\paragraph{Linear Recurrent Models.}
243	=== watson2023predictive ===
244	sections/related_work.tex-
245	sections/related_work.tex-\paragraph{Underspecification and Predictive Multiplicity.}
246	sections/related_work.tex:\citet{damour2022underspecification} formalized underspecification: equivalent aggregate performance can mask per-prediction divergence. Concrete NLP instances include seed-dependent BERT disagreement \citep{mccoy2020berts,sellam2022multiberts} and the four-phase convergence pattern of autoregressive LMs \citep{fehlauer2025convergence}. \citet{marx2020predictive} introduced predictive multiplicity as a complementary lens, showing that near-optimal models produce conflicting per-example predictions; extensions address probabilistic classification \citep{watson2023predictive}, Rashomon capacity \citep{hsu2022rashomon}, reconciliation \citep{du2025reconciling,haghighat2026resolving}, and cross-model disagreement as a correctness signal \citep{gorbett2026crossmodel}. These studies attribute divergence to initialization noise or the near-optimal set within a single architecture. We show that architectural variation in hybrid recurrent models produces analogous per-example multiplicity under matched training conditions.
247	=== yang2024gateddeltanet ===
248	sections/method.tex-\subsection{Model Zoo}\label{ssec:model_zoo}
249	sections/method.tex-
250	sections/method.tex:We use the pretrained model zoo of \citet{wang2025hybrid}, which provides controlled comparisons across architectures and attention ratios. The zoo contains three linear recurrent architectures: GatedDeltaNet \citep{yang2024gateddeltanet}, RetNet \citep{sun2023retnet}, and HGRN2 \citep{qin2024hgrn2}. These three architectures represent distinct approaches to linear recurrence: GatedDeltaNet uses gated delta rules, RetNet uses multi-scale exponential decay, and HGRN2 uses gated linear recurrence with state expansion. Each architecture is trained at five attention ratios: 0\% (pure recurrent), 4\%, 7.7\%, 14.3\%, and 25\%. We adopt the h$k$-1 notation from the original work, where one attention layer is interleaved per every $k{+}1$ total layers: h3-1 corresponds to 25\% attention, h6-1 to 14.3\%, h12-1 to 7.7\%, and h24-1 to 4\%. All configurations are available at two scales: 340M and 1.3B parameters. Within each scale, all models share identical training data, tokenizer, and hyperparameters; they differ only in architecture and attention configuration. This controlled design isolates the effect of attention from confounds such as training data or optimization differences. The zoo also includes a Transformer baseline (pure attention) at both scales.
251	sections/method.tex-
252	sections/method.tex-\subsection{Task Taxonomy}\label{ssec:task_taxonomy}
253	--
254	sections/related_work.tex-
255	sections/related_work.tex-\paragraph{Linear Recurrent Models.}
256	sections/related_work.tex:Our three recurrent backbones represent distinct gating strategies within the linear recurrence family: RetNet \citep{sun2023retnet} uses multi-scale exponential decay, HGRN2 \citep{qin2024hgrn2} applies gated state expansion, and GatedDeltaNet \citep{yang2024gateddeltanet} combines gated updates with delta rules. These descend from S4 \citep{gu2022s4} and Mamba \citep{gu2024mamba}, which introduced structured state spaces and input-dependent selection, respectively, and connect to linear attention \citep{katharopoulos2020transformers} through the state-space--attention duality of Mamba-2.
257	sections/related_work.tex-
258	sections/related_work.tex-\paragraph{Underspecification and Predictive Multiplicity.}
259	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "47d4ebea-3a48-4c06-8a6d-af5fe97c7af8",
  "isSidechain": true,
  "promptId": "aeac6180-ae00-4058-bb9d-97b85fb92ee8",
  "agentId": "a5d47b67d0fecf656",
  "type": "user",
  "uuid": "72293b7e-7f81-4441-ae6e-50545ab38938",
  "sourceToolAssistantUUID": "47d4ebea-3a48-4c06-8a6d-af5fe97c7af8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/.claude/sessions/director_63b8b789",
  "sessionId": "765154e5-66a9-4450-b7d7-710330a17dfd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 20 · 2026-05-21T17:56:35.266Z_

Perfect! Now let me create a detailed summary of each key:

## Summary: Orphan Bib Key Status

Based on a thorough search of all .tex files in `/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/docs/paper/`, **ALL 30 reported "orphan" bib keys are ACTUALLY CITED** somewhere in the paper. The consistency checker's report was incorrect.

Here is the detailed breakdown:

1. **ali2025hidden**: CITED in `sections/appendix.tex` and `sections/related_work.tex` (via \citet and \citep)
2. **arora2024based**: CITED in `sections/appendix.tex` and `sections/experiments.tex` (via \citep)
3. **arora2024zoology**: CITED in `sections/appendix.tex` and `sections/experiments.tex` (via \citep)
4. **basu2026routing**: CITED in `sections/related_work.tex` (via \citep)
5. **botev2024recurrentgemma**: CITED in `sections/introduction.tex` and `sections/related_work.tex` (via \citep)
6. **clark2018arc**: CITED in `sections/method.tex` (via \citep)
7. **damour2022underspecification**: CITED in `sections/introduction.tex`, `sections/experiments.tex`, and `sections/related_work.tex` (via \citet and \citep)
8. **dao2024mamba2**: CITED in `sections/related_work.tex` (via \citep)
9. **de2024griffin**: CITED in `sections/introduction.tex` and `sections/related_work.tex` (via \citep)
10. **dong2024hymba**: CITED in `sections/related_work.tex` (via \citep)
11. **du2025reconciling**: CITED in `sections/related_work.tex` (via \citep)
12. **fehlauer2025convergence**: CITED in `sections/related_work.tex` (via \citep)
13. **gorbett2026crossmodel**: CITED in `sections/experiments.tex` and `sections/related_work.tex` (via \citep)
14. **gu2022s4**: CITED in `sections/related_work.tex` (via \citep)
15. **gu2024mamba**: CITED in `sections/related_work.tex` (via \citep)
16. **haghighat2026resolving**: CITED in `sections/related_work.tex` (via \citep)
17. **hsu2022rashomon**: CITED in `sections/related_work.tex` (via \citep)
18. **katharopoulos2020transformers**: CITED in `sections/related_work.tex` (via \citep)
19. **lahoti2026mamba3**: CITED in `sections/related_work.tex` (via \citep)
20. **lieber2024jamba**: CITED in `sections/introduction.tex` and `sections/related_work.tex` (via \citep)
21. **mccoy2020berts**: CITED in `sections/introduction.tex`, `sections/experiments.tex`, and `sections/related_work.tex` (via \citet and \citep)
22. **paperno2016lambada**: CITED in `sections/introduction.tex` and `sections/method.tex` (via \citep)
23. **peng2024eagle**: CITED in `sections/introduction.tex` and `sections/related_work.tex` (via \citep)
24. **qin2024hgrn2**: CITED in `sections/method.tex` and `sections/related_work.tex` (via \citep)
25. **ren2024samba**: CITED in `sections/related_work.tex` (via \citep)
26. **sellam2022multiberts**: CITED in `sections/related_work.tex` (via \citep)
27. **sun2023retnet**: CITED in `sections/method.tex` and `sections/related_work.tex` (via \citep)
28. **waleffe2024empirical**: CITED in `sections/related_work.tex` (via \citep)
29. **watson2023predictive**: CITED in `sections/related_work.tex` (via \citep)
30. **yang2024gateddeltanet**: CITED in `sections/method.tex` and `sections/related_work.tex` (via \citep)

The keys appear primarily in three sections:
- **sections/related_work.tex**: Contains most of the citations (dense cluster in the "Hybrid Recurrent Architectures" and "Underspecification and Predictive Multiplicity" paragraphs)
- **sections/introduction.tex**: Contains citations for hybrid architecture papers and predictive multiplicity references
- **sections/method.tex**: Contains citations for model zoo and benchmark papers
- **sections/experiments.tex**: Contains citations supporting experimental findings
- **sections/appendix.tex**: Contains citations supporting detailed analysis

This is a false positive from the consistency checker. None of these keys are actually orphaned.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "72293b7e-7f81-4441-ae6e-50545ab38938",
  "isSidechain": true,
  "agentId": "a5d47b67d0fecf656",
  "requestId": "req_011CbG9PGoc4q8w8qj1Brf5y",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "0840af95-001a-459a-b372-c67ef4d001ea",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/entrainment_gated_ft/.claude/sessions/director_63b8b789",
  "sessionId": "765154e5-66a9-4450-b7d7-710330a17dfd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01HSu1JRBMCXJ5zu5axAGw6e",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 19513,
      "cache_read_input_tokens": 49471,
      "output_tokens": 1268,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 19513
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 1268,
          "cache_read_input_tokens": 49471,
          "cache_creation_input_tokens": 19513,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 19513,
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
