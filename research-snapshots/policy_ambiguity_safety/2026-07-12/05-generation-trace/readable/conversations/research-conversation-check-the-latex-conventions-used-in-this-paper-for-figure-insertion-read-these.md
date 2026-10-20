# Research conversation: Check the LaTeX conventions used in this paper for figure insertion. Read these files: 1. /home/ubuntu/.agent-ml-researc

**Policy Ambiguity Is Nocuous: Clause-Level Causal Effects on Customer-Service Agent Safety (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 9
- **Recorded user turns:** 1
- **Tool calls:** 3
- **Original source:** `logs/chats/exported-trajectories/account-3/agent-ad182a86533afbf78.jsonl`
- **Structured JSON:** [`a0e37087dd1a4d434449.json`](../../sessions/a0/a0e37087dd1a4d434449.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Round 1

9 recorded events

### User

_source line 1 · 2026-05-24T08:44:20.212Z_

Check the LaTeX conventions used in this paper for figure insertion. Read these files:
1. /home/ubuntu/.agent-ml-research-be-idea-gen-0519-4/projects/policy_ambiguity_safety/docs/paper/sections/analysis.tex - look at the new figure I added (fig_convergent_nocuity) and compare its format with existing figures
2. /home/ubuntu/.agent-ml-research-be-idea-gen-0519-4/projects/policy_ambiguity_safety/docs/paper/sections/introduction.tex - look at fig:overview format
3. /home/ubuntu/.agent-ml-research-be-idea-gen-0519-4/projects/policy_ambiguity_safety/docs/paper/sections/experiments.tex - look at fig:variance_decomposition and fig:forest_plot format

Report: are there any format inconsistencies in the new figure insertion vs the existing ones? Check:
- figure vs figure* environment
- includegraphics width parameter
- caption style
- label naming convention
- placement specifier
- whether \ref calls use correct syntax (Figure~\ref vs \ref)

Brief report, under 200 words.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": true,
  "promptId": "c6318a7f-649a-4be2-bc1c-747622a98113",
  "agentId": "ad182a86533afbf78",
  "type": "user",
  "uuid": "543c6032-1d26-4fb8-85eb-8e86b2e61135",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-4/projects/policy_ambiguity_safety/.claude/sessions/paper_figure_add_1a4de744",
  "sessionId": "0216ed0a-c08b-49ce-97de-1409772cd735",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 2 · 2026-05-24T08:44:21.891Z_

I'll examine the LaTeX figure conventions in these three files to check for inconsistencies.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "543c6032-1d26-4fb8-85eb-8e86b2e61135",
  "isSidechain": true,
  "agentId": "ad182a86533afbf78",
  "requestId": "req_011CbM6iAYGdHAfPqmpLgR9o",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "a947aa58-0750-4a05-9fcb-ff10bb7db8e7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-4/projects/policy_ambiguity_safety/.claude/sessions/paper_figure_add_1a4de744",
  "sessionId": "0216ed0a-c08b-49ce-97de-1409772cd735",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_0149B2ktrbpHyDiJ4uW8znXb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 35885,
      "cache_read_input_tokens": 0,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 35885,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 7,
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

_source line 3 · 2026-05-24T08:44:22.383Z_

<details open><summary>🔧 Tool call — Read · `toolu_01KxbUw5bxCW5RiPEZcVc4m6`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-4/projects/policy_ambiguity_safety/docs/paper/sections/analysis.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a947aa58-0750-4a05-9fcb-ff10bb7db8e7",
  "isSidechain": true,
  "agentId": "ad182a86533afbf78",
  "requestId": "req_011CbM6iAYGdHAfPqmpLgR9o",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "ab3f35aa-5473-4b95-bca1-376d318aaa4f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-4/projects/policy_ambiguity_safety/.claude/sessions/paper_figure_add_1a4de744",
  "sessionId": "0216ed0a-c08b-49ce-97de-1409772cd735",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_0149B2ktrbpHyDiJ4uW8znXb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 35885,
      "cache_read_input_tokens": 0,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 35885,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 7,
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

_source line 4 · 2026-05-24T08:44:22.408Z_

<details><summary>↩ Tool result · `toolu_01KxbUw5bxCW5RiPEZcVc4m6`</summary>

```text
1	\section{Error Analysis \emph{[Exploratory]}}
2	\label{sec:analysis}
3	
4	\begin{figure}[t]
5	\centering
6	\includegraphics[width=\columnwidth]{figures/fig_type_mechanism.pdf}
7	\caption{Type--mechanism association (percentage of violation traces per type assigned to each failure mechanism). Each type maps to a dominant mechanism ($\geq$3/5 model consistency), supporting the taxonomy's diagnostic value (NMI $= 0.23$, Cram\'{e}r's $V = 0.45$, LLM-coded; human collapsed $\kappa = 0.34$--$0.52$).}
8	\label{fig:type_mechanism}
9	\end{figure}
10	
11	The following failure mode taxonomy emerges empirically from LLM-coded traces, distinct from the input ambiguity taxonomy (\S\ref{sec:taxonomy}).
12	
13	We analyze 614 violation traces across all five models, coded into five failure modes (Gwet's AC$_1$ $= 0.62$, $\kappa = 0.52$ \citep{gwet_2014,cohen_1960}); the coder prompt excludes ambiguity type labels, with type assigned post hoc. Using LLMs to code LLM failures risks circularity; however, type--mechanism mutual information (NMI $= 0.23$; Cram\'{e}r's $V = 0.45$, bootstrap 95\% CI $[0.41, 0.50]$; Appendix~\ref{app:type_mechanism}) provides structural evidence against this.\footnote{$V$ is computed on a $6\times 5$ table vs.\ $6\times 2$ for severity; higher dimensionality makes $V = 0.45$ conservative.} Human mechanism coding yields $\kappa = 0.15$, rising to $0.34$--$0.52$ after collapsing the spurious-compliance/structural-misparse boundary (Appendix~\ref{app:human_validation}); we treat $V = 0.45$ as an upper bound. The higher inter-coder agreement among LLMs ($\kappa = 0.52$) than humans ($\kappa = 0.15$) may partly reflect shared classification conventions---a meta-level parallel to the convergent nocuity documented below---so the following patterns are best interpreted as categorization tendencies rather than ground-truth assignments. Two of six mappings reflect partial definitional affinity (authorization scope$\to$boundary violation, incompleteness$\to$gap-filling); the remaining four (e.g., scopal$\to$structural misparse, 82.7\% consistency) are empirically derived.
14	
15	\subsection{Type-Specific Failure Mechanisms}
16	
17	Three failure patterns emerge ($\geq$3/5 cross-model consistency; Appendix~\ref{app:failure_details}): \emph{structural misparse}---incorrect parse commitment \citep{frazier_rayner_1982}---dominates scopal (5/5), conditional precedence (4/5), and coreferential (3/5); \emph{information gap-filling}---plausible but incorrect defaults---dominates incompleteness (3/5) and lexical (3/5); and \emph{boundary violation}---unauthorized escalation (69.2\%, $p < 10^{-4}$)---dominates authorization scope exclusively (5/5).
18	
19	\enlargethispage{28\baselineskip}
20	
21	\subsection{Disambiguation Neglect}
22	\label{sec:dn}
23	
24	Agents rarely recognize ambiguity: overall awareness is 4.6\%, with GPT-4.1 and Claude at 10--11\% while Qwen3 and DeepSeek show zero ($p = 2.2 \times 10^{-9}$; Appendix~\ref{app:awareness_breakdown}). We term this \emph{disambiguation neglect}---extending ambiguity collapse \citep{liu_ambiguity_2023,hu_ambiguity_2025} from the representational level to the behavioral level: agents act on collapsed readings without recognizing ambiguity, producing irreversible safety violations rather than mere accuracy degradation. Convergent nocuity (\S\ref{sec:nocuity}) further extends to the population level. A prompt-based mitigation (Appendix~\ref{app:mitigation}) confirms type-dependent effectiveness: authorization scope ($-$18.0\,pp), lexical ($-$8.9\,pp), but not incompleteness ($-$3.4\,pp, n.s.).
25	
26	\subsection{Convergent Nocuity}
27	\label{sec:nocuity}
28	
29	\begin{figure}[t]
30	\centering
31	\includegraphics[width=\columnwidth]{figures/fig_convergent_nocuity.pdf}
32	\caption{Convergent nocuity. (a)~Among majority-convergent violations ($\geq$3/5 models), 77\% reflect permissive interpretation; authorization scope shows near-universal permissive bias (99\%), while conditional precedence splits between permissive and restrictive. (b)~Pairwise Jaccard similarity of violation clause sets: cross-family mean (0.46) approaches within-family levels (0.54; dashed box), indicating convergence reflects shared architectural biases rather than training-data overlap.}
33	\label{fig:convergent_nocuity}
34	\end{figure}
35	
36	We adopt `nocuous' from \citet{berry_kamsties_2004}, but inverted: our agents exhibit \emph{convergent} rather than \emph{divergent} errors. Among ambiguous clauses, 41.3\% trigger majority-convergent violations ($\geq$3/5 models; 13.0\% unanimous)---we term this \emph{convergent nocuity}, invisible in agreement-based evaluation. These convergent violations exhibit a \emph{permissive attractor} (Figure~\ref{fig:convergent_nocuity}a): 77.0\% reflect permissive interpretation ($p \approx 0$; Appendix~\ref{app:attractor}). Cross-family violation co-occurrence (mean Jaccard $= 0.46$, $n = 9$ pairs; Figure~\ref{fig:convergent_nocuity}b) approaches within-family levels ($0.54$, $n = 1$), with three cross-family pairs within $0.05$ of the within-family rate, indicating convergent violations reflect shared architectural biases rather than training-data overlap (Appendix~\ref{app:cross_family}).
37	
38	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ab3f35aa-5473-4b95-bca1-376d318aaa4f",
  "isSidechain": true,
  "promptId": "c6318a7f-649a-4be2-bc1c-747622a98113",
  "agentId": "ad182a86533afbf78",
  "type": "user",
  "uuid": "71b894c5-bb8e-4a09-b1cf-34ad391e9db2",
  "sourceToolAssistantUUID": "ab3f35aa-5473-4b95-bca1-376d318aaa4f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-4/projects/policy_ambiguity_safety/.claude/sessions/paper_figure_add_1a4de744",
  "sessionId": "0216ed0a-c08b-49ce-97de-1409772cd735",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-24T08:44:22.605Z_

<details open><summary>🔧 Tool call — Read · `toolu_01CQWVVSrrtmdbsjKg6SnrLd`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-4/projects/policy_ambiguity_safety/docs/paper/sections/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "71b894c5-bb8e-4a09-b1cf-34ad391e9db2",
  "isSidechain": true,
  "agentId": "ad182a86533afbf78",
  "requestId": "req_011CbM6iAYGdHAfPqmpLgR9o",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "95614f80-0aca-4ace-b8d6-c465a8d73c8e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-4/projects/policy_ambiguity_safety/.claude/sessions/paper_figure_add_1a4de744",
  "sessionId": "0216ed0a-c08b-49ce-97de-1409772cd735",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_0149B2ktrbpHyDiJ4uW8znXb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 35885,
      "cache_read_input_tokens": 0,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 35885,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 7,
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

_source line 6 · 2026-05-24T08:44:22.618Z_

<details><summary>↩ Tool result · `toolu_01CQWVVSrrtmdbsjKg6SnrLd`</summary>

```text
1	\section{Introduction}
2	\label{sec:introduction}
3	
4	A customer asks to return a customized item within the 30-day window. The agent consults the store policy, which states that ``items may be returned within 30 days.'' The word ``items'' scopes over all product categories, including custom orders that are normally final sale. The agent grants a full refund and arranges free return shipping. One word of scopal ambiguity costs the retailer \$200.
5	
6	LLM-based agents increasingly operate under natural-language policy specifications that govern their permitted actions. These specifications inevitably contain ambiguity---a pilot audit of 407 clauses from 24 production policy documents finds a majority of clauses contain at least one ambiguity type (55--87\%, depending on union vs.\ intersection of two judges; $\kappa = 0.30$; Appendix~\ref{app:prevalence})---a property studied for decades in requirements engineering (RE) and computational linguistics. \citet{berry_kamsties_2004} distinguish between \emph{nocuous} (i.e., harmful) ambiguity, where different stakeholders arrive at different interpretations, and \emph{innocuous} ambiguity, where shared organizational context ensures convergent interpretation. Berry and Kamsties define nocuity in terms of stakeholder \emph{divergence}; convergent interpretation is assumed innocuous because consistency implies shared understanding. We document a distinct failure mode that breaks this assumption: LLM agents \emph{converge} on the same incorrect interpretation, making ambiguity harmful through systematic, undetectable error rather than inconsistency (\S\ref{sec:analysis}). Unlike human teams, where convergence reflects shared domain knowledge, agent convergence reflects shared training biases operating on identical inputs. We term this \emph{convergent nocuity}: Berry's nocuity criterion---predicated on divergent stakeholder interpretations---does not extend to LLM agents, where convergence reflects shared training biases rather than shared domain knowledge, and errors are invisible to agreement-based monitoring. In human RE workflows, most ambiguity is innocuous because developers share domain knowledge, can consult colleagues, and iteratively clarify requirements.
7	
8	LLM agents lack these disambiguation channels. They cannot consult colleagues, rarely escalate to users, and must resolve ambiguity in real time from the text alone. This raises a question that has not been empirically addressed: does policy ambiguity cause safety violations in LLM agents, and if so, does the \emph{type} of ambiguity predict the severity of the violation? Prior work classifies ambiguity types in policies \citep{drip_r_2026,li_ambiguity_taxonomy_2024} or measures policy understanding quality \citep{policybank_2026}, but no existing study provides a causal, type-granularity mapping from ambiguity to safety violations.
9	
10	\begin{figure*}[t]
11	\centering
12	\includegraphics[width=\textwidth]{figures/fig1_overview.pdf}
13	\caption{Experimental overview. We construct 300 matched clause pairs across a six-type, two-layer ambiguity taxonomy and inject them into $\tau^2$-bench policy documents. Five models interact with the modified policies across 2,997 episodes. A cross-judge evaluation pipeline classifies violation severity on a four-tier scale.}
14	\label{fig:overview}
15	\end{figure*}
16	
17	We address this gap with a matched-pair causal study on $\tau^2$-bench \citep{tau2_bench_2025}, a dual-control conversational agent benchmark. Using a six-type taxonomy organized into two layers---linguistic and specification (\S\ref{sec:taxonomy})---we construct 300 ambiguous/unambiguous clause pairs and evaluate five architecturally diverse models across 2,997 episodes.
18	
19	Our results reveal a \emph{type--mechanism dissociation}: policy ambiguity consistently increases violations ($+34.0$\,pp under synthetic conditions; $+31.0$\,pp excluding incompleteness), but ambiguity \emph{type} predicts \emph{how} agents fail, not \emph{whether} they fail. Clause wording explains 22.4\% of violation variance while type membership explains only 0.4\%; yet type predicts failure mechanism substantially more strongly than violation rate (NMI $= 0.23$ vs.\ $0.01$; Cram\'{e}r's $V = 0.45$ vs.\ $0.14$ on tables of different dimensionality; Appendix~\ref{app:type_mechanism}). This dissociation suggests viewing the taxonomy as a diagnostic instrument rather than a risk classifier (\S\ref{sec:discussion}). Incompleteness is the highest-risk type (46--62\%); the remaining types form a partial ordering with robust extremes but margin-dependent mid-tier structure (Table~\ref{tab:tost_sensitivity}).
20	
21	Our contributions are: (1)~a matched-pair causal study establishing that policy ambiguity increases violations by $+$34.0\,pp ($+$18.7\,pp for the confound-minimized coreferential type) in customer-service domains, with clause wording---not type membership---as the primary risk factor (22.4\% vs.\ 0.4\% of variance; \S\ref{sec:results}); (2)~\emph{convergent nocuity}---41.3\% of ambiguous clauses trigger majority-convergent violations across architecturally diverse models (cross-family Jaccard $= 0.46$, approaching within-family $0.54$), with 77\% permissive bias and 4.6\% disambiguation awareness, rendering agreement-based safety monitoring blind to the most systematic failures (\S\ref{sec:analysis}); and (3)~a \emph{type--mechanism dissociation} ($V = 0.45$, 95\% CI $[0.41, 0.50]$, LLM-coded; human $\kappa = 0.34$--$0.52$ collapsed; \S\ref{sec:analysis}), where each type maps to a dominant failure mechanism with $\geq$3/5 cross-model consistency, providing initial evidence that the taxonomy functions as a diagnostic instrument.
22	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "95614f80-0aca-4ace-b8d6-c465a8d73c8e",
  "isSidechain": true,
  "promptId": "c6318a7f-649a-4be2-bc1c-747622a98113",
  "agentId": "ad182a86533afbf78",
  "type": "user",
  "uuid": "6528016b-d72e-4668-bd1e-f926ac75efae",
  "sourceToolAssistantUUID": "95614f80-0aca-4ace-b8d6-c465a8d73c8e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-4/projects/policy_ambiguity_safety/.claude/sessions/paper_figure_add_1a4de744",
  "sessionId": "0216ed0a-c08b-49ce-97de-1409772cd735",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-24T08:44:22.681Z_

<details open><summary>🔧 Tool call — Read · `toolu_0138WSGnncUyW8mDBj9juYdL`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-4/projects/policy_ambiguity_safety/docs/paper/sections/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6528016b-d72e-4668-bd1e-f926ac75efae",
  "isSidechain": true,
  "agentId": "ad182a86533afbf78",
  "requestId": "req_011CbM6iAYGdHAfPqmpLgR9o",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "2342bbcd-b68f-4ba8-976c-badd013c70fb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-4/projects/policy_ambiguity_safety/.claude/sessions/paper_figure_add_1a4de744",
  "sessionId": "0216ed0a-c08b-49ce-97de-1409772cd735",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_0149B2ktrbpHyDiJ4uW8znXb",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 35885,
      "cache_read_input_tokens": 0,
      "output_tokens": 265,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 35885
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 265,
          "cache_read_input_tokens": 0,
          "cache_creation_input_tokens": 35885,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 35885,
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

_source line 8 · 2026-05-24T08:44:22.687Z_

<details><summary>↩ Tool result · `toolu_0138WSGnncUyW8mDBj9juYdL`</summary>

```text
1	\section{Results}
2	\label{sec:results}
3	
4	We organize results around three analyses: the binary ambiguity effect (C1), the type partial ordering (C2, including the inconclusive layer effect C3), and the model$\times$type interaction (C4). C1 and C2 are primary supported claims; C3 (layer effect) is inconclusive; C4 (model$\times$type interaction) is exploratory.
5	
6	\enlargethispage{8\baselineskip}
7	\subsection{Binary Ambiguity Effect (C1)}
8	
9	\begin{figure}[t]
10	\centering
11	\includegraphics[width=\columnwidth]{figures/fig_variance_decomposition.pdf}
12	\caption{Variance decomposition of violation rates (temperature $= 0$). Clause identity: 22.4\% (0.4\% between types); condition: 15.8\%; model: 1.0\%; residual: 60.8\%. Clause wording---not type membership---is the primary risk factor.}
13	\label{fig:variance_decomposition}
14	\end{figure}
15	
16	Across all five models and six types, ambiguous clauses increase violation rates by 34.0 pp (41.0\% vs.\ 6.9\%, McNemar OR $= 15.1$ (based on $n = 580$ discordant pairs), 95\% CI $[10.78, 21.17]$, $p < 10^{-105}$). All six types individually produce significant increases (all $p < 10^{-5}$) across both domains (Appendix~\ref{app:cross_domain}), and all five models show large effects ($+25.7$ to $+39.0$ pp, all $p < 10^{-17}$). Perturbation controls confirm specificity to semantic ambiguity (\S\ref{sec:method}). Figure~\ref{fig:variance_decomposition} decomposes violation-rate variance\footnote{Type III SS; logistic regression (Appendix~\ref{app:regression}) confirms concordant results (Tjur's $R^2 = 0.175$; \citealp{tjur_2009}).}: clause identity explains 22.4\% (0.4\% between types, 22.0\% within), condition 15.8\%, model 1.0\%, and residual 60.8\% ($\sim$15\% stochastic, $\sim$46\% systematic; Appendix~\ref{app:residual}). A permutation test confirms that clause wording---not type membership---drives this variance ($p < 0.001$; Appendix~\ref{app:clause_variance}); surface linguistic features predict clause-level risk modestly ($R^2 = 0.069$; Appendix~\ref{app:clause_predictors}). The incompleteness effect ($+$49.2\,pp) is an upper bound: the unambiguous variant necessarily adds policy content, introducing an information-addition confound that token-count matching cannot address (Appendix~\ref{app:confound}). Excluding incompleteness, the effect is $+$31.0\,pp (95\% CI $[27.9, 34.1]$; Appendix~\ref{app:sans_incompleteness}), ranging from $+$18.7\,pp (coreferential) to $+$36.0\,pp (authorization scope). Coreferential ambiguity requires minimal lexical change ($\Delta$token $\approx 7.8$ words) yet still produces $+$18.7\,pp violations, providing direct evidence of an ambiguity-only effect (Appendix~\ref{app:confound}). Per-type mean token difference (Appendix~\ref{app:clause_length}) and violation rate are correlated (Spearman $\rho = 0.94$, $p = 0.005$, $n = 6$), but this reflects ambiguity severity as a common cause rather than information-addition as a confounder: the perturbation control ($\Delta = -0.67$\,pp) rules out non-semantic textual additions, and token-count logistic regression yields $\beta = +0.027$ (longer clauses predict more violations), consistent with a clause-complexity interpretation but uninformative about within-pair information addition. More broadly, coreferential ambiguity ($+$18.7\,pp) isolates the ambiguity-only effect; types with large $\Delta$token (incompleteness, authorization scope) conflate ambiguity resolution with information addition.
17	
18	Replication on two additional models confirms the effect across seven models ($\Delta = +20.0$ to $+33.6$\,pp; Appendix~\ref{app:model_expansion}); SOPBench~\citep{li_sopbench_2025} confirms directional consistency ($+12.7$\,pp unweighted mean; Appendix~\ref{app:sopbench}). The taxonomy predicts failure mechanisms more strongly than violation rate (NMI $= 0.23$ vs.\ $0.01$; $V = 0.45$ vs.\ $0.14$ on tables of different dimensionality; Appendix~\ref{app:type_mechanism}), making type-level analysis (C2--C4) informative for diagnosis.
19	
20	\FloatBarrier
21	\subsection{Type Partial Ordering (C2)}
22	
23	\begin{table*}[t]
24	\centering
25	\caption{Violation rates (\%) under ambiguous policy clauses by type and model (5.4 = GPT-5.4, 4.1 = GPT-4.1, Cla.\ = Claude, Qw3 = Qwen3, DS = DeepSeek). $\Delta$pp: pooled difference (ambiguous $-$ unambiguous) with Newcombe 95\% CIs. Cluster: TOST equivalence cluster at $\pm 15$\,pp---U = upper bound (separated at all margins), M = mid-tier (6/6 pairwise equivalent), L = lower (separates at $\pm 12$\,pp). All per-type $p < 10^{-5}$ (Fisher's exact).}
26	\label{tab:main_results}
27	\footnotesize
28	\setlength{\tabcolsep}{3.8pt}
29	\begin{tabular}{llrrrrrrr@{\hskip 6pt}cr}
30	\toprule
31	Layer & Type & Pooled & 5.4 & 4.1 & Cla. & Qw3 & DS & $\Delta$pp\,[95\% CI] & Cl. & $p$ \\
32	\midrule
33	\multirow{3}{*}{\textcolor{speccolor}{Spec.}} & Incompleteness$^\dagger$ & 53.6 & 46 & 58 & 48 & 62 & 54 & +49.2\,[42.2, 55.6] & U & $<\!10^{-37}$ \\
34	 & Auth.\ Scope$^\ddagger$ & 41.6 & 64 & 46 & 12 & 26 & 60 & +36.0\,[29.1, 42.6] & M & $<\!10^{-22}$ \\
35	 & Cond.\ Prec. & 36.8 & 34 & 36 & 36 & 40 & 38 & +30.8\,[24.0, 37.4] & M & $<\!10^{-17}$ \\
36	\midrule
37	\multirow{3}{*}{\textcolor{lingcolor}{Ling.}} & Lexical & 42.8 & 42 & 34 & 32 & 52 & 54 & +35.2\,[28.0, 42.0] & M & $<\!10^{-20}$ \\
38	 & Scopal & 39.4 & 42 & 38 & 32 & 37 & 48 & +34.2\,[27.4, 40.7] & M & $<\!10^{-21}$ \\
39	 & Coreferential & 31.6 & 18 & 32 & 22 & 42 & 44 & +18.7\,[11.5, 25.7] & L & $<\!10^{-6}$ \\
40	\midrule
41	\multicolumn{2}{l}{\textbf{Overall}} & \textbf{41.0} & 41 & 41 & 30 & 43 & 50 & \textbf{+34.0}\,[31.3, 36.9] & --- & $<\!10^{-105}$ \\
42	\bottomrule
43	\end{tabular}
44	
45	\vspace{2pt}
46	{\footnotesize $\dagger$\,Subject to information-addition confound; see \S\ref{sec:results} and Appendix~\ref{app:confound}. $\ddagger$\,Lowest inter-judge agreement ($\kappa = 0.385$, per-type calibration $n \approx 17$); $\Delta$token$\,= 36.1$ words, subject to information-addition confound analogous to incompleteness; see \S\ref{sec:results}. Excluding incompleteness: pooled $\Delta = +31.0$\,pp (95\% CI $[27.9, 34.1]$).}
47	\end{table*}
48	
49	The six types are not interchangeable. An omnibus $\chi^2$ test on ambiguous-condition violation rates rejects the uniformity null ($\chi^2 = 28.02$, $df = 5$, $p = 3.6 \times 10^{-5}$, Cram\'{e}r's $V = 0.137$). Table~\ref{tab:tost_sensitivity} reveals a margin-dependent equivalence structure: three types achieve equivalence at $\pm 10$\,pp, five at $\pm 12$\,pp, and all six at $\pm 15$\,pp; we present the full sensitivity analysis without anchoring to a single margin. The NMI comparison ($0.23$ vs.\ $0.01$) is threshold-independent. Table~\ref{tab:main_results} and Figure~\ref{fig:forest_plot} present the full breakdown.
50	
51	Bootstrap clustering ($B = 10{,}000$; Appendix~\ref{app:cluster}) confirms stable extremes across all margins. Cross-model concordance is moderate ($W = 0.398$, $p = 0.072$; Appendix~\ref{app:kendall_w}).
52	
53	An important qualification: cross-judge validation with three independent evaluation models yields pairwise type-ranking concordance $\rho = 0.71$--$0.89$ (Appendix~\ref{app:cross_judge}), indicating substantial stability when model composition is held constant. The two-group ranking ($\rho = 0.09$; Appendix~\ref{app:judge_group_ranking}) reflects differential model vulnerability to authorization scope$^\ddagger$ (12\%--64\% range), not type ranking instability: when the same models are evaluated by all three judges, type rankings are concordant. The partial ordering thus has robust extremes---incompleteness as upper bound and coreferential as lower bound, replicated across all seven models and three judges---with model-composition-dependent mid-tier structure.
54	
55	Incompleteness ranks highest in four of five models ($\geq$46\% in all seven; Appendix~\ref{app:model_expansion}); its 49.2\,pp effect is an upper bound (Appendix~\ref{app:confound}). C3 (layer grouping) did not survive Holm--Bonferroni ($p = 0.017$, threshold $0.0125$).
56	
57	\begin{figure}[!ht]
58	\centering
59	\includegraphics[width=\columnwidth]{figures/fig2_forest_plot.pdf}
60	\caption{Per-type effect sizes ($\Delta$pp) with Newcombe 95\% CIs (overall: $+$34.0\,pp, OR $= 15.1$). Types form a partial ordering: incompleteness as upper bound (conditional on information-addition confound), coreferential as lower bound, and a mid-range equivalence cluster. Mid-tier ordering is margin-dependent (\S\ref{sec:results}).}
61	\label{fig:forest_plot}
62	\end{figure}
63	
64	\enlargethispage{18\baselineskip}
65	\label{sec:c4}C4 (model$\times$type interaction) is exploratory. The interaction is driven entirely by authorization scope (Claude 12\% vs.\ GPT-5.4/DeepSeek $>$60\%; Figure~\ref{fig:heatmap}, Appendix~\ref{app:c4_sans_auth}); excluding it, the interaction vanishes ($p = 0.97$; Appendix~\ref{app:sans_auth} extends this to all primary analyses). Cross-judge validation confirms model rankings (Fleiss' $\kappa = 0.717$; Appendix~\ref{app:cross_judge}).
66	
67	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "2342bbcd-b68f-4ba8-976c-badd013c70fb",
  "isSidechain": true,
  "promptId": "c6318a7f-649a-4be2-bc1c-747622a98113",
  "agentId": "ad182a86533afbf78",
  "type": "user",
  "uuid": "57671301-a0be-407f-bdd6-c0950cbef05f",
  "sourceToolAssistantUUID": "2342bbcd-b68f-4ba8-976c-badd013c70fb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-4/projects/policy_ambiguity_safety/.claude/sessions/paper_figure_add_1a4de744",
  "sessionId": "0216ed0a-c08b-49ce-97de-1409772cd735",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 9 · 2026-05-24T08:44:28.881Z_

**Format Consistency Report**

**Inconsistencies Found:**

1. **Figure Environment**: All three existing figures use `figure[t]` (single-column), but `fig:overview` in introduction.tex uses `figure*[t]` (double-column). The new fig_convergent_nocuity correctly uses `figure[t]`, matching the majority standard in analysis.tex and experiments.tex.

2. **Width Parameter**: All figures consistently use `[width=\columnwidth]` except `fig:overview` which uses `[width=\textwidth]` for its two-column layout. The new figure correctly uses `[width=\columnwidth]`.

3. **Caption Style**: Consistent across all—uses plain text with inline LaTeX math where needed. New caption follows this pattern correctly.

4. **Label Naming**: All follow `\label{fig:name}` convention consistently. The new label `fig:convergent_nocuity` follows this correctly.

5. **Placement Specifier**: Most use `[t]` (top). New figure matches this.

6. **Reference Syntax**: **CRITICAL ISSUE**: 
   - Analysis.tex line 36 uses `Figure~\ref{fig:convergent_nocuity}` (correct)
   - But experiments.tex line 59 uses bare `\ref{fig:forest_plot}` in caption without "Figure" prefix
   - Introduction.tex uses `Figure~\ref{fig:overview}` (correct)
   
   The new figure caption is cited correctly with `Figure~\ref{...}`, but the paper is inconsistent overall.

**Summary**: The new fig_convergent_nocuity is well-formatted and matches the single-column standard. The only real concern is inconsistent reference syntax in existing captions (some use "Figure~\ref", others just "\ref"), but the new figure adheres to the better convention.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "57671301-a0be-407f-bdd6-c0950cbef05f",
  "isSidechain": true,
  "agentId": "ad182a86533afbf78",
  "requestId": "req_011CbM6iM91Fc1j9mpW7T13C",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "b5888517-c41c-473a-964c-1b0fa89da42b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-4/projects/policy_ambiguity_safety/.claude/sessions/paper_figure_add_1a4de744",
  "sessionId": "0216ed0a-c08b-49ce-97de-1409772cd735",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01Nqso5P7YiqQCT4rx3yZJ4N",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 7,
      "cache_creation_input_tokens": 7775,
      "cache_read_input_tokens": 35885,
      "output_tokens": 436,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 7775
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 7,
          "output_tokens": 436,
          "cache_read_input_tokens": 35885,
          "cache_creation_input_tokens": 7775,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 7775,
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
