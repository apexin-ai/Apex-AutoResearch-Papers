# Research conversation: [Director 指令] [Patch — 修正] effective_rank 框架纠正 + 新引用 ## effective_rank 框架修正（重要） 之前在 D128 Detection Hierarchy 中我可能把 effec — Part 4 of 55

**Characterizing the Detectability Landscape of Iterative Model Collapse (July export snapshot)** · Conversation logs

[← Part 3](part-003.md) · [Transcript overview](../research-conversation-director-patch-effective-rank-effective-rank-d128-detection-hierarchy-effec.md) · [Part 5 →](part-005.md) · [Structured JSON](../../../sessions/a8/a8e0ebae48d08b0112dc.json)

## Round 29

### User

_source line 739 · 2026-05-20T10:04:32.917Z_

This session is being continued from a previous conversation that ran out of context. The summary below covers the earlier portion of the conversation.

Summary:
1. Primary Request and Intent:
   The Paper Agent session handles a series of Director Patch directives for the `distrib_canary_collapse` EMNLP 2026 paper, culminating in a major Reframe directive (D130).
   
   **Completed Patches (in order):**
   - **Patch 2 Phase E**: Verification of the 5-regime non-monotonic framework (carried over from prior context)
   - **Patch 3**: Replace 5-regime/τ_H/τ_D framework with simpler S×R (Signal × Resolution) 4-regime competition model
   - **Patch 4**: Add three cross-disciplinary connections (Hormesis, Zero-lag Granger failure, Critical speeding-up)
   - **Patch 5**: D127 Track D phase transition results (sigmoid fit α_c=0.476) + replace hallucinated `gu2025datamixing` with `gu2024cmr`
   - **Patch 6**: Mark CSD as inconclusive at T=11 (Director constraint)
   - **Patch 7**: D129 four theory upgrades — detection phase transition claim, T-dependence predictions, robust onset across architectures, three-layer taxonomy
   - **Patch 8**: Per-generation signal threshold paragraph (cumulative contamination ≠ detection)
   - **Patch 9**: CSD suggestive evidence + upgrade to four-layer detection taxonomy
   - **Gu citation clarification**: Confirmed `gu2025datamixing` already replaced, asked Director for decision
   
   **Pending Reframe (D130):** Transform paper from "Method Matters" methodology paper to "Detection Phase Transition Discovery" paper. Requires writing_plan.yaml generation for Director approval before execution. Target: EMNLP 2026 ARR June cycle, 8-page main text.

2. Key Technical Concepts:
   - **S×R Competition Model**: Detectability(α) ∝ S(α) × R(α), where S = signal strength (monotonic), R = temporal resolution (non-monotonic due to relaxation time matching)
   - **Four regimes**: Blind (α≤0.45), Onset (α≈0.50), Synchronous dip (α≈0.60), Detection (α≥0.75)
   - **Detection Phase Transition**: Near-discontinuous onset at α_c=0.476 (sigmoid R²=0.969, k≥200, Δα≈0.02)
   - **Per-generation signal threshold**: Δh(g) ∝ α · d_TV(p_g^model, p^real); detection depends on per-generation SNR, not cumulative contamination C(α,G) = 1-(1-α)^G
   - **Four-layer detection taxonomy**: (1) Distributional dimensionality/erank (onset ~0.10, established), (2) Distributional instability/variance (onset ~0.25, suggestive), (3) Causal coupling/PermG (onset ~0.50, established), (4) Dynamical stability/AC1 (onset ~0.50, suggestive)
   - **Cross-disciplinary connections**: Hormesis (Calabrese 2003), zero-lag Granger failure (Deshpande 2010), critical speeding-up (Titus 2020)
   - **CSD at T=11**: Suggestive but not conclusive — AC1 jump +0.30 at onset, variance 10× at α=0.25, but 95% CI ≈ ±0.3
   - **Terminology constraints**: "detection phase transition" OK, "phase transition" alone too strong; "sharp onset"/"near-discontinuous onset" OK; "robust across architectures" OK, "universal" too strong; CSD = "suggestive" not "confirmed"

3. Files and Code Sections:
   - **`/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/method.tex`**
     - Core theoretical motivation section (§5.4). Most heavily edited file.
     - v94: S×R 4-regime framework with equation \label{eq:detectability}
     - v95: effective_rank paragraph synced to R(α) terminology
     - v100: Cross-disciplinary connections (hormesis, zero-lag GC, speeding-up)
     - v102: Gu citation updated to gu2024cmr + α_c=0.476 integrated
     - v106: "phase transition in detection" → "near-discontinuous onset of detection"
     - v116: New "Detection threshold vs. accumulated contamination" paragraph with C(α,G) formula and per-generation signal Δh(g)
     - v120: "two layers" → "four complementary detection channels"
     - Key content at lines ~299-355: S×R framework, regime enumeration, cross-disciplinary connections, per-generation threshold, effective rank, four-layer channels, phase transition theory
   
   - **`/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/experiments.tex`**
     - v97-98: Four regimes in figure caption and body text
     - v104: "Quantifying the onset boundary" paragraph (sigmoid fit, Figure float with commented \includegraphics)
     - v105: "near-discontinuous onset" terminology fix
     - v108: Effective contamination comparison + "detection phase transition" terminology
     - v109: "Predictions for longer generation chains" paragraph (T=20 predictions)
     - v110: Architecture-independent onset claim in generalization section
     - v117: Fixed "<0.1%" → "0.15 percentage points" with precise formula
   
   - **`/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/discussion.tex`**
     - v99: Synchronous collapse paragraph — S×R terminology
     - v103: Gu citation → gu2024cmr in future work
     - v113: Three-layer detection taxonomy (later superseded)
     - v119: Four-layer detection taxonomy + "Suggestive CSD signatures" paragraph (~150 words)
   
   - **`/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/introduction.tex`**
     - v96: "five-regime" → "four-regime" + "signal-times-resolution framework"
     - v112: Contribution 3 → "detection phase transition" + sigmoid quantification
     - v118: "<0.1%" → "0.15 percentage points"
   
   - **`/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/abstract.tex`**
     - v111: Added "detection phase transition" with α_c, R², Δα
     - v115: Precision fix 0.48→0.476, 0.97→0.969
   
   - **`/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/references.bib`**
     - Replaced `gu2025datamixing` (hallucination) with `gu2024cmr` (EMNLP 2024, arXiv:2407.17467)
     - Added `calabrese2003hormesis` (Nature 421, DOI:10.1038/421691a)
     - Added `deshpande2010instantaneous` (NeuroImage 54(2), DOI:10.1016/j.neuroimage.2010.09.024)
     - Added `titus2020speeding` (Theoretical Ecology 13, DOI:10.1007/s12080-020-00451-0)
     - `dakos2012methods` already existed from prior patch
   
   - **`/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/related_work.tex`**
     - v101: Gu citation updated to gu2024cmr + description adjusted
   
   - **`/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/limitations.tex`**
     - v107: CSD T=11 limitation sentence added
     - v114: "sharp or gradual" → answered by sigmoid, remaining open = scale/domain

4. Errors and Fixes:
   - **Edit tool parameter names**: Used `old_text`/`new_text` instead of `old_string`/`new_string` for the Edit tool (not edit_paper_section). Fixed by using correct parameter names.
   - **Abstract precision mismatch** (check_paper_consistency critical): Abstract used rounded 0.48/0.97, experiments used 0.476/0.969. Fixed by updating abstract to match full precision (v115).
   - **"<0.1%" inconsistency**: D129 Direction 1 said "<0.1%" but precise calculation gives 0.15 pp. Fixed across experiments.tex (v117) and introduction.tex (v118) to say "0.15 percentage points" with formula.
   - **paper_compile_and_check UTF-8 error**: Pre-existing MCP tool issue with binary PDFs. Workaround: manual pdflatex + bibtex compilation via Bash.
   - **fig_phase_transition.pdf missing locally**: File on remote server (westd-17855) only. Workaround: commented `\includegraphics`, kept figure float + label functional. Flagged in Director report.
   - **Duplicate Director instruction** (cross-disciplinary connections sent twice): Correctly identified as already completed, reported to Director without re-executing.
   - **Gu citation confusion**: Director sent instruction to fix `gu2025datamixing` venue (ICLR→NeurIPS) but it was already replaced with `gu2024cmr`. Correctly identified and asked Director for decision.

5. Problem Solving:
   - **5-regime → S×R 4-regime**: Successfully replaced the two-timescale (τ_H/τ_D) framework with the simpler S×R competition model across all files, eliminating all residual terminology
   - **Cumulative contamination calculation**: Verified C(0.45,10)=99.75%, C(0.50,10)=99.90% via Python, confirming 0.15 pp difference at displayed precision
   - **Terminology compliance**: Systematically grepped for prohibited terms ("phase transition" on own data, "universal", "CSD confirmed") and fixed 2 instances of "phase transition" describing own results
   - **Cross-file consistency**: Each patch included systematic grep for residual old terminology + check_paper_consistency + compilation verification
   - **Citation verification**: All new citations (Calabrese, Deshpande, Titus, Gu 2024 CMR) verified via WebSearch before adding to bib

6. All User Messages:
   - "Continue from where you left off." (multiple times — resumption prompts)
   - "[Director 指令] [P0 URGENT — 覆盖之前的修正指令] 理论非单调性：S×R 竞争模型" — Replace 5-regime with S×R 4-regime
   - "[Director 指令] [Patch — 补充] S×R 理论 + 跨学科三连接" — Add Hormesis, Deshpande, Titus connections
   - "[Director 指令] [Patch — 跨学科框架] α=0.60 DIP 的三个文献连接" — Duplicate of above (already completed)
   - "[Director 指令] [Patch — D127 Track D 结果 + 引用修正] Phase Transition 数据 + Dakos BibTeX" — Sigmoid fit results + Gu hallucination fix
   - "[Director 指令] [约束更新] D127 Track A CSD = inconclusive，不作为论文证据" — CSD unreliable at T=11
   - "[Director 指令] [Patch — D129] 4 条理论升级方向整合" — Detection phase transition, T-dependence, robust onset, three-layer taxonomy
   - "[Director 指令] [Patch — D129 核心理论] Per-Generation Signal Threshold 段落" — Cumulative vs per-generation contamination
   - "[Director 指令] [引用修正] gu2025datamixing venue 错误" — Gu venue fix (already handled)
   - "[Director 指令] [Patch — CSD Discussion + Four-Layer Taxonomy 更新]" — CSD suggestive evidence + four-layer taxonomy
   - "[Director 指令] [Reframe — D130] 论文从 Methodology Paper 转型为 Detection Phase Transition Discovery Paper" — Major reframe for EMNLP 2026
   - Multiple "[系统提醒]" about calling main_agent_post_to_director (false alarms — paper_agent_post_to_director was called correctly)

7. Pending Tasks:
   - **D130 Reframe execution**: Generate writing_plan.yaml for the paper transformation from methodology paper to discovery paper. Director explicitly said "请生成 writing_plan.yaml 提交我审批" (generate writing_plan.yaml for my approval).
   - **fig_phase_transition.pdf transfer**: Figure needs to be transferred from westd-17855 to local paper/figures/
   - **Gu 2025 decision**: Director needs to decide whether to restore `gu2025datamixing` (as NeurIPS 2025 Spotlight) alongside `gu2024cmr`, or keep only `gu2024cmr`
   - **Note on regime count**: D130 says "Predicts 5 regimes: blind → onset → sync dip → recovery → saturation" in C2, but current paper has 4 regimes. This needs clarification — the Reframe may intend to restore 5 regimes.

8. Current Work:
   The most recent Director instruction is **[Reframe — D130]**, a major paper transformation from "Method Matters" methodology paper to "Detection Phase Transition Discovery Paper" targeting EMNLP 2026. The Director explicitly requests: "请生成 writing_plan.yaml 提交我审批" — generate writing_plan.yaml for approval before any writing begins.
   
   This is a **Reframe** operation (per CLAUDE.md: "Reframe 全文重构"), not an incremental Patch. Per the Paper Agent protocol, when Director sends `[FRAMING APPROVED]` + new narrative + affected sections, it triggers a mini Full Draft with all affected sections rewritten.
   
   However, the Director has NOT yet approved — they are asking for the plan first. The current paper is at 39 pages and needs to be compressed to 8 pages main text.
   
   Key details from the Reframe:
   - New title: "A Detection Phase Transition in Iterative Training Collapse"
   - 4 contributions: C1 (Phase Transition), C2 (S×R Theory), C3 (Multi-Method Toolkit, downgraded), C4 (Practical Applications)
   - 8-page budget: Abstract+Intro 1.5p, Background+RW 1.0p, Theory+Method 2.0p, Results 2.5p, Discussion+Conclusion 1.0p
   - Much content moves to Appendix

9. Optional Next Step:
   Generate `writing_plan.yaml` for the D130 Reframe, covering:
   - Paper outline with word/page budgets per section
   - Visualization plan (which figures stay in main, which move to appendix)
   - Table plan
   - Literature strategy (existing citations sufficient)
   - Writing order
   
   Per the Director: "请生成 writing_plan.yaml 提交我审批" and "执行模式: 这是 Reframe——需要重写 Abstract, Introduction, 重组 Results section, 压缩全文。不是增量 Patch。请生成 writing_plan.yaml 提交我审批。"
   
   Before generating, need to read the paper-plan skill (`skills/global/paper-plan.skill.md`) and current `writing_plan.yaml` if it exists. Also need to clarify the regime count discrepancy (D130 says 5 regimes in C2, current paper has 4).

If you need specific details from before compaction (like exact code snippets, error messages, or content you generated), read the full transcript at: /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-4-projects-distrib-canary-collapse--claude-sessions-paper-agent-73c709c0/71c5797e-c964-4419-a009-2e487a4de1fc.jsonl
Continue the conversation from where it left off without asking the user any further questions. Resume directly — do not acknowledge the summary, do not recap what was happening, do not preface with "I'll continue" or similar. Pick up the last task as if the break never happened.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "cd93e242-0d6b-4f20-a129-15353d62c0df",
  "isSidechain": false,
  "promptId": "0bc1eef6-835a-4ee4-a8a1-06010792cb3b",
  "type": "user",
  "isVisibleInTranscriptOnly": true,
  "isCompactSummary": true,
  "uuid": "59d61d64-cf62-4ab8-af9e-de7c9915328d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Runtime record

_source line 740 · 2026-05-20T10:04:32.430Z_

```json
{
  "parentUuid": "59d61d64-cf62-4ab8-af9e-de7c9915328d",
  "isSidechain": false,
  "attachment": {
    "type": "file",
    "filename": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/abstract.tex",
    "content": {
      "type": "text",
      "file": {
        "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/abstract.tex",
        "content": "\\begin{abstract}\nWe show that lead-lag conclusions in iterative model collapse are fragile: method choice alone inflates spurious-signal rates to at least 62.5\\% (inter-method $\\kappa{=}0.091$--$0.185$), with the most liberal method yielding 75\\% forward-direction FPR even at the null ($\\alpha{=}0.0$).\nWe identify three pitfalls (method sensitivity, spurious regression under shared trends, and regime dependence) and systematically compare five statistical methods through a Multi-Method Consensus Test (MMCT).\nPermutation Granger causality emerges as the only method combining zero null-control FPR with high sensitivity, exhibiting a detection phase transition ($\\alpha_c{=}0.476$, sigmoid $R^2{=}0.969$, $\\Delta\\alpha{\\approx}0.02$): 0/8 through $\\alpha{=}0.45$, near-discontinuous onset at $\\alpha{=}0.50$ (6/8, dual-seed), a non-monotonic dip at $\\alpha{=}0.60$ (synchronous collapse), and reliable detection at $\\alpha{\\geq}0.75$.\nCross-architecture validation across 14 model-seed combinations confirms PermG detection (${\\geq}6/8$ metric pairs) in 12 cases (86\\%), with directional asymmetry (24/24 forward, 0/24 reverse) confirmed across four seeds on WikiText-103.\nFirst-differencing cleanly separates genuine from spurious channels: all canary$\\to$diversity leads survive while all canary$\\to$perplexity leads vanish.\nApplied to Pythia-410M and replicated across six model families (345M--6.9B parameters), the framework identifies token entropy as a one-generation-ahead canary for diversity collapse, with canary-based predictive cessation validated across two model scales (410M, 1.4B).\n\\end{abstract}",
        "numLines": 8,
        "startLine": 1,
        "totalLines": 8
      }
    },
    "displayPath": "../../../docs/paper/abstract.tex"
  },
  "type": "attachment",
  "uuid": "771848dc-6a42-4f73-9eae-c14b41a01ce9",
  "timestamp": "2026-05-20T10:04:32.430Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

---


### Runtime record

_source line 741 · 2026-05-20T10:04:32.914Z_

```json
{
  "parentUuid": "771848dc-6a42-4f73-9eae-c14b41a01ce9",
  "isSidechain": false,
  "attachment": {
    "type": "file",
    "filename": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/limitations.tex",
    "content": {
      "type": "text",
      "file": {
        "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/limitations.tex",
        "content": "\\section*{Limitations}\n\\label{sec:limitations}\n\nSeveral limitations constrain the generalizability of our findings.\n\n\\paragraph{Model scale.}\nOur experiments are validated at scales ${\\leq}1.4$B parameters (GPT-2-medium 345M, Pythia-410M, OPT-1.3B), all decoder-only transformers small by contemporary standards.\nWhether the temporal lead shortens or vanishes at frontier scale (7B+) is an open question requiring proportionally more compute per condition: 10 generations $\\times$ 5{,}000 steps per generation makes iterative training at 7B+ prohibitively expensive for academic settings.\nEncoder-decoder architectures (T5, BART) and non-autoregressive models (e.g., diffusion-based text generators) are entirely untested; their fundamentally different generation mechanisms may alter canary dynamics in ways that autoregressive decoder-only results cannot predict.\nThe batch size difference between architectures (4 for Pythia vs.\\ 32 for GPT-2-medium) means each training step exposes $8\\times$ more data in the latter, potentially accelerating collapse dynamics without altering the qualitative pattern.\n\n\\paragraph{Data domain and scale.}\nTraining data is drawn from a 5K-document subset of WikiText-103, three orders of magnitude smaller than typical pre-training corpora.\nThis scale gap means our iterative training dynamics reflect a low-data regime where overfitting to synthetic content may onset faster than in production-scale pipelines.\nDomain-specific properties (vocabulary richness, syntactic complexity, topical diversity) may further influence canary-downstream coupling, and domains with inherently low diversity (e.g., legal text, code) could exhibit different canary dynamics.\nThe C4-domain generalization experiments (\\S\\ref{sec:generalization}) introduce an additional confound: switching from WikiText to C4 simultaneously changes both the textual domain and the data-scale characteristics, preventing full disentanglement of domain effects from scale effects within a single experimental comparison.\n\n\\paragraph{Pre-training data confound (C4).}\nOur C4-domain generalization experiments (\\S\\ref{sec:generalization}) use Pythia models that were pre-trained on the Pile~\\cite{gao2021pile}, which includes Common Crawl data overlapping with C4.\nThis means the model has prior exposure to the domain used for iterative training, potentially conflating domain familiarity with collapse dynamics.\nThe WikiText-103 experiments do not share this confound because Pythia's pre-training corpus does not include WikiText-103 directly.\nInterpreting C4 results therefore requires caution: observed differences from the WikiText baseline may reflect domain familiarity effects rather than genuine domain-dependent collapse behavior.\n\n\\paragraph{Short time series ($T{=}10$).}\nWith 11 data points per series, our statistical analyses operate near the lower bound of what standard methods require.\nThis limits power for all methods and renders two of the five evaluated methods effectively inoperative: threshold onset detection yields 0/8 significant pairs in the majority of conditions under corrected $3\\sigma$ calibration, and Toda--Yamamoto Granger achieves moderate detection (3--4/8 at $\\alpha{\\geq}0.50$) with reduced power relative to the primary methods (\\S\\ref{sec:ty_limitation}).\nBoth threshold onset and Toda--Yamamoto are classified as supplementary: the former due to power limitations (\\S\\ref{sec:threshold_limitation}), the latter due to sensitivity to the augmentation order $d_{\\max}$ and lower detection rates at $T{=}11$; longer generation chains ($T{\\geq}20$) could improve both methods' power.\nOur method recommendation (permutation Granger) is robust at $T{=}10$; threshold onset could become viable at $T{\\geq}20$ with additional degrees of freedom.\nWe omit transfer entropy, a standard nonlinear Granger alternative, because kernel density estimation requires substantially longer time series (typically $T{\\geq}100$) than our 10-generation design permits, yielding negligible statistical power at $T{=}10$.\nClassical critical slowing down (CSD) indicators---rising autocorrelation (AC1) and variance---similarly require substantially longer time series ($T{\\geq}50$--$100$; \\citealt{dakos2012methods}) for reliable detection; our $T{=}11$ sequences are insufficient to test whether CSD signatures accompany the onset of causal detectability, which we leave to future work with extended generation protocols.\nLonger generation chains would improve statistical power but impose substantial computational cost.\n\n\\paragraph{Bivariate Granger $\\neq$ causality.}\nBivariate Granger tests cannot exclude confounders.\nAn unobserved process (such as a latent shift in the training data distribution) could independently drive both token entropy and diversity metrics, producing spurious lead-lag associations.\nOur multi-method consensus framework mitigates but does not eliminate this limitation; multivariate VAR models would be required to test for confounders directly.\n\n\\paragraph{Regime boundary uncertainty.}\nThe onset boundary at $\\alpha{\\approx}0.45$--$0.50$ has been refined by probing at $\\alpha{=}0.35$, $0.40$, and $0.45$ (all 0/8), narrowing the transition to a ${\\leq}0.05$-wide interval; a faint single-pair signal appears at $\\alpha{=}0.25$ (FDR $p{=}0.053$) but does not reach aggregate detection.\nSigmoid regression (\\S\\ref{sec:regime}) characterizes this boundary as near-discontinuous ($\\alpha_c{=}0.476$, steepness $k{\\geq}200$, $\\Delta\\alpha{\\approx}0.02$), but whether this sharpness is preserved at larger model scales or different data domains remains open.\nThree-seed replication at $\\alpha{=}0.75$ on WikiText confirms directional asymmetry (20/24 forward, 0/24 reverse) but method consensus remains transitional (Tier~2--3), leaving the exact boundary position uncertain.\nDirectional asymmetry itself is domain-dependent: C4 exhibits near-symmetric bidirectional coupling at $\\alpha{=}0.50$ (PermG reverse 7/8; \\S\\ref{sec:discussion}), and whether this pattern generalizes to other domains or contamination levels is untested.\nThe canary blind spot observed at $\\alpha{=}0.10$ (diversity collapsed but canary silent) rests on a single seed; multi-seed confirmation is needed to establish whether this dissociation is robust.\n\n\\paragraph{Intervention scope.}\nOur intervention experiments (\\S\\ref{sec:intervention}) validate canary-based predictive cessation across two model scales (410M, 1.4B) and three seed-precision conditions, but only at $\\alpha{=}1.0$ (full synthetic replacement).\nWhether the 15\\% entropy threshold remains effective under partial contamination or accumulate-mode training is untested; the $\\alpha{=}0.60$ trigger observation (\\S\\ref{sec:discussion}) remains without intervention validation.\n\n\\paragraph{Replace-only protocol.}\nOur experiments use replace-only data accumulation; accumulate-mode training~\\cite{dey2024breaking,kazdan2025collapse} may exhibit qualitatively different canary dynamics or eliminate the need for canary monitoring entirely~\\cite{falahati2026curated}.\n\n\\paragraph{Scope limited to diversity metrics.}\nOur canary claims are scoped to distinct-$n$ diversity metrics~\\cite{li2016diversity}, not to model collapse broadly~\\cite{schaeffer2025position}, as the perplexity channel proved spurious after differencing.\nThis scoping is theoretically motivated by the calibration-diversity tradeoff~\\cite{cao2025entropycal}, but means our findings may not generalize to other collapse manifestations (e.g., factual degradation, reasoning capability loss).\n",
        "numLines": 55,
        "startLine": 1,
        "totalLines": 55
      }
    },
    "displayPath": "../../../docs/paper/limitations.tex"
  },
  "type": "attachment",
  "uuid": "20fbdb12-ff5e-416b-9a38-a6ba126e4169",
  "timestamp": "2026-05-20T10:04:32.914Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

---


### Runtime record

_source line 742 · 2026-05-20T10:04:32.742Z_

```json
{
  "parentUuid": "20fbdb12-ff5e-416b-9a38-a6ba126e4169",
  "isSidechain": false,
  "attachment": {
    "type": "compact_file_reference",
    "filename": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/references.bib",
    "displayPath": "../../../docs/paper/references.bib"
  },
  "type": "attachment",
  "uuid": "15f3aba0-483f-4e8a-8c23-6fb611ebe278",
  "timestamp": "2026-05-20T10:04:32.742Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

---


### Runtime record

_source line 743 · 2026-05-20T10:04:32.432Z_

```json
{
  "parentUuid": "15f3aba0-483f-4e8a-8c23-6fb611ebe278",
  "isSidechain": false,
  "attachment": {
    "type": "file",
    "filename": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/artifacts/_project/chart/fig_phase_transition_location.txt",
    "content": {
      "type": "text",
      "file": {
        "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/artifacts/_project/chart/fig_phase_transition_location.txt",
        "content": "Figure saved on westd-17855:/root/autodl-tmp/distrib_canary_collapse/artifacts_phase_transition/fig_phase_transition.pdf and .png",
        "numLines": 1,
        "startLine": 1,
        "totalLines": 1
      }
    },
    "displayPath": "../../../artifacts/_project/chart/fig_phase_transition_location.txt"
  },
  "type": "attachment",
  "uuid": "0adb61c1-34f2-47fb-8bc8-c0cf67649cd2",
  "timestamp": "2026-05-20T10:04:32.432Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

---


### Runtime record

_source line 744 · 2026-05-20T10:04:32.916Z_

```json
{
  "parentUuid": "0adb61c1-34f2-47fb-8bc8-c0cf67649cd2",
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
      "mcp__agent-ml-research__auto_build_provenance",
      "mcp__agent-ml-research__bootstrap_provenance",
      "mcp__agent-ml-research__check_figures_and_layout",
      "mcp__agent-ml-research__check_paper_consistency",
      "mcp__agent-ml-research__check_provenance_completeness",
      "mcp__agent-ml-research__cleanup_pdf_images",
      "mcp__agent-ml-research__compute_coverage_matrix",
      "mcp__agent-ml-research__edit_paper_section",
      "mcp__agent-ml-research__get_image_info",
      "mcp__agent-ml-research__get_worker_status",
      "mcp__agent-ml-research__list_artifacts",
      "mcp__agent-ml-research__list_workers",
      "mcp__agent-ml-research__load_project_config",
      "mcp__agent-ml-research__overleaf_init",
      "mcp__agent-ml-research__overleaf_pull",
      "mcp__agent-ml-research__overleaf_push",
      "mcp__agent-ml-research__overleaf_status",
      "mcp__agent-ml-research__overleaf_sync",
      "mcp__agent-ml-research__paper_agent_post_to_director",
      "mcp__agent-ml-research__paper_agent_request_review",
      "mcp__agent-ml-research__paper_compile_and_check",
      "mcp__agent-ml-research__pdf_to_images",
      "mcp__agent-ml-research__read_experiment_plan_with_status",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__read_roadmap",
      "mcp__agent-ml-research__register_artifact",
      "mcp__agent-ml-research__save_project_file",
      "mcp__agent-ml-research__send_progress",
      "mcp__agent-ml-research__spawn_worker",
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
      "mcp__agent-ml-research__auto_build_provenance",
      "mcp__agent-ml-research__bootstrap_provenance",
      "mcp__agent-ml-research__check_figures_and_layout",
      "mcp__agent-ml-research__check_paper_consistency",
      "mcp__agent-ml-research__check_provenance_completeness",
      "mcp__agent-ml-research__cleanup_pdf_images",
      "mcp__agent-ml-research__compute_coverage_matrix",
      "mcp__agent-ml-research__edit_paper_section",
      "mcp__agent-ml-research__get_image_info",
      "mcp__agent-ml-research__get_worker_status",
      "mcp__agent-ml-research__list_artifacts",
      "mcp__agent-ml-research__list_workers",
      "mcp__agent-ml-research__load_project_config",
      "mcp__agent-ml-research__overleaf_init",
      "mcp__agent-ml-research__overleaf_pull",
      "mcp__agent-ml-research__overleaf_push",
      "mcp__agent-ml-research__overleaf_status",
      "mcp__agent-ml-research__overleaf_sync",
      "mcp__agent-ml-research__paper_agent_post_to_director",
      "mcp__agent-ml-research__paper_agent_request_review",
      "mcp__agent-ml-research__paper_compile_and_check",
      "mcp__agent-ml-research__pdf_to_images",
      "mcp__agent-ml-research__read_experiment_plan_with_status",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__read_roadmap",
      "mcp__agent-ml-research__register_artifact",
      "mcp__agent-ml-research__save_project_file",
      "mcp__agent-ml-research__send_progress",
      "mcp__agent-ml-research__spawn_worker",
      "mcp__agent-ml-research__verify_references",
      "mcp__agent-ml-research__write_paper_section"
    ],
    "removedNames": []
  },
  "type": "attachment",
  "uuid": "57605287-38de-43e4-ba72-ea1ca41b0c52",
  "timestamp": "2026-05-20T10:04:32.916Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

---


### Runtime record

_source line 745 · 2026-05-20T10:04:32.916Z_

```json
{
  "parentUuid": "57605287-38de-43e4-ba72-ea1ca41b0c52",
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
  "uuid": "0684d7bf-440d-47bc-940d-d6d181eb848d",
  "timestamp": "2026-05-20T10:04:32.916Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

---


### Runtime record

_source line 746_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Director 指令] [Reframe — D130] 论文从 Methodology Paper 转型为 Detection Phase Transition Discovery Paper  投稿目标：EMNLP 2026 ARR June cycle，8 页 main text + unlimited references + appendix。当前 37 页需大幅压缩。  ## 核心…",
  "leafUuid": "59d61d64-cf62-4ab8-af9e-de7c9915328d",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


### Runtime record

_source line 747_

```json
{
  "type": "ai-title",
  "aiTitle": "Correct effective_rank framework and add phase transition citations",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


### Assistant

_source line 748 · 2026-05-20T10:04:37.382Z_

<details><summary>Logged reasoning block</summary>

```text
The pending task is to generate `writing_plan.yaml` for the D130 Reframe. Let me first read the paper-plan skill and the current writing_plan.yaml, then read the current state of key files to understand what needs to be restructured.

Let me start by reading the necessary files in parallel.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0684d7bf-440d-47bc-940d-d6d181eb848d",
  "isSidechain": false,
  "requestId": "req_011CbDdbGbHsxcAJ2cFy9cJd",
  "type": "assistant",
  "uuid": "8cf05fd1-7ff2-4e7b-a3e5-80c065ad126a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Qba1ghYceSfqrEKdawtfyJ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 26814,
      "cache_read_input_tokens": 11841,
      "output_tokens": 320,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26814,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 320,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 26814,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26814
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

_source line 749 · 2026-05-20T10:04:38.427Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Dn3i7sebu3r3ou8yK2k7nR`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/skills/paper-plan.skill.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8cf05fd1-7ff2-4e7b-a3e5-80c065ad126a",
  "isSidechain": false,
  "requestId": "req_011CbDdbGbHsxcAJ2cFy9cJd",
  "type": "assistant",
  "uuid": "4dcce121-4048-4662-83d1-aef4cc9bd4b5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Qba1ghYceSfqrEKdawtfyJ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 26814,
      "cache_read_input_tokens": 11841,
      "output_tokens": 320,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26814,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 320,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 26814,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26814
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

_source line 750 · 2026-05-20T10:04:38.458Z_

<details><summary>↩ Tool result · reported error · `toolu_01Dn3i7sebu3r3ou8yK2k7nR`</summary>

```text
File does not exist. Note: your current working directory is /home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "4dcce121-4048-4662-83d1-aef4cc9bd4b5",
  "isSidechain": false,
  "promptId": "0bc1eef6-835a-4ee4-a8a1-06010792cb3b",
  "type": "user",
  "uuid": "eda89815-f3fb-450e-ab7e-c7368904a358",
  "toolUseResult": "Error: File does not exist. Note: your current working directory is /home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0.",
  "sourceToolAssistantUUID": "4dcce121-4048-4662-83d1-aef4cc9bd4b5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Tool result

_source line 751 · 2026-05-20T10:04:39.172Z_

<details><summary>↩ Tool result · `toolu_019mSjMxYQEwjnc6KsyqaQCq`</summary>

```text
1	\documentclass[11pt,a4paper,twocolumn]{article}
2	\usepackage{times}
3	\usepackage{latexsym}
4	\usepackage{amsmath}
5	\usepackage{amssymb}
6	\usepackage{graphicx}
7	\usepackage{booktabs}
8	\usepackage{subcaption}
9	\usepackage{xcolor}
10	\usepackage{algorithm}
11	\usepackage{algpseudocode}
12	\usepackage[T1]{fontenc}
13	\usepackage[utf8]{inputenc}
14	\usepackage{microtype}
15	\usepackage[numbers]{natbib}
16	\usepackage{hyperref}
17	\usepackage[margin=2.5cm]{geometry}
18	
19	\title{Method Matters: Pitfalls and a Multi-Method Consensus Framework for Lead-Lag Analysis in Iterative Training Collapse}
20	
21	\author{Anonymous}
22	\date{}
23	
24	\begin{document}
25	\maketitle
26	
27	\input{abstract}
28	\input{introduction}
29	\input{background}
30	\input{related_work}
31	\input{method}
32	\input{experiments}
33	\input{discussion}
34	\input{conclusion}
35	\input{limitations}
36	\input{ethics}
37	
38	\bibliographystyle{plainnat}
39	\bibliography{references}
40	
41	\input{appendix}
42	
43	\end{document}
44	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "1eef34b7-2335-4610-a857-2258924aec0b",
  "isSidechain": false,
  "promptId": "0bc1eef6-835a-4ee4-a8a1-06010792cb3b",
  "type": "user",
  "uuid": "15e22217-2ac8-43b2-80d3-6b1b651e7c28",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/main.tex",
      "content": "\\documentclass[11pt,a4paper,twocolumn]{article}\n\\usepackage{times}\n\\usepackage{latexsym}\n\\usepackage{amsmath}\n\\usepackage{amssymb}\n\\usepackage{graphicx}\n\\usepackage{booktabs}\n\\usepackage{subcaption}\n\\usepackage{xcolor}\n\\usepackage{algorithm}\n\\usepackage{algpseudocode}\n\\usepackage[T1]{fontenc}\n\\usepackage[utf8]{inputenc}\n\\usepackage{microtype}\n\\usepackage[numbers]{natbib}\n\\usepackage{hyperref}\n\\usepackage[margin=2.5cm]{geometry}\n\n\\title{Method Matters: Pitfalls and a Multi-Method Consensus Framework for Lead-Lag Analysis in Iterative Training Collapse}\n\n\\author{Anonymous}\n\\date{}\n\n\\begin{document}\n\\maketitle\n\n\\input{abstract}\n\\input{introduction}\n\\input{background}\n\\input{related_work}\n\\input{method}\n\\input{experiments}\n\\input{discussion}\n\\input{conclusion}\n\\input{limitations}\n\\input{ethics}\n\n\\bibliographystyle{plainnat}\n\\bibliography{references}\n\n\\input{appendix}\n\n\\end{document}\n",
      "numLines": 44,
      "startLine": 1,
      "totalLines": 44
    }
  },
  "sourceToolAssistantUUID": "1eef34b7-2335-4610-a857-2258924aec0b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Tool call

_source line 752 · 2026-05-20T10:04:38.920Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Kvxop1qnRYoGge6398zBtb`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/writing_plan.yaml"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "eda89815-f3fb-450e-ab7e-c7368904a358",
  "isSidechain": false,
  "requestId": "req_011CbDdbGbHsxcAJ2cFy9cJd",
  "type": "assistant",
  "uuid": "1e190fcf-4b2f-4022-be0d-f505a21cc2d9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Qba1ghYceSfqrEKdawtfyJ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 26814,
      "cache_read_input_tokens": 11841,
      "output_tokens": 320,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26814,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 320,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 26814,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26814
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

_source line 753 · 2026-05-20T10:04:38.932Z_

<details><summary>↩ Tool result · `toolu_01Kvxop1qnRYoGge6398zBtb`</summary>

```text
1	meta:
2	  title: "Method Matters: Pitfalls and a Multi-Method Consensus Framework for Lead-Lag Analysis in Iterative Training Collapse"
3	  venue: EMNLP 2026
4	  track: main
5	  deadline: "2026-06-15 (estimated, ARR submission)"
6	  format: "ACL/EMNLP two-column, 8 pages + unlimited references/appendix"
7	  template: "acl2023"
8	  template_note: "D043: 投稿目标从 AAAI 2027 变更为 EMNLP 2026 main track。使用 ACL 2023 模板（acl2023.sty），EMNLP 2026 沿用 ACL 格式"
9	  word_budget_total: 7200
10	  citation_budget: 40-45
11	  status: approved
12	
13	paper_outline:
14	  - section: abstract
15	    word_budget: 200
16	    dependencies: [method, experiments, introduction]
17	    key_points:
18	      - "Problem: lead-lag analysis in model collapse lacks methodological rigor"
19	      - "Gap: method choice can flip conclusions; no systematic sensitivity analysis exists"
20	      - "Approach: 3 pitfalls + multi-method consensus framework with FPR/FNR calibration"
21	      - "Results: naive correlation 100% sig → differenced Granger 25%; consensus framework achieves FPR=0/FNR=0 on reference extremes"
22	      - "Case study: token entropy Granger-causes diversity collapse at α≥0.75 with 1-gen lead"
23	
24	  - section: introduction
25	    word_budget: 1100
26	    dependencies: []
27	    key_points:
28	      - "Model collapse 文献日益关注 lead-lag 分析（Du et al., SIGMA, DCES），但方法论基础薄弱"
29	      - "Gap: 无差分检验、无多方法交叉验证、无 FDR 校正、无 regime-dependent 分析"
30	      - "Our approach: systematic case study exposing 3 pitfalls + consensus framework"
31	      - "Headline: naive 100% sig → differenced 25%; same test flips across α regimes"
32	      - "Contribution statement (D042): diagnostic + prescriptive framework with empirically calibrated thresholds"
33	    contributions:
34	      - "C1: 系统性暴露 lead-lag 分析中三个方法论陷阱（method sensitivity, spurious regression, regime dependence）"
35	      - "C2: 多方法共识框架 + empirically calibrated thresholds，FPR=0/FNR=0 on reference extremes"
36	      - "C3: 应用框架识别 token entropy 为 diversity collapse 的 1-gen-ahead canary（α≥0.75），附分层实用指南"
37	
38	  - section: related_work
39	    word_budget: 900
40	    dependencies: [introduction]
41	    key_points:
42	      - "Model collapse foundations: Shumailov et al. 2024, Alemohammad et al. 2024, Dohmatob et al. 2024/2025"
43	      - "Canary/monitoring: chen2025scales (ECE先于accuracy), SIGMA (spectral), Kalinowski (topology), Gambetta (surplexity)"
44	      - "Data mixing theory: Kazdan et al. 2025, Dey et al. 2024, Fu et al. 2025, He et al. 2025 golden ratio"
45	      - "Early warning signals: Scheffer et al. 2009/2012 (tipping points), Boettiger & Hastings 2012 (detection limits)"
46	      - "与 Du et al. 4 点显式区分：多指标/多方法/regime mapping/方法敏感性"
47	    literature_clusters:
48	      - name: core_collapse
49	        must_cite: [shumailov2024curse, alemohammad2024mad, dohmatob2024tale, dohmatob2025strong, truong2025entropy]
50	        target_count: 6
51	      - name: canary_monitoring
52	        must_cite: [chen2025scales, sigma2026spectral, kalinowski2026topology]
53	        target_count: 5
54	      - name: data_mixing
55	        must_cite: [kazdan2025collapse, dey2024breaking, fu2025selfconsuming]
56	        target_count: 4
57	      - name: early_warning_tipping
58	        must_cite: [scheffer2009early, scheffer2012anticipating, boettiger2012limits]
59	        target_count: 3
60	      - name: methodology_granger
61	        must_cite: [shojaie2022granger]
62	        target_count: 2
63	      - name: diversity_metrics
64	        must_cite: [li2016diversity, guo2024linguistic]
65	        target_count: 2
66	
67	  - section: background
68	    word_budget: 500
69	    dependencies: []
70	    key_points:
71	      - "Iterative training loop 形式化定义：M_t, D_synth, α mixing ratio"
72	      - "Metric families: canary (token_entropy, ECE) vs downstream (distinct_1/2, perplexity)"
73	      - "Lead-lag testing problem: 给定两条时间序列，判定是否存在 temporal precedence"
74	      - "5 种方法简述：naive cross-correlation, differenced cross-correlation, threshold onset, permutation Granger, Toda-Yamamoto"
75	
76	  - section: method
77	    word_budget: 1300
78	    dependencies: [background]
79	    subsections:
80	      - name: "Methodological Pitfalls in Lead-Lag Analysis"
81	        word_budget: 400
82	        key_points:
83	          - "Pitfall 1 — Method sensitivity: naive Pearson 100% sig vs permutation Granger 25% (16/16 → 6/16)"
84	          - "Pitfall 2 — Spurious regression: canary→perplexity 差分后 0/8 SIG (F≈0, p=0.99)，diversity 通道不变"
85	          - "Pitfall 3 — Regime dependence: 同一检验 α=1.0 24/24 FDR-sig → α≤0.50 0/8"
86	      - name: "Multi-Method Consensus Framework"
87	        word_budget: 500
88	        key_points:
89	          - "Definition: pair (X,Y) classified ROBUST iff ≥K/M methods judge significant AND ≥S/N seeds replicate"
90	          - "Sequential filtering pipeline: naive → differencing → Granger+FDR → multi-seed"
91	          - "Default: K=4/5, S=3/4 (empirically calibrated)"
92	      - name: "Empirical Calibration"
93	        word_budget: 300
94	        key_points:
95	          - "FPR from α=0.0 null control (no synthetic data)"
96	          - "FNR from α=1.0 (4 seeds, 6 ground-truth robust pairs)"
97	          - "K=4/5 S=3/4 achieves FPR=0 FNR=0 on reference extremes"
98	          - "D041 约束: FNR 独立验证 via D017 differencing"
99	          - "Discussion 声明: calibration limited to current setup"
100	
101	  - section: experiments
102	    word_budget: 2100
103	    dependencies: [method]
104	    subsections:
105	      - name: "Experimental Setup"
106	        word_budget: 300
107	        key_points:
108	          - "Pythia-410M, WikiText-103 5K subset, 10 generations, 5000 steps/gen"
109	          - "α ∈ {0, 0.25, 0.50, 0.75, 1.0}, seeds {42,43,44,45}"
110	          - "Metrics: token_entropy, ECE (next-token), distinct_1/2/3, perplexity"
111	          - "Statistical: BH FDR q=0.05, 5000 permutations"
112	      - name: "Method Sensitivity Analysis (Claim 3)"
113	        word_budget: 500
114	        key_points:
115	          - "5-method ablation: naive→differenced→threshold→permG→TY sig rates"
116	          - "2×2 差分对比: diversity channel (12/12→12/12) vs perplexity channel (8/8→0/8)"
117	          - "d_max sensitivity: 0%↔94% spurious rate swing"
118	          - "Cohen κ=0.185 (poor inter-method agreement)"
119	          - "method × α interaction: naive 100% everywhere vs permG dose-response"
120	          - "Ref to Fig 2"
121	      - name: "Regime-Dependent Detectability (Claim 2)"
122	        word_budget: 400
123	        key_points:
124	          - "5-point regime map: Granger FDR sig rate vs α"
125	          - "Detectability boundary at α≈0.50-0.75"
126	          - "Raw drift magnitude dose-response (primary): distinct_1 -14%→-40%→-93%"
127	          - "Non-monotonic diversity decline at α=0.25 (single-seed caveat)"
128	          - "α=0.50 null = positive finding (synchronous collapse, no temporal lead)"
129	          - "Ref to Fig 1, Fig 3"
130	      - name: "Case Study: Canary Prediction (Claim 1)"
131	        word_budget: 400
132	        key_points:
133	          - "token_entropy Granger-causes distinct_1/2 at α≥0.75"
134	          - "α=1.0: 24/24 FDR-sig across 4 seeds, cross-corr lag=+1 (r>0.99, std=0.0)"
135	          - "α=0.75: 3/4 FDR-sig (single-seed, C001 caveat), entropy→d1 borderline p_fdr=0.054"
136	          - "ECE as conditional secondary canary (equivalent in 4/5 methods, TY Type II only)"
137	          - "Consensus framework application: 6/16 robust pairs survive full pipeline"
138	          - "Ref to Fig 4, Fig 5"
139	      - name: "Consensus Framework Validation"
140	        word_budget: 200
141	        key_points:
142	          - "FPR=0 at α=0.0 null control"
143	          - "FNR=0 on 6 reference robust pairs (independently validated by D017 differencing)"
144	          - "Comparison: naive FPR=100%, TY FNR=25%"
145	          - "Ref to Table 3"
146	
147	  - section: discussion
148	    word_budget: 700
149	    dependencies: [experiments]
150	    key_points:
151	      - "Granger precedence ≠ true causality (Granger 1969); bivariate cannot exclude confounders"
152	      - "Calibration limited to current setup (Pythia-410M, WikiText-103); generalization needs independent validation"
153	      - "FPR/FNR dimension asymmetry (D041): FPR method-only, FNR method×seed joint"
154	      - "Phase 3 three-phase dynamics (if multi-seed confirmed): observation window sensitivity as Claim 3 evidence"
155	      - "Limitations: single architecture family, T=10 short series, no intervention experiment"
156	      - "Future work: multi-variate VAR, cross-architecture validation, online monitoring integration"
157	
158	  - section: conclusion
159	    word_budget: 250
160	    dependencies: [discussion]
161	    key_points:
162	      - "Method choice matters: 3 pitfalls that can flip lead-lag conclusions"
163	      - "Consensus framework: actionable from exploratory to publication-grade"
164	      - "Practical takeaway: token entropy as 1-gen-ahead canary for diversity collapse at α≥0.75"
165	
166	visualization_plan:
167	  - fig_id: fig_regime_map
168	    type: line_with_threshold
169	    description: "Granger FDR p-value vs α (5-point) for 4 canary→diversity directions. Horizontal line at p=0.05. Shows detectability boundary at α≈0.50-0.75."
170	    placement: "Claim 2 core, §Experiments Regime-Dependent Detectability"
171	    aspect_ratio: "single column (3.25in × 2.5in)"
172	    tool: matplotlib
173	    data_source: "registry: alpha_sweep_a000_s42, alpha_sweep_a025_s42_v3, alpha_sweep_a050_s42, alpha_sweep_a075_s42, mvp_v4_rep42; artifacts/D040/data/cross_alpha_v6.json"
174	    output_path: "projects/distrib_canary_collapse/figures/paper/fig_regime_map.pdf"
175	    status: DONE
176	    artifact_id: art_20260515_06ffe6
177	
178	  - fig_id: fig_differencing_dmax
179	    type: multi_panel
180	    description: "2×2 multi-panel. Top row: 差分前后 significance heatmap (channel × differencing status); Bottom row: d_max sensitivity curves (spurious rate vs d_max for 3 settings). Shows Pitfall 1+2."
181	    placement: "Claim 3 core, §Experiments Method Sensitivity"
182	    aspect_ratio: "double column (6.5in × 4in)"
183	    tool: matplotlib
184	    data_source: "registry: method_ablation_phase1, method_ablation_phase2; artifacts/D040/data/filtering_pipeline_data.json"
185	    output_path: "projects/distrib_canary_collapse/figures/paper/fig_differencing_dmax.pdf"
186	    status: TODO
187	
188	  - fig_id: fig_consensus_heatmap
189	    type: heatmap
190	    description: "Method × α significance rate heatmap. 5 methods (rows) × 5 α levels (columns). Cell color = FDR sig rate. Shows method×regime interaction."
191	    placement: "Bridge Claim 2+3, §Experiments after Regime Map"
192	    aspect_ratio: "single column (3.25in × 2.5in)"
193	    tool: matplotlib
194	    data_source: "registry: method_ablation_phase2; artifacts/analysis/consensus_framework/consensus_classification.json"
195	    output_path: "projects/distrib_canary_collapse/figures/paper/fig_consensus_heatmap.pdf"
196	    status: DONE
197	    artifact_id: art_20260515_97707a
198	
199	  - fig_id: fig_metric_trajectory
200	    type: line_plot
201	    description: "Single-panel: token_entropy and distinct_1 trajectories across 10 generations at α=1.0 (4-seed mean±std). Vertical annotation showing 1-gen lead. Normalized to gen 0."
202	    placement: "Claim 1 case study, §Experiments Case Study"
203	    aspect_ratio: "single column (3.25in × 2.5in)"
204	    tool: matplotlib
205	    data_source: "registry: mvp_v4_rep42, mvp_v4_rep43, mvp_v4_rep44, mvp_v4_rep45"
206	    output_path: "projects/distrib_canary_collapse/figures/paper/fig_metric_trajectory.pdf"
207	    status: TODO
208	
209	  - fig_id: fig_consensus_workflow
210	    type: multi_panel
211	    description: "3-panel: (a) sequential filtering pipeline funnel (16→14→6→6 pairs at α=1.0); (b) FPR/FNR trade-off across K threshold; (c) practical guidance cards (4 tiers). Methodology contribution showcase."
212	    placement: "§Method / §Experiments Consensus Validation"
213	    aspect_ratio: "double column (6.5in × 3in)"
214	    tool: matplotlib
215	    data_source: "artifacts/D040/data/filtering_pipeline_data.json; artifacts/D040/data/fpr_fnr_calibration.json"
216	    output_path: "projects/distrib_canary_collapse/figures/paper/fig_consensus_workflow.pdf"
217	    status: DONE
218	    artifact_id: art_20260515_390d50
219	
220	table_plan:
221	  - table_id: tab_drift_summary
222	    type: metric_comparison
223	    columns: ["α", "token_entropy Δ%", "ECE Δ%", "distinct_1 Δ%", "distinct_2 Δ%", "perplexity Δ%"]
224	    data_source: "registry: alpha_sweep_a000_s42, alpha_sweep_a025_s42_v3, alpha_sweep_a050_s42, alpha_sweep_a075_s42, mvp_v4_rep42 (α=1.0 mean of 4 seeds)"
225	    placement: "§Experiments Setup or Regime Map"
226	    description: "Raw metric drift across 5 α levels. Primary evidence for Claim 2 (regime-dependent)."
227	
228	  - table_id: tab_method_comparison
229	    type: significance_rates
230	    columns: ["Method", "α=0.0", "α=0.25", "α=0.50", "α=0.75", "α=1.0", "FPR (null)"]
231	    data_source: "registry: method_ablation_phase2; artifacts/analysis/consensus_framework/fpr_fnr_table.json"
232	    placement: "§Experiments Method Sensitivity"
233	    description: "5-method FDR sig rates across α. Core Claim 3 table."
234	
235	  - table_id: tab_fpr_fnr
236	    type: calibration
237	    columns: ["K (method threshold)", "S (seed threshold)", "FPR", "FNR_robust", "FNR_all"]
238	    data_source: "artifacts/D040/data/fpr_fnr_calibration.json"
239	    placement: "§Method Empirical Calibration or §Experiments Consensus Validation"
240	    description: "FPR/FNR across 5K×4S = 20 configurations. Recommended K=4/5 S=3/4."
241	
242	  - table_id: tab_practical_guidance
243	    type: guidance
244	    columns: ["Tier", "Use Case", "Methods Required", "Seed Requirement", "Expected FPR", "Expected FNR"]
245	    data_source: "manual (from consensus_framework formalization)"
246	    placement: "§Method or §Discussion"
247	    description: "4-tier practical guidance: exploratory→screening→confirmatory→publication."
248	
249	literature_strategy:
250	  macro_context: "Model collapse → canary/monitoring → lead-lag methodology → tipping points/EWS"
251	  micro_clusters:
252	    - cluster_name: core_collapse
253	      search_queries: ["model collapse iterative training LLM", "self-consuming generative models"]
254	      must_cite: [shumailov2024curse, alemohammad2024mad, dohmatob2024tale, dohmatob2025strong, truong2025entropy]
255	      target_count: 6
256	    - cluster_name: canary_monitoring
257	      search_queries: ["early warning model collapse metrics", "ECE calibration synthetic data"]
258	      must_cite: [chen2025scales, sigma2026spectral, kalinowski2026topology]
259	      target_count: 5
260	    - cluster_name: data_mixing
261	      search_queries: ["synthetic data mixing ratio collapse prevention"]
262	      must_cite: [kazdan2025collapse, dey2024breaking, fu2025selfconsuming]
263	      target_count: 4
264	    - cluster_name: early_warning_tipping
265	      search_queries: ["early warning signals critical transitions ecology"]
266	      must_cite: [scheffer2009early, scheffer2012anticipating, boettiger2012limits]
267	      target_count: 3
268	    - cluster_name: methodology_granger
269	      search_queries: ["Granger causality review time series"]
270	      must_cite: [shojaie2022granger]
271	      target_count: 2
272	    - cluster_name: diversity_metrics
273	      search_queries: ["distinct-n text generation diversity"]
274	      must_cite: [li2016diversity, guo2024linguistic]
275	      target_count: 2
276	  citation_budget: 40-45
277	
278	writing_order:
279	  - step: 1
280	    section: experiments
281	    rationale: "Data-driven, most constrained by registry. Write first to lock down all numbers."
282	  - step: 2
283	    section: method
284	    rationale: "Consensus framework definition. References Experiments for calibration data."
285	  - step: 3
286	    section: background
287	    rationale: "Definitions and notation needed by Method+Experiments, but content determined by them."
288	  - step: 4
289	    section: introduction
290	    rationale: "Frames the story. Needs final Experiments numbers for headline result."
291	  - step: 5
292	    section: related_work
293	    rationale: "Positions after Introduction sets framing. Needs verified references."
294	  - step: 6
295	    section: discussion
296	    rationale: "Limitations and future work, after all results known."
297	  - step: 7
298	    section: conclusion
299	    rationale: "Summary of contributions."
300	  - step: 8
301	    section: abstract
302	    rationale: "Last, summarizes everything."
303	
304	presentation_constraints:
305	  - id: PC01
306	    source: D038
307	    rule: "α=0.75 vs α=1.0 consensus scores 不可直接对比（标准不同：single-seed vs 4-seed）"
308	  - id: PC02
309	    source: D038
310	    rule: "token_entropy→perplexity @ α=0.75 不可引用为 robust evidence（D017 confirmed spurious）"
311	  - id: PC03
312	    source: D041
313	    rule: "FNR=0 声明必须补充 D017 独立证据，不能仅自引"
314	  - id: PC04
315	    source: D041
316	    rule: "FPR/FNR 维度不对称须显式说明"
317	  - id: PC05
318	    source: D042
319	    rule: "Discussion 须声明 calibration 仅适用于当前 setup"
320	  - id: PC06
321	    source: D035
322	    rule: "Phase 3 三相动力学：如 multi-seed 确认，Claim 3 Results 末尾加 ~150 词"
323	  - id: PC07
324	    source: paper_framing
325	    rule: "不能 claim canary predicts model collapse，只能 claim canary predicts diversity collapse"
326	  - id: PC08
327	    source: paper_framing
328	    rule: "effective_rank 和 self_bleu 作为 canary 失败必须全量报告"
329	  - id: PC09
330	    source: paper_framing
331	    rule: "distinct_3 放 supplementary，主文聚焦 distinct_1/2"
332	  - id: PC10
333	    source: paper_framing
334	    rule: "f² 效应量禁用 Cohen 基准（df_resid<20），permutation p-value 为主要推断证据"
335	  - id: PC11
336	    source: paper_framing
337	    rule: "Granger precedence ≠ true causality，Discussion 须声明"
338	  - id: PC12
339	    source: paper_framing
340	    rule: "用 regime map 非 phase diagram（α 点不足）"
341	  - id: PC13
342	    source: paper_framing
343	    rule: "CRS 降级为 illustration，不列入 core contribution"
344	  - id: PC14
345	    source: paper_framing
346	    rule: "强度词限制：单数据集/实验禁用 consistently outperforms / state-of-the-art；无统计检验禁用 significantly"
347	  - id: PC15
348	    source: paper_framing
349	    rule: "spurious_rate 双版本报告：含TY 75% / 排除TY 62.5%"
350	  - id: PC16
351	    source: paper_framing
352	    rule: "α=0.75 single-seed caveat C001 标注"
353	  - id: PC17
354	    source: paper_framing
355	    rule: "非单调性结论标注 observed at seed=42; multi-seed confirmation required"
356	
357	running_experiments_note: |
358	  以下实验仍在运行或排队，论文初稿基于已完成数据：
359	  - RUNNING: gen_wiki_gpt2m_a100_s42_v3 (GPT-2-medium, ~45%, cuda:0)
360	  - RUNNING: alpha_sweep_a025_s43 (multi-seed, ~57%, cuda:1)
361	  - QUEUED: alpha_sweep_a050_s43, a025_s44, a050_s44, plan_006_s43, gen_wiki_gpt2m_a025_s42
362	  初稿完成后，新数据到位时通过 Patch 模式更新。GPT-2-medium 结果如果到位，加入 Discussion 或 Supplementary。
363	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "1e190fcf-4b2f-4022-be0d-f505a21cc2d9",
  "isSidechain": false,
  "promptId": "0bc1eef6-835a-4ee4-a8a1-06010792cb3b",
  "type": "user",
  "uuid": "d2318007-f0de-4ae7-b1e4-147f58ef8c04",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/writing_plan.yaml",
      "content": "meta:\n  title: \"Method Matters: Pitfalls and a Multi-Method Consensus Framework for Lead-Lag Analysis in Iterative Training Collapse\"\n  venue: EMNLP 2026\n  track: main\n  deadline: \"2026-06-15 (estimated, ARR submission)\"\n  format: \"ACL/EMNLP two-column, 8 pages + unlimited references/appendix\"\n  template: \"acl2023\"\n  template_note: \"D043: 投稿目标从 AAAI 2027 变更为 EMNLP 2026 main track。使用 ACL 2023 模板（acl2023.sty），EMNLP 2026 沿用 ACL 格式\"\n  word_budget_total: 7200\n  citation_budget: 40-45\n  status: approved\n\npaper_outline:\n  - section: abstract\n    word_budget: 200\n    dependencies: [method, experiments, introduction]\n    key_points:\n      - \"Problem: lead-lag analysis in model collapse lacks methodological rigor\"\n      - \"Gap: method choice can flip conclusions; no systematic sensitivity analysis exists\"\n      - \"Approach: 3 pitfalls + multi-method consensus framework with FPR/FNR calibration\"\n      - \"Results: naive correlation 100% sig → differenced Granger 25%; consensus framework achieves FPR=0/FNR=0 on reference extremes\"\n      - \"Case study: token entropy Granger-causes diversity collapse at α≥0.75 with 1-gen lead\"\n\n  - section: introduction\n    word_budget: 1100\n    dependencies: []\n    key_points:\n      - \"Model collapse 文献日益关注 lead-lag 分析（Du et al., SIGMA, DCES），但方法论基础薄弱\"\n      - \"Gap: 无差分检验、无多方法交叉验证、无 FDR 校正、无 regime-dependent 分析\"\n      - \"Our approach: systematic case study exposing 3 pitfalls + consensus framework\"\n      - \"Headline: naive 100% sig → differenced 25%; same test flips across α regimes\"\n      - \"Contribution statement (D042): diagnostic + prescriptive framework with empirically calibrated thresholds\"\n    contributions:\n      - \"C1: 系统性暴露 lead-lag 分析中三个方法论陷阱（method sensitivity, spurious regression, regime dependence）\"\n      - \"C2: 多方法共识框架 + empirically calibrated thresholds，FPR=0/FNR=0 on reference extremes\"\n      - \"C3: 应用框架识别 token entropy 为 diversity collapse 的 1-gen-ahead canary（α≥0.75），附分层实用指南\"\n\n  - section: related_work\n    word_budget: 900\n    dependencies: [introduction]\n    key_points:\n      - \"Model collapse foundations: Shumailov et al. 2024, Alemohammad et al. 2024, Dohmatob et al. 2024/2025\"\n      - \"Canary/monitoring: chen2025scales (ECE先于accuracy), SIGMA (spectral), Kalinowski (topology), Gambetta (surplexity)\"\n      - \"Data mixing theory: Kazdan et al. 2025, Dey et al. 2024, Fu et al. 2025, He et al. 2025 golden ratio\"\n      - \"Early warning signals: Scheffer et al. 2009/2012 (tipping points), Boettiger & Hastings 2012 (detection limits)\"\n      - \"与 Du et al. 4 点显式区分：多指标/多方法/regime mapping/方法敏感性\"\n    literature_clusters:\n      - name: core_collapse\n        must_cite: [shumailov2024curse, alemohammad2024mad, dohmatob2024tale, dohmatob2025strong, truong2025entropy]\n        target_count: 6\n      - name: canary_monitoring\n        must_cite: [chen2025scales, sigma2026spectral, kalinowski2026topology]\n        target_count: 5\n      - name: data_mixing\n        must_cite: [kazdan2025collapse, dey2024breaking, fu2025selfconsuming]\n        target_count: 4\n      - name: early_warning_tipping\n        must_cite: [scheffer2009early, scheffer2012anticipating, boettiger2012limits]\n        target_count: 3\n      - name: methodology_granger\n        must_cite: [shojaie2022granger]\n        target_count: 2\n      - name: diversity_metrics\n        must_cite: [li2016diversity, guo2024linguistic]\n        target_count: 2\n\n  - section: background\n    word_budget: 500\n    dependencies: []\n    key_points:\n      - \"Iterative training loop 形式化定义：M_t, D_synth, α mixing ratio\"\n      - \"Metric families: canary (token_entropy, ECE) vs downstream (distinct_1/2, perplexity)\"\n      - \"Lead-lag testing problem: 给定两条时间序列，判定是否存在 temporal precedence\"\n      - \"5 种方法简述：naive cross-correlation, differenced cross-correlation, threshold onset, permutation Granger, Toda-Yamamoto\"\n\n  - section: method\n    word_budget: 1300\n    dependencies: [background]\n    subsections:\n      - name: \"Methodological Pitfalls in Lead-Lag Analysis\"\n        word_budget: 400\n        key_points:\n          - \"Pitfall 1 — Method sensitivity: naive Pearson 100% sig vs permutation Granger 25% (16/16 → 6/16)\"\n          - \"Pitfall 2 — Spurious regression: canary→perplexity 差分后 0/8 SIG (F≈0, p=0.99)，diversity 通道不变\"\n          - \"Pitfall 3 — Regime dependence: 同一检验 α=1.0 24/24 FDR-sig → α≤0.50 0/8\"\n      - name: \"Multi-Method Consensus Framework\"\n        word_budget: 500\n        key_points:\n          - \"Definition: pair (X,Y) classified ROBUST iff ≥K/M methods judge significant AND ≥S/N seeds replicate\"\n          - \"Sequential filtering pipeline: naive → differencing → Granger+FDR → multi-seed\"\n          - \"Default: K=4/5, S=3/4 (empirically calibrated)\"\n      - name: \"Empirical Calibration\"\n        word_budget: 300\n        key_points:\n          - \"FPR from α=0.0 null control (no synthetic data)\"\n          - \"FNR from α=1.0 (4 seeds, 6 ground-truth robust pairs)\"\n          - \"K=4/5 S=3/4 achieves FPR=0 FNR=0 on reference extremes\"\n          - \"D041 约束: FNR 独立验证 via D017 differencing\"\n          - \"Discussion 声明: calibration limited to current setup\"\n\n  - section: experiments\n    word_budget: 2100\n    dependencies: [method]\n    subsections:\n      - name: \"Experimental Setup\"\n        word_budget: 300\n        key_points:\n          - \"Pythia-410M, WikiText-103 5K subset, 10 generations, 5000 steps/gen\"\n          - \"α ∈ {0, 0.25, 0.50, 0.75, 1.0}, seeds {42,43,44,45}\"\n          - \"Metrics: token_entropy, ECE (next-token), distinct_1/2/3, perplexity\"\n          - \"Statistical: BH FDR q=0.05, 5000 permutations\"\n      - name: \"Method Sensitivity Analysis (Claim 3)\"\n        word_budget: 500\n        key_points:\n          - \"5-method ablation: naive→differenced→threshold→permG→TY sig rates\"\n          - \"2×2 差分对比: diversity channel (12/12→12/12) vs perplexity channel (8/8→0/8)\"\n          - \"d_max sensitivity: 0%↔94% spurious rate swing\"\n          - \"Cohen κ=0.185 (poor inter-method agreement)\"\n          - \"method × α interaction: naive 100% everywhere vs permG dose-response\"\n          - \"Ref to Fig 2\"\n      - name: \"Regime-Dependent Detectability (Claim 2)\"\n        word_budget: 400\n        key_points:\n          - \"5-point regime map: Granger FDR sig rate vs α\"\n          - \"Detectability boundary at α≈0.50-0.75\"\n          - \"Raw drift magnitude dose-response (primary): distinct_1 -14%→-40%→-93%\"\n          - \"Non-monotonic diversity decline at α=0.25 (single-seed caveat)\"\n          - \"α=0.50 null = positive finding (synchronous collapse, no temporal lead)\"\n          - \"Ref to Fig 1, Fig 3\"\n      - name: \"Case Study: Canary Prediction (Claim 1)\"\n        word_budget: 400\n        key_points:\n          - \"token_entropy Granger-causes distinct_1/2 at α≥0.75\"\n          - \"α=1.0: 24/24 FDR-sig across 4 seeds, cross-corr lag=+1 (r>0.99, std=0.0)\"\n          - \"α=0.75: 3/4 FDR-sig (single-seed, C001 caveat), entropy→d1 borderline p_fdr=0.054\"\n          - \"ECE as conditional secondary canary (equivalent in 4/5 methods, TY Type II only)\"\n          - \"Consensus framework application: 6/16 robust pairs survive full pipeline\"\n          - \"Ref to Fig 4, Fig 5\"\n      - name: \"Consensus Framework Validation\"\n        word_budget: 200\n        key_points:\n          - \"FPR=0 at α=0.0 null control\"\n          - \"FNR=0 on 6 reference robust pairs (independently validated by D017 differencing)\"\n          - \"Comparison: naive FPR=100%, TY FNR=25%\"\n          - \"Ref to Table 3\"\n\n  - section: discussion\n    word_budget: 700\n    dependencies: [experiments]\n    key_points:\n      - \"Granger precedence ≠ true causality (Granger 1969); bivariate cannot exclude confounders\"\n      - \"Calibration limited to current setup (Pythia-410M, WikiText-103); generalization needs independent validation\"\n      - \"FPR/FNR dimension asymmetry (D041): FPR method-only, FNR method×seed joint\"\n      - \"Phase 3 three-phase dynamics (if multi-seed confirmed): observation window sensitivity as Claim 3 evidence\"\n      - \"Limitations: single architecture family, T=10 short series, no intervention experiment\"\n      - \"Future work: multi-variate VAR, cross-architecture validation, online monitoring integration\"\n\n  - section: conclusion\n    word_budget: 250\n    dependencies: [discussion]\n    key_points:\n      - \"Method choice matters: 3 pitfalls that can flip lead-lag conclusions\"\n      - \"Consensus framework: actionable from exploratory to publication-grade\"\n      - \"Practical takeaway: token entropy as 1-gen-ahead canary for diversity collapse at α≥0.75\"\n\nvisualization_plan:\n  - fig_id: fig_regime_map\n    type: line_with_threshold\n    description: \"Granger FDR p-value vs α (5-point) for 4 canary→diversity directions. Horizontal line at p=0.05. Shows detectability boundary at α≈0.50-0.75.\"\n    placement: \"Claim 2 core, §Experiments Regime-Dependent Detectability\"\n    aspect_ratio: \"single column (3.25in × 2.5in)\"\n    tool: matplotlib\n    data_source: \"registry: alpha_sweep_a000_s42, alpha_sweep_a025_s42_v3, alpha_sweep_a050_s42, alpha_sweep_a075_s42, mvp_v4_rep42; artifacts/D040/data/cross_alpha_v6.json\"\n    output_path: \"projects/distrib_canary_collapse/figures/paper/fig_regime_map.pdf\"\n    status: DONE\n    artifact_id: art_20260515_06ffe6\n\n  - fig_id: fig_differencing_dmax\n    type: multi_panel\n    description: \"2×2 multi-panel. Top row: 差分前后 significance heatmap (channel × differencing status); Bottom row: d_max sensitivity curves (spurious rate vs d_max for 3 settings). Shows Pitfall 1+2.\"\n    placement: \"Claim 3 core, §Experiments Method Sensitivity\"\n    aspect_ratio: \"double column (6.5in × 4in)\"\n    tool: matplotlib\n    data_source: \"registry: method_ablation_phase1, method_ablation_phase2; artifacts/D040/data/filtering_pipeline_data.json\"\n    output_path: \"projects/distrib_canary_collapse/figures/paper/fig_differencing_dmax.pdf\"\n    status: TODO\n\n  - fig_id: fig_consensus_heatmap\n    type: heatmap\n    description: \"Method × α significance rate heatmap. 5 methods (rows) × 5 α levels (columns). Cell color = FDR sig rate. Shows method×regime interaction.\"\n    placement: \"Bridge Claim 2+3, §Experiments after Regime Map\"\n    aspect_ratio: \"single column (3.25in × 2.5in)\"\n    tool: matplotlib\n    data_source: \"registry: method_ablation_phase2; artifacts/analysis/consensus_framework/consensus_classification.json\"\n    output_path: \"projects/distrib_canary_collapse/figures/paper/fig_consensus_heatmap.pdf\"\n    status: DONE\n    artifact_id: art_20260515_97707a\n\n  - fig_id: fig_metric_trajectory\n    type: line_plot\n    description: \"Single-panel: token_entropy and distinct_1 trajectories across 10 generations at α=1.0 (4-seed mean±std). Vertical annotation showing 1-gen lead. Normalized to gen 0.\"\n    placement: \"Claim 1 case study, §Experiments Case Study\"\n    aspect_ratio: \"single column (3.25in × 2.5in)\"\n    tool: matplotlib\n    data_source: \"registry: mvp_v4_rep42, mvp_v4_rep43, mvp_v4_rep44, mvp_v4_rep45\"\n    output_path: \"projects/distrib_canary_collapse/figures/paper/fig_metric_trajectory.pdf\"\n    status: TODO\n\n  - fig_id: fig_consensus_workflow\n    type: multi_panel\n    description: \"3-panel: (a) sequential filtering pipeline funnel (16→14→6→6 pairs at α=1.0); (b) FPR/FNR trade-off across K threshold; (c) practical guidance cards (4 tiers). Methodology contribution showcase.\"\n    placement: \"§Method / §Experiments Consensus Validation\"\n    aspect_ratio: \"double column (6.5in × 3in)\"\n    tool: matplotlib\n    data_source: \"artifacts/D040/data/filtering_pipeline_data.json; artifacts/D040/data/fpr_fnr_calibration.json\"\n    output_path: \"projects/distrib_canary_collapse/figures/paper/fig_consensus_workflow.pdf\"\n    status: DONE\n    artifact_id: art_20260515_390d50\n\ntable_plan:\n  - table_id: tab_drift_summary\n    type: metric_comparison\n    columns: [\"α\", \"token_entropy Δ%\", \"ECE Δ%\", \"distinct_1 Δ%\", \"distinct_2 Δ%\", \"perplexity Δ%\"]\n    data_source: \"registry: alpha_sweep_a000_s42, alpha_sweep_a025_s42_v3, alpha_sweep_a050_s42, alpha_sweep_a075_s42, mvp_v4_rep42 (α=1.0 mean of 4 seeds)\"\n    placement: \"§Experiments Setup or Regime Map\"\n    description: \"Raw metric drift across 5 α levels. Primary evidence for Claim 2 (regime-dependent).\"\n\n  - table_id: tab_method_comparison\n    type: significance_rates\n    columns: [\"Method\", \"α=0.0\", \"α=0.25\", \"α=0.50\", \"α=0.75\", \"α=1.0\", \"FPR (null)\"]\n    data_source: \"registry: method_ablation_phase2; artifacts/analysis/consensus_framework/fpr_fnr_table.json\"\n    placement: \"§Experiments Method Sensitivity\"\n    description: \"5-method FDR sig rates across α. Core Claim 3 table.\"\n\n  - table_id: tab_fpr_fnr\n    type: calibration\n    columns: [\"K (method threshold)\", \"S (seed threshold)\", \"FPR\", \"FNR_robust\", \"FNR_all\"]\n    data_source: \"artifacts/D040/data/fpr_fnr_calibration.json\"\n    placement: \"§Method Empirical Calibration or §Experiments Consensus Validation\"\n    description: \"FPR/FNR across 5K×4S = 20 configurations. Recommended K=4/5 S=3/4.\"\n\n  - table_id: tab_practical_guidance\n    type: guidance\n    columns: [\"Tier\", \"Use Case\", \"Methods Required\", \"Seed Requirement\", \"Expected FPR\", \"Expected FNR\"]\n    data_source: \"manual (from consensus_framework formalization)\"\n    placement: \"§Method or §Discussion\"\n    description: \"4-tier practical guidance: exploratory→screening→confirmatory→publication.\"\n\nliterature_strategy:\n  macro_context: \"Model collapse → canary/monitoring → lead-lag methodology → tipping points/EWS\"\n  micro_clusters:\n    - cluster_name: core_collapse\n      search_queries: [\"model collapse iterative training LLM\", \"self-consuming generative models\"]\n      must_cite: [shumailov2024curse, alemohammad2024mad, dohmatob2024tale, dohmatob2025strong, truong2025entropy]\n      target_count: 6\n    - cluster_name: canary_monitoring\n      search_queries: [\"early warning model collapse metrics\", \"ECE calibration synthetic data\"]\n      must_cite: [chen2025scales, sigma2026spectral, kalinowski2026topology]\n      target_count: 5\n    - cluster_name: data_mixing\n      search_queries: [\"synthetic data mixing ratio collapse prevention\"]\n      must_cite: [kazdan2025collapse, dey2024breaking, fu2025selfconsuming]\n      target_count: 4\n    - cluster_name: early_warning_tipping\n      search_queries: [\"early warning signals critical transitions ecology\"]\n      must_cite: [scheffer2009early, scheffer2012anticipating, boettiger2012limits]\n      target_count: 3\n    - cluster_name: methodology_granger\n      search_queries: [\"Granger causality review time series\"]\n      must_cite: [shojaie2022granger]\n      target_count: 2\n    - cluster_name: diversity_metrics\n      search_queries: [\"distinct-n text generation diversity\"]\n      must_cite: [li2016diversity, guo2024linguistic]\n      target_count: 2\n  citation_budget: 40-45\n\nwriting_order:\n  - step: 1\n    section: experiments\n    rationale: \"Data-driven, most constrained by registry. Write first to lock down all numbers.\"\n  - step: 2\n    section: method\n    rationale: \"Consensus framework definition. References Experiments for calibration data.\"\n  - step: 3\n    section: background\n    rationale: \"Definitions and notation needed by Method+Experiments, but content determined by them.\"\n  - step: 4\n    section: introduction\n    rationale: \"Frames the story. Needs final Experiments numbers for headline result.\"\n  - step: 5\n    section: related_work\n    rationale: \"Positions after Introduction sets framing. Needs verified references.\"\n  - step: 6\n    section: discussion\n    rationale: \"Limitations and future work, after all results known.\"\n  - step: 7\n    section: conclusion\n    rationale: \"Summary of contributions.\"\n  - step: 8\n    section: abstract\n    rationale: \"Last, summarizes everything.\"\n\npresentation_constraints:\n  - id: PC01\n    source: D038\n    rule: \"α=0.75 vs α=1.0 consensus scores 不可直接对比（标准不同：single-seed vs 4-seed）\"\n  - id: PC02\n    source: D038\n    rule: \"token_entropy→perplexity @ α=0.75 不可引用为 robust evidence（D017 confirmed spurious）\"\n  - id: PC03\n    source: D041\n    rule: \"FNR=0 声明必须补充 D017 独立证据，不能仅自引\"\n  - id: PC04\n    source: D041\n    rule: \"FPR/FNR 维度不对称须显式说明\"\n  - id: PC05\n    source: D042\n    rule: \"Discussion 须声明 calibration 仅适用于当前 setup\"\n  - id: PC06\n    source: D035\n    rule: \"Phase 3 三相动力学：如 multi-seed 确认，Claim 3 Results 末尾加 ~150 词\"\n  - id: PC07\n    source: paper_framing\n    rule: \"不能 claim canary predicts model collapse，只能 claim canary predicts diversity collapse\"\n  - id: PC08\n    source: paper_framing\n    rule: \"effective_rank 和 self_bleu 作为 canary 失败必须全量报告\"\n  - id: PC09\n    source: paper_framing\n    rule: \"distinct_3 放 supplementary，主文聚焦 distinct_1/2\"\n  - id: PC10\n    source: paper_framing\n    rule: \"f² 效应量禁用 Cohen 基准（df_resid<20），permutation p-value 为主要推断证据\"\n  - id: PC11\n    source: paper_framing\n    rule: \"Granger precedence ≠ true causality，Discussion 须声明\"\n  - id: PC12\n    source: paper_framing\n    rule: \"用 regime map 非 phase diagram（α 点不足）\"\n  - id: PC13\n    source: paper_framing\n    rule: \"CRS 降级为 illustration，不列入 core contribution\"\n  - id: PC14\n    source: paper_framing\n    rule: \"强度词限制：单数据集/实验禁用 consistently outperforms / state-of-the-art；无统计检验禁用 significantly\"\n  - id: PC15\n    source: paper_framing\n    rule: \"spurious_rate 双版本报告：含TY 75% / 排除TY 62.5%\"\n  - id: PC16\n    source: paper_framing\n    rule: \"α=0.75 single-seed caveat C001 标注\"\n  - id: PC17\n    source: paper_framing\n    rule: \"非单调性结论标注 observed at seed=42; multi-seed confirmation required\"\n\nrunning_experiments_note: |\n  以下实验仍在运行或排队，论文初稿基于已完成数据：\n  - RUNNING: gen_wiki_gpt2m_a100_s42_v3 (GPT-2-medium, ~45%, cuda:0)\n  - RUNNING: alpha_sweep_a025_s43 (multi-seed, ~57%, cuda:1)\n  - QUEUED: alpha_sweep_a050_s43, a025_s44, a050_s44, plan_006_s43, gen_wiki_gpt2m_a025_s42\n  初稿完成后，新数据到位时通过 Patch 模式更新。GPT-2-medium 结果如果到位，加入 Discussion 或 Supplementary。\n",
      "numLines": 363,
      "startLine": 1,
      "totalLines": 363
    }
  },
  "sourceToolAssistantUUID": "1e190fcf-4b2f-4022-be0d-f505a21cc2d9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Tool call

_source line 754 · 2026-05-20T10:04:39.166Z_

<details open><summary>🔧 Tool call — Read · `toolu_019mSjMxYQEwjnc6KsyqaQCq`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d2318007-f0de-4ae7-b1e4-147f58ef8c04",
  "isSidechain": false,
  "requestId": "req_011CbDdbGbHsxcAJ2cFy9cJd",
  "type": "assistant",
  "uuid": "1eef34b7-2335-4610-a857-2258924aec0b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Qba1ghYceSfqrEKdawtfyJ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 26814,
      "cache_read_input_tokens": 11841,
      "output_tokens": 320,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 26814,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 320,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 26814,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 26814
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

_source line 755_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Director 指令] [Reframe — D130] 论文从 Methodology Paper 转型为 Detection Phase Transition Discovery Paper  投稿目标：EMNLP 2026 ARR June cycle，8 页 main text + unlimited references + appendix。当前 37 页需大幅压缩。  ## 核心…",
  "leafUuid": "15e22217-2ac8-43b2-80d3-6b1b651e7c28",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


### Runtime record

_source line 756_

```json
{
  "type": "ai-title",
  "aiTitle": "Correct effective_rank framework and add phase transition citations",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


### Tool call

_source line 757 · 2026-05-20T10:04:43.019Z_

<details open><summary>🔧 Tool call — Read · `toolu_013boq9xhkRHcD1edY2MZeDs`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "15e22217-2ac8-43b2-80d3-6b1b651e7c28",
  "isSidechain": false,
  "requestId": "req_011CbDdbjfTscrvQ98HLDD8A",
  "type": "assistant",
  "uuid": "dc6f8c8f-bc75-4b20-a9ac-02802246be2d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019Xoa2Yo79oG4AZ6f48eGVL",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7918,
      "cache_read_input_tokens": 38655,
      "output_tokens": 233,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 7918,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 233,
          "cache_read_input_tokens": 38655,
          "cache_creation_input_tokens": 7918,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 7918
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

_source line 758 · 2026-05-20T10:04:43.038Z_

<details><summary>↩ Tool result · `toolu_013boq9xhkRHcD1edY2MZeDs`</summary>

```text
1	\section{Introduction}
2	\label{sec:introduction}
3	
4	When language models train iteratively on their own output, the training distribution progressively loses its tail modes, a phenomenon termed model collapse~\cite{shumailov2024curse,alemohammad2024mad}.
5	Lexical diversity narrows, calibration deteriorates, and each generation inherits the systematic biases of its predecessors.
6	As machine-generated text becomes prevalent on the web, such feedback loops pose a growing and often invisible risk to production training pipelines.
7	By the time standard quality metrics register degradation, the underlying distribution may have already shifted irreversibly.
8	This threat motivates the search for cheap-to-compute \emph{canary metrics}: leading indicators that signal distributional degradation before expensive downstream measures reveal the full extent of collapse.
9	The concept parallels early-warning signals for critical transitions in ecological systems~\cite{scheffer2009early,scheffer2012anticipating}, where proxy indicators allow intervention before a tipping point.
10	Several recent studies have pursued this direction: \citet{du2026geometric} observe that calibration error rises before accuracy degrades, SIGMA~\cite{sigma2026spectral} proposes spectral indicators, and DCES~\cite{dces2026counter} uses center-edge sampling dynamics as a collapse signal.
11	
12	Yet the statistical methodology underlying these lead-lag claims has received little scrutiny.
13	Whether a candidate canary genuinely \emph{precedes} downstream degradation, or merely correlates with it under shared non-stationary trends, is a question that existing analyses leave unresolved.
14	Iterative training produces short, noisy time series (often fewer than 15 points per generation sequence), where detection power drops sharply and false positive rates can be high~\cite{boettiger2012limits}.
15	In the absence of proper controls, the choice of statistical method alone can shift conclusions on the same data from universal significance to complete null.
16	This makes the validity of existing canary claims an open question with direct consequences for practitioners who rely on such signals to trigger training interventions.
17	
18	We identify four specific deficiencies that pervade existing lead-lag analyses of iterative training collapse.
19	(1)~No differencing tests rule out spurious regression from shared non-stationary trends, a well-documented hazard in analyses of co-trending time series~\cite{granger1974spurious}.
20	(2)~Conclusions rest on a single statistical method whose assumptions about stationarity and directionality are rarely examined; no multi-method cross-validation is conducted.
21	(3)~No false discovery rate (FDR) correction (e.g., Benjamini--Hochberg) guards against spurious findings when testing many metric pairs simultaneously.
22	(4)~No regime-dependent analysis is performed, despite the possibility that the same test yields opposite conclusions at different contamination levels.
23	The closest predecessor is \citet{du2026geometric}, who report that calibration error rises before accuracy degrades in iteratively trained language models.
24	Their analysis, however, covers a single metric pair, spans only 1--3 generations, and relies on visual comparisons without statistical tests.
25	The early-warning framework of \citet{scheffer2009early,scheffer2012anticipating} provides theoretical motivation but has not been applied to training collapse with the rigor that such short, non-stationary series require.
26	
27	We address these gaps through a multiverse-style analysis~\cite{bell2022modeling,kapoor2024reforms} of canary prediction of diversity collapse, the progressive loss of lexical diversity (as measured by distinct-$n$~\cite{li2016diversity}) across training generations.
28	Using Pythia-410M~\cite{biderman2023pythia} across six contamination levels ($\alpha \in \{0.00, 0.10, 0.25, 0.50, 0.75, 1.00\}$) and up to four random seeds, we apply five statistical methods to expose three methodological pitfalls (method sensitivity, spurious regression, and regime dependence) through the Multi-Method Consensus Test (MMCT), a formal FPR-inverse-weighted consensus framework inspired by specification curve analysis~\cite{simonsohn2020specification}.
29	An extended eight-point regime map ($\alpha \in \{0.00, 0.05, 0.10, 0.25, 0.50, 0.60, 0.75, 1.00\}$) reveals a canary blind spot: at $\alpha{=}0.10$, diversity has already collapsed measurably but canary metrics remain at null levels, which places a detection lower bound at $\alpha{\geq}0.50$.
30	Permutation Granger causality emerges as the only method with both zero null-control FPR and high sensitivity; applied to token entropy, it identifies a robust one-generation-ahead canary for diversity collapse, and early detection enables timely cessation of synthetic-data training, reducing peak perplexity by 58\% compared to reactive cessation at $\alpha{\geq}0.75$.
31	Cross-architecture validation on GPT-2-medium and OPT-1.3B confirms that these findings transfer beyond the primary experimental platform.
32	Granger precedence in our framework establishes temporal predictive improvement, not true causality~\cite{shojaie2022granger}; our canary claim is scoped to diversity metrics, not model collapse broadly.
33	To our knowledge, this constitutes the first multiverse-style analysis of lead-lag claims in model collapse: the same dataset, analyzed with five methods across six contamination regimes, yields conclusions that span the full spectrum from universal significance to complete null.
34	
35	Our contributions are:
36	\begin{enumerate}
37	    \item \textbf{Systematic multi-method evaluation framework} (\S\ref{sec:method}, \S\ref{sec:method_sensitivity}).
38	    We apply five lead-lag detection methods to the same data and expose three methodological pitfalls: method choice alone inflates spurious-signal rates to at least 62.5\% (inter-method $\kappa{=}0.185$), first-differencing eliminates canary$\to$perplexity associations entirely ($F{\approx}0$, $p{=}0.99$), and regime dependence causes the same Granger test to shift from 20/24 FDR-significant pairs at $\alpha{=}0.75$ to 0/24 at $\alpha{\leq}0.25$.
39	    The Multi-Method Consensus Test (MMCT) formalizes this comparison through FPR-inverse weighted consensus with null-calibrated $p$-values.
40	    Shapley-value decomposition (exact 32-coalition enumeration; Figure~\ref{fig:shapley}) identifies naive cross-correlation as the sole FPR driver (Shapley(FPR)${=}{+}0.348$) and permutation Granger as the strongest suppressor (Shapley(FPR)${=}{-}0.194$).
41	
42	    \item \textbf{Permutation Granger causality as the recommended detection method} (\S\ref{sec:case_study}, \S\ref{sec:generalization}).
43	    Among the five methods evaluated, permutation Granger causality (PermG) is the only one combining zero null-control FPR with high sensitivity.
44	    PermG identifies token entropy as a one-generation-ahead canary for diversity collapse: on WikiText-103, 24/24 forward-direction pairs are FDR-significant and 0/24 in the reverse direction at $\alpha{=}1.0$ (4 seeds $\times$ 6 metric pairs), confirmed across GPT-2-medium, OPT-1.3B, and four additional model families.
45	    Cross-architecture validation across 14 model-seed combinations spanning six families (345M--6.9B) confirms PermG detection (${\geq}6/8$) in 12 cases (86\%).
46	    At $\alpha{=}0.75$, three-seed replication yields 20/24 forward and 0/24 reverse.
47	    This claim is scoped to diversity metrics (distinct-$n$); the perplexity channel is spurious.
48	
49	    \item \textbf{Dose-response characterization revealing a detection phase transition} (\S\ref{sec:regime}).
50	    A signal-times-resolution framework (\S\ref{sec:theory}) predicts non-monotonic detectability; PermG confirms a four-regime structure: 0/8 through $\alpha{=}0.45$ (blind), near-discontinuous onset at $\alpha{=}0.50$ (6/8, dual-seed), a synchronous dip at $\alpha{=}0.60$ (0--3/8), and reliable detection at $\alpha{\geq}0.75$ (5--6/8 per seed, three seeds; 6/8 per seed at $\alpha{=}1.0$, four seeds).
51	    Sigmoid regression quantifies the onset as a detection phase transition ($\alpha_c{=}0.476$, sigmoid $R^2{=}0.969$, $\Delta\alpha{\approx}0.02$), occurring despite only 0.15 percentage points difference in cumulative contamination across the transition boundary.
52	    At $\alpha{=}0.10$, a canary blind spot emerges: diversity has already collapsed (distinct-1 drops 39.6\%) but canary metrics remain indistinguishable from the null condition (entropy drift $-5.3\%$ vs.\ null $-4.6{\pm}0.4\%$, a gap of less than one percentage point).
53	
54	    \item \textbf{Canary-based early detection and cessation} (\S\ref{sec:intervention}).
55	    As a practical demonstration, we compare predictive cessation (triggered when token entropy drops ${>}15\%$) against reactive cessation (triggered when distinct-1 drops ${>}10\%$).
56	    The entropy-based trigger fires one generation earlier, enabling cessation of synthetic-data training before irreversible damage: peak perplexity is reduced by 58\% (pooled estimate; bootstrap 95\% CI: 29--64\%)\footnote{Bootstrap CI computed from two seed-precision pairs (s42 fp32, s43 bf16); the interval reflects observed variation rather than population-level uncertainty.} and convergence completes one generation faster (Generation~2 vs.\ Generation~3).
57	    At $\alpha{=}0.75$, entropy drops 31.6\% at generation~1, exceeding the 15\% threshold and confirming that the trigger generalizes beyond full synthetic replacement.
58	    Results are validated at $\alpha{=}1.0$ across two model scales: Pythia-410M (s42 fp32; s43 bf16, subject to precision effects discussed in \S\ref{sec:discussion}) and Pythia-1.4B (s42 fp32), confirming that the trigger and recovery pattern is scale-independent.
59	\end{enumerate}
60	
61	The remainder of this paper is organized as follows.
62	\S\ref{sec:related_work} surveys related work on model collapse, early-warning signals, and lead-lag methodology.
63	\S\ref{sec:background} establishes the formal setup, notation, and the five detection methods used throughout.
64	\S\ref{sec:method} distills the three methodological pitfalls into a unified diagnostic framework, presents the multi-method consensus pipeline, and reports its empirical calibration.
65	\S\ref{sec:experiments} provides full experimental results: method sensitivity analysis (\S\ref{sec:method_sensitivity}), regime-dependent detectability (\S\ref{sec:regime}), canary prediction of diversity collapse (\S\ref{sec:case_study}), consensus framework validation (\S\ref{sec:consensus_validation}), cross-architecture generalization (\S\ref{sec:generalization}), and canary-based early intervention (\S\ref{sec:intervention}).
66	\S\ref{sec:discussion} discusses implications and future directions, and \S\ref{sec:conclusion} concludes, followed by a dedicated Limitations section (\S\ref{sec:limitations}).
67	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "dc6f8c8f-bc75-4b20-a9ac-02802246be2d",
  "isSidechain": false,
  "promptId": "0bc1eef6-835a-4ee4-a8a1-06010792cb3b",
  "type": "user",
  "uuid": "3e9d7b55-e55a-4676-8fed-1416a89d1799",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/introduction.tex",
      "content": "\\section{Introduction}\n\\label{sec:introduction}\n\nWhen language models train iteratively on their own output, the training distribution progressively loses its tail modes, a phenomenon termed model collapse~\\cite{shumailov2024curse,alemohammad2024mad}.\nLexical diversity narrows, calibration deteriorates, and each generation inherits the systematic biases of its predecessors.\nAs machine-generated text becomes prevalent on the web, such feedback loops pose a growing and often invisible risk to production training pipelines.\nBy the time standard quality metrics register degradation, the underlying distribution may have already shifted irreversibly.\nThis threat motivates the search for cheap-to-compute \\emph{canary metrics}: leading indicators that signal distributional degradation before expensive downstream measures reveal the full extent of collapse.\nThe concept parallels early-warning signals for critical transitions in ecological systems~\\cite{scheffer2009early,scheffer2012anticipating}, where proxy indicators allow intervention before a tipping point.\nSeveral recent studies have pursued this direction: \\citet{du2026geometric} observe that calibration error rises before accuracy degrades, SIGMA~\\cite{sigma2026spectral} proposes spectral indicators, and DCES~\\cite{dces2026counter} uses center-edge sampling dynamics as a collapse signal.\n\nYet the statistical methodology underlying these lead-lag claims has received little scrutiny.\nWhether a candidate canary genuinely \\emph{precedes} downstream degradation, or merely correlates with it under shared non-stationary trends, is a question that existing analyses leave unresolved.\nIterative training produces short, noisy time series (often fewer than 15 points per generation sequence), where detection power drops sharply and false positive rates can be high~\\cite{boettiger2012limits}.\nIn the absence of proper controls, the choice of statistical method alone can shift conclusions on the same data from universal significance to complete null.\nThis makes the validity of existing canary claims an open question with direct consequences for practitioners who rely on such signals to trigger training interventions.\n\nWe identify four specific deficiencies that pervade existing lead-lag analyses of iterative training collapse.\n(1)~No differencing tests rule out spurious regression from shared non-stationary trends, a well-documented hazard in analyses of co-trending time series~\\cite{granger1974spurious}.\n(2)~Conclusions rest on a single statistical method whose assumptions about stationarity and directionality are rarely examined; no multi-method cross-validation is conducted.\n(3)~No false discovery rate (FDR) correction (e.g., Benjamini--Hochberg) guards against spurious findings when testing many metric pairs simultaneously.\n(4)~No regime-dependent analysis is performed, despite the possibility that the same test yields opposite conclusions at different contamination levels.\nThe closest predecessor is \\citet{du2026geometric}, who report that calibration error rises before accuracy degrades in iteratively trained language models.\nTheir analysis, however, covers a single metric pair, spans only 1--3 generations, and relies on visual comparisons without statistical tests.\nThe early-warning framework of \\citet{scheffer2009early,scheffer2012anticipating} provides theoretical motivation but has not been applied to training collapse with the rigor that such short, non-stationary series require.\n\nWe address these gaps through a multiverse-style analysis~\\cite{bell2022modeling,kapoor2024reforms} of canary prediction of diversity collapse, the progressive loss of lexical diversity (as measured by distinct-$n$~\\cite{li2016diversity}) across training generations.\nUsing Pythia-410M~\\cite{biderman2023pythia} across six contamination levels ($\\alpha \\in \\{0.00, 0.10, 0.25, 0.50, 0.75, 1.00\\}$) and up to four random seeds, we apply five statistical methods to expose three methodological pitfalls (method sensitivity, spurious regression, and regime dependence) through the Multi-Method Consensus Test (MMCT), a formal FPR-inverse-weighted consensus framework inspired by specification curve analysis~\\cite{simonsohn2020specification}.\nAn extended eight-point regime map ($\\alpha \\in \\{0.00, 0.05, 0.10, 0.25, 0.50, 0.60, 0.75, 1.00\\}$) reveals a canary blind spot: at $\\alpha{=}0.10$, diversity has already collapsed measurably but canary metrics remain at null levels, which places a detection lower bound at $\\alpha{\\geq}0.50$.\nPermutation Granger causality emerges as the only method with both zero null-control FPR and high sensitivity; applied to token entropy, it identifies a robust one-generation-ahead canary for diversity collapse, and early detection enables timely cessation of synthetic-data training, reducing peak perplexity by 58\\% compared to reactive cessation at $\\alpha{\\geq}0.75$.\nCross-architecture validation on GPT-2-medium and OPT-1.3B confirms that these findings transfer beyond the primary experimental platform.\nGranger precedence in our framework establishes temporal predictive improvement, not true causality~\\cite{shojaie2022granger}; our canary claim is scoped to diversity metrics, not model collapse broadly.\nTo our knowledge, this constitutes the first multiverse-style analysis of lead-lag claims in model collapse: the same dataset, analyzed with five methods across six contamination regimes, yields conclusions that span the full spectrum from universal significance to complete null.\n\nOur contributions are:\n\\begin{enumerate}\n    \\item \\textbf{Systematic multi-method evaluation framework} (\\S\\ref{sec:method}, \\S\\ref{sec:method_sensitivity}).\n    We apply five lead-lag detection methods to the same data and expose three methodological pitfalls: method choice alone inflates spurious-signal rates to at least 62.5\\% (inter-method $\\kappa{=}0.185$), first-differencing eliminates canary$\\to$perplexity associations entirely ($F{\\approx}0$, $p{=}0.99$), and regime dependence causes the same Granger test to shift from 20/24 FDR-significant pairs at $\\alpha{=}0.75$ to 0/24 at $\\alpha{\\leq}0.25$.\n    The Multi-Method Consensus Test (MMCT) formalizes this comparison through FPR-inverse weighted consensus with null-calibrated $p$-values.\n    Shapley-value decomposition (exact 32-coalition enumeration; Figure~\\ref{fig:shapley}) identifies naive cross-correlation as the sole FPR driver (Shapley(FPR)${=}{+}0.348$) and permutation Granger as the strongest suppressor (Shapley(FPR)${=}{-}0.194$).\n\n    \\item \\textbf{Permutation Granger causality as the recommended detection method} (\\S\\ref{sec:case_study}, \\S\\ref{sec:generalization}).\n    Among the five methods evaluated, permutation Granger causality (PermG) is the only one combining zero null-control FPR with high sensitivity.\n    PermG identifies token entropy as a one-generation-ahead canary for diversity collapse: on WikiText-103, 24/24 forward-direction pairs are FDR-significant and 0/24 in the reverse direction at $\\alpha{=}1.0$ (4 seeds $\\times$ 6 metric pairs), confirmed across GPT-2-medium, OPT-1.3B, and four additional model families.\n    Cross-architecture validation across 14 model-seed combinations spanning six families (345M--6.9B) confirms PermG detection (${\\geq}6/8$) in 12 cases (86\\%).\n    At $\\alpha{=}0.75$, three-seed replication yields 20/24 forward and 0/24 reverse.\n    This claim is scoped to diversity metrics (distinct-$n$); the perplexity channel is spurious.\n\n    \\item \\textbf{Dose-response characterization revealing a detection phase transition} (\\S\\ref{sec:regime}).\n    A signal-times-resolution framework (\\S\\ref{sec:theory}) predicts non-monotonic detectability; PermG confirms a four-regime structure: 0/8 through $\\alpha{=}0.45$ (blind), near-discontinuous onset at $\\alpha{=}0.50$ (6/8, dual-seed), a synchronous dip at $\\alpha{=}0.60$ (0--3/8), and reliable detection at $\\alpha{\\geq}0.75$ (5--6/8 per seed, three seeds; 6/8 per seed at $\\alpha{=}1.0$, four seeds).\n    Sigmoid regression quantifies the onset as a detection phase transition ($\\alpha_c{=}0.476$, sigmoid $R^2{=}0.969$, $\\Delta\\alpha{\\approx}0.02$), occurring despite only 0.15 percentage points difference in cumulative contamination across the transition boundary.\n    At $\\alpha{=}0.10$, a canary blind spot emerges: diversity has already collapsed (distinct-1 drops 39.6\\%) but canary metrics remain indistinguishable from the null condition (entropy drift $-5.3\\%$ vs.\\ null $-4.6{\\pm}0.4\\%$, a gap of less than one percentage point).\n\n    \\item \\textbf{Canary-based early detection and cessation} (\\S\\ref{sec:intervention}).\n    As a practical demonstration, we compare predictive cessation (triggered when token entropy drops ${>}15\\%$) against reactive cessation (triggered when distinct-1 drops ${>}10\\%$).\n    The entropy-based trigger fires one generation earlier, enabling cessation of synthetic-data training before irreversible damage: peak perplexity is reduced by 58\\% (pooled estimate; bootstrap 95\\% CI: 29--64\\%)\\footnote{Bootstrap CI computed from two seed-precision pairs (s42 fp32, s43 bf16); the interval reflects observed variation rather than population-level uncertainty.} and convergence completes one generation faster (Generation~2 vs.\\ Generation~3).\n    At $\\alpha{=}0.75$, entropy drops 31.6\\% at generation~1, exceeding the 15\\% threshold and confirming that the trigger generalizes beyond full synthetic replacement.\n    Results are validated at $\\alpha{=}1.0$ across two model scales: Pythia-410M (s42 fp32; s43 bf16, subject to precision effects discussed in \\S\\ref{sec:discussion}) and Pythia-1.4B (s42 fp32), confirming that the trigger and recovery pattern is scale-independent.\n\\end{enumerate}\n\nThe remainder of this paper is organized as follows.\n\\S\\ref{sec:related_work} surveys related work on model collapse, early-warning signals, and lead-lag methodology.\n\\S\\ref{sec:background} establishes the formal setup, notation, and the five detection methods used throughout.\n\\S\\ref{sec:method} distills the three methodological pitfalls into a unified diagnostic framework, presents the multi-method consensus pipeline, and reports its empirical calibration.\n\\S\\ref{sec:experiments} provides full experimental results: method sensitivity analysis (\\S\\ref{sec:method_sensitivity}), regime-dependent detectability (\\S\\ref{sec:regime}), canary prediction of diversity collapse (\\S\\ref{sec:case_study}), consensus framework validation (\\S\\ref{sec:consensus_validation}), cross-architecture generalization (\\S\\ref{sec:generalization}), and canary-based early intervention (\\S\\ref{sec:intervention}).\n\\S\\ref{sec:discussion} discusses implications and future directions, and \\S\\ref{sec:conclusion} concludes, followed by a dedicated Limitations section (\\S\\ref{sec:limitations}).\n",
      "numLines": 67,
      "startLine": 1,
      "totalLines": 67
    }
  },
  "sourceToolAssistantUUID": "dc6f8c8f-bc75-4b20-a9ac-02802246be2d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Tool call

_source line 759 · 2026-05-20T10:04:43.503Z_

<details open><summary>🔧 Tool call — Read · `toolu_01X9FBCo8YuxaejDx43eRsrD`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3e9d7b55-e55a-4676-8fed-1416a89d1799",
  "isSidechain": false,
  "requestId": "req_011CbDdbjfTscrvQ98HLDD8A",
  "type": "assistant",
  "uuid": "bd354e0c-092e-4fc6-bbba-fade3ad71384",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019Xoa2Yo79oG4AZ6f48eGVL",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7918,
      "cache_read_input_tokens": 38655,
      "output_tokens": 233,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 7918,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 233,
          "cache_read_input_tokens": 38655,
          "cache_creation_input_tokens": 7918,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 7918
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

_source line 760 · 2026-05-20T10:04:43.790Z_

<details><summary>↩ Tool result · `toolu_01X9FBCo8YuxaejDx43eRsrD`</summary>

```text
1	\section{Experiments}
2	\label{sec:experiments}
3	
4	\subsection{Experimental Setup}
5	\label{sec:setup}
6	
7	We study lead-lag analysis pitfalls in iterative training collapse using Pythia-410M \cite{biderman2023pythia}, a 410M-parameter decoder-only language model.
8	Pythia provides a controlled setting: small enough for multi-seed experiments across six contamination levels, yet large enough to exhibit meaningful generation-over-generation degradation.
9	Cross-architecture validation uses GPT-2-medium (345M parameters, also decoder-only), a second transformer family of similar scale; results are reported in \S\ref{sec:method_sensitivity}, \S\ref{sec:regime}, and \S\ref{sec:discussion}.
10	Training data is drawn from WikiText-103 \cite{merity2017pointer}, using 5{,}000-sample subsets per generation.
11	
12	Our protocol follows the replace paradigm of \citet{shumailov2024curse}, adapted for mixed synthetic-real training at $\alpha{<}1.0$.
13	Each generation $t$ proceeds in three steps: (1)~fine-tune the generation-$(t{-}1)$ model for 5{,}000 steps on a mixture of $\alpha$ fraction synthetic data and $(1{-}\alpha)$ fraction real data (AdamW optimizer, learning rate $5 \times 10^{-5}$, 500 warmup steps, weight decay $0.01$, batch size 4 for Pythia-410M, 32 for GPT-2-medium); (2)~generate 5{,}000 synthetic samples from the fine-tuned model (temperature $1.0$, top-$k{=}50$, max length 512 tokens); (3)~fully replace the synthetic pool.
14	We run $T{=}10$ generations (11 time points including the generation-0 baseline) across contamination levels $\alpha \in \{0.00, 0.10, 0.25, 0.50, 0.75, 1.00\}$.
15	The $\alpha{=}1.0$ condition uses four random seeds $\{42, 43, 44, 45\}$; $\alpha \in \{0.00, 0.25, 0.50, 0.75\}$ each use three seeds $\{42, 43, 44\}$; $\alpha{=}0.10$ uses a single seed (42, preliminary).
16	
17	We track two \emph{canary metrics} (cheap-to-compute statistics hypothesized to precede downstream degradation, inspired by early-warning signals in dynamical systems \cite{scheffer2009early}) and three \emph{downstream metrics}.
18	Canary metrics are token entropy (next-token prediction entropy averaged over held-out samples) and expected calibration error (ECE).
19	Downstream metrics are distinct-1 and distinct-2 ($n$-gram diversity \cite{li2016diversity}, computed over all 5{,}000 generated samples per generation) and perplexity (evaluated on held-out real data).
20	Token entropy is the mean next-token prediction entropy $H(p_\theta | \text{context})$ averaged over 1{,}000 held-out samples; ECE uses 15 equal-width bins.
21	We additionally evaluate effective rank and Self-BLEU as candidate canaries (\S\ref{sec:case_study}).
22	Results for distinct-3 are reported in Appendix~\ref{app:distinct3}.
23	Code and data will be released upon publication.
24	
25	All hypothesis tests apply Benjamini--Hochberg (BH) FDR correction at $q{=}0.05$.
26	Permutation Granger causality tests use 5{,}000 permutations on first-differenced series \cite{shojaie2022granger}.
27	Cross-correlation analysis uses a maximum lag of 5 generations.
28	Table~\ref{tab:drift_summary} summarizes raw metric drift from generation~0 to generation~10 across all six contamination levels.
29	
30	\begin{table}[t]
31	\centering
32	\small
33	\caption{Metric drift (\%, generation~0$\to$10) for Pythia-410M across contamination levels. Diversity collapse occurs at all $\alpha$ levels, with the strongest decline at low-to-moderate contamination ($\alpha{=}0.25$: distinct-1 $-40.3{\pm}0.3\%$) rather than full replacement ($\alpha{=}1.0$: $-27.8{\pm}1.6\%$). $^\dagger$$\alpha{=}0.10$: single seed (seed~42, preliminary). $\alpha{=}0.00$, $\alpha{=}0.25$, $\alpha{=}0.50$, $\alpha{=}0.75$: 3-seed mean${\pm}$std (seeds 42, 43, 44); $\alpha{=}1.0$: 4-seed mean${\pm}$std (seeds 42, 43, 44, 45).}
34	\label{tab:drift_summary}
35	\begin{tabular}{lccccc}
36	\toprule
37	$\alpha$ & Entropy & ECE & Distinct-1 & Distinct-2 & Perplexity \\
38	\midrule
39	0.00 & $-4.6{\pm}0.4$ & $+37.6{\pm}14$ & $-14.1{\pm}0.4$ & $-9.6{\pm}0.4$ & $-20.6{\pm}1.0$ \\
40	0.10$^\dagger$ & $-5.3$ & $+57$ & $-39.6$ & $-56.4$ & $-21.0$ \\
41	0.25 & $-4.7{\pm}0.5$ & $+81.8{\pm}15.9$ & $-40.3{\pm}0.3$ & $-56.4{\pm}0.7$ & $-18.1{\pm}0.8$ \\
42	0.50 & $-18.0{\pm}0.5$ & $+822.6{\pm}18.3$ & $-37.1{\pm}0.4$ & $-50.4{\pm}1.0$ & $+21.0{\pm}0.1$ \\
43	0.75 & $-27.6{\pm}0.2$ & $+1791{\pm}18$ & $-32.3{\pm}0.5$ & $-41.0{\pm}1.0$ & $+182.6{\pm}0.7$ \\
44	1.00 & $-60.8{\pm}1.2$ & $+3780{\pm}30$ & $-27.8{\pm}1.6$ & $-34.0{\pm}3.3$ & $+3674{\pm}45$ \\
45	\bottomrule
46	\end{tabular}
47	\end{table}
48	
49	
50	\subsection{Method Sensitivity Analysis}
51	\label{sec:method_sensitivity}
52	
53	We open with Claim~3 (method sensitivity) because it conditions the interpretation of all subsequent results.
54	If different statistical methods yield contradictory conclusions on the same data, any single-method analysis is unreliable by construction.
55	
56	\paragraph{Five-method ablation.}
57	We apply five lead-lag detection methods to the $\alpha{=}1.0$ condition (4~seeds, 16 canary$\to$downstream pairs).
58	The fraction of pairs reaching BH-corrected FDR significance varies dramatically by method: naive cross-correlation \textbf{16/16} (100\%), differenced cross-correlation \textbf{14/16} (87.5\%), threshold onset detection \textbf{9/16} (56.3\%), permutation Granger causality \textbf{6/16} (37.5\%), and Toda--Yamamoto Granger \textbf{5/16} (31.3\%; moderate supplementary, \S\ref{sec:ty_limitation}).
59	Method choice alone swings significance from \textbf{100\% to 37.5\%} among the primary methods: 50--57\% of pairs classified as significant under one method flip to non-significant under another.
60	The spurious-signal rate (the fraction of pairs detected by the most liberal method but not confirmed by the most conservative) is at least \textbf{62.5\%} across the primary methods.
61	Table~\ref{tab:method_comparison} reports significance rates restricted to 8 validated canary$\to$downstream pairs (excluding failed candidates); the 16-pair rates above include effective rank and Self-BLEU to capture the full method-sensitivity landscape.
62	
63	\paragraph{First-differencing diagnostic.}
64	A single preprocessing decision can eliminate an entire analysis channel.
65	For canary$\to$diversity pairs at $\alpha{=}1.0$, all pairs retain unanimous FDR significance after first-differencing (24/24$\to$24/24), confirming genuine temporal precedence rather than shared-trend confounding.
66	For canary$\to$perplexity, however, undifferenced tests find near-universal significance ($F{=}16$--$36$) while differenced tests find \textbf{zero} significant pairs ($F{\approx}0$, $p{=}0.99$; Figure~\ref{fig:differencing_dmax}a).
67	The apparent canary$\to$perplexity relationship is entirely an artifact of co-trending.
68	Notably, at $\alpha{=}0.75$, differenced cross-correlation finds 8/8 pairs significant in \emph{both} forward and reverse directions per seed, demonstrating that this method alone cannot distinguish genuine directional precedence from shared dynamics even after detrending.
69	
70	\paragraph{Augmentation order sensitivity.}
71	Toda--Yamamoto Granger tests show extreme sensitivity to the augmentation order $d_{\max}$ (Figure~\ref{fig:differencing_dmax}b).
72	After correcting the statsmodels API incompatibility (\S\ref{sec:ty_limitation}), TY achieves moderate detection (3--4/8 at $\alpha{\geq}0.50$) at the default $d_{\max}{=}1$; however, the qualitative finding that this single hyperparameter can swing conclusions between near-universal significance and near-universal non-significance remains, consistent with known properties of the Toda--Yamamoto procedure~\cite{toda1995statistical}.
73	
74	\begin{figure}[t]
75	\centering
76	\includegraphics[width=\linewidth]{figures/differencing_dmax.pdf}
77	\caption{First-differencing diagnostic and augmentation order sensitivity (Pythia-410M, $\alpha{=}1.0$, 4~seeds). \textbf{(a)}~First-differencing eliminates the canary$\to$perplexity channel: undifferenced tests find near-universal significance ($F{=}16$--$36$) while differenced tests find zero significant pairs ($F{\approx}0$, $p{=}0.99$), exposing these associations as shared-trend artifacts. Canary$\to$diversity pairs retain significance after differencing (24/24$\to$24/24). \textbf{(b)}~Toda--Yamamoto Granger significance rates vary dramatically with augmentation order $d_{\max}$; after correcting the implementation (\S\ref{sec:ty_limitation}), TY achieves moderate detection at the default $d_{\max}{=}1$, but the qualitative sensitivity to this hyperparameter persists.}
78	\label{fig:differencing_dmax}
79	\end{figure}
80	
81	\paragraph{Inter-method agreement.}
82	Cohen's $\kappa$, averaged over all method pairs, is \textbf{0.185} (near chance; poor agreement); this value is consistent across contamination levels ($\alpha{=}0.0$ through $\alpha{=}1.0$), indicating that method disagreement is a structural property of the analysis rather than a regime-specific artifact.
83	Cross-architecture validation on GPT-2-medium (12 canary$\to$downstream pairs) yields Fleiss' $\kappa{=}0.091$, also in the ``slight agreement'' range, confirming that low inter-method agreement is not architecture-specific.
84	Restricting to three informative methods (excluding naive cross-correlation, which anchors the permissive extreme, and Toda--Yamamoto, which provides moderate supplementary signal) raises $\kappa$ to 0.667 (substantial agreement), indicating that the low full-panel $\kappa$ is driven by the deliberate inclusion of methods spanning the entire permissive-to-conservative spectrum rather than by fundamental incoherence among methods.
85	Table~\ref{tab:method_comparison} extends the analysis across contamination levels.
86	Direction checking (D111) itself constitutes a sensitivity dimension beyond the five statistical methods: restricting to forward-direction associations inverts naive cross-correlation's profile from uniformly high (${\approx}100\%$ undirected) to regime-dependent, revealing that much of its apparent signal was reverse-directional.
87	At $\alpha{=}0.0$ (null control), naive cross-correlation still finds \textbf{75\%} (6/8) of forward-direction pairs significant---lower than the undirected 100\%, but still a substantial FPR.
88	Permutation Granger correctly finds 0\%, achieving perfect null-control specificity.
89	At $\alpha{=}0.50$ (fp32), permutation Granger finds 75\% (6/8), while naive finds 37.5\% (Figure~\ref{fig:consensus_heatmap}; Table~\ref{tab:method_comparison}).
90	
91	\paragraph{Method$\times$regime interaction.}
92	Table~\ref{tab:method_comparison} reveals that direction checking reshapes the method hierarchy across contamination levels.
93	At $\alpha{=}0.25$, naive cross-correlation drops to 12.5\% while permutation Granger remains at 0\%, narrowing the gap visible in undirected analysis.
94	At $\alpha{\geq}0.75$, naive rises to 87.5\% while permutation Granger reaches 75\%; both methods detect, but naive's persistent 75\% null-control FPR means its high-$\alpha$ detections cannot be distinguished from false positives without the consensus framework.
95	This regime-dependent reversal, combined with the block structure visible in Figure~\ref{fig:consensus_heatmap}, motivates the regime-dependent analysis in \S\ref{sec:regime}.
96	
97	\paragraph{Why permutation Granger succeeds.}
98	The systematic comparison identifies PermG as the only method combining zero null-control FPR with consistent detection across all regimes where signal exists ($\alpha{\geq}0.50$).
99	Three properties explain this outcome.
100	First, the nonparametric permutation procedure inherently controls FPR by constructing the null distribution from the observed data rather than from distributional assumptions, making it robust to the non-stationarity that inflates false positives in correlation-based methods.
101	Second, Granger tests are directional by construction: they test whether past values of $X$ improve prediction of $Y$ beyond $Y$'s own history, naturally filtering the reverse-directional associations that inflate naive cross-correlation's FPR.
102	Third, PermG does not require threshold calibration or augmentation order selection, avoiding the hyperparameter sensitivity observed in Toda--Yamamoto (Figure~\ref{fig:differencing_dmax}b; \S\ref{sec:ty_limitation}) and the power limitations that reduce threshold onset to near-zero detection under $3\sigma$ calibration (\S\ref{sec:threshold_limitation}).
103	By contrast, differenced cross-correlation retains 100\% FDR significance in both forward \emph{and} reverse directions at $\alpha{=}0.75$, failing to distinguish genuine directional precedence from shared dynamics; and Toda--Yamamoto, while achieving moderate detection (3--4/8 at $\alpha{\geq}0.50$), remains sensitive to the augmentation order $d_{\max}$ (\S\ref{sec:ty_limitation}).
104	These complementary failures, exposed through the MMCT evaluation framework, converge on a single recommendation: for short iterative training series ($T{\leq}20$), permutation Granger causality should be the primary detection method.
105	
106	\begin{figure}[t]
107	\centering
108	\includegraphics[width=\linewidth]{figures/consensus_heatmap.pdf}
109	\caption{Method$\times$regime consensus heatmap (Pythia-410M, fp32, 12 contamination levels, direction-checked). Each cell shows the forward-direction detection rate (\% of 8 pairs reaching FDR significance) for five individual methods (top) and two consensus thresholds (bottom, separated by white line). Direction checking dramatically reshapes method profiles: naive cross-correlation drops from near-100\% (undirected) to regime-dependent rates with persistent 75\% null-control FPR. Permutation Granger achieves FPR${=}$0\% in the blind zone (green dashed box) and detects only at $\alpha{\geq}0.50$. The onset boundary ($\alpha{\approx}0.45$--$0.50$) is where method divergence is sharpest (Pitfall~3). \emph{Note: figure will be regenerated with D120 canonical data including corrected TY rates (\S\ref{sec:ty_limitation}).}}
110	\label{fig:consensus_heatmap}
111	\end{figure}
112	
113	\begin{table}[t]
114	\centering
115	\small
116	\caption{Forward-direction FDR significance rates (\%) for five lead-lag methods across contamination levels (Pythia-410M, seed~42, fp32, direction-checked). Direction checking reshapes method profiles: naive cross-correlation drops from near-100\% (undirected) to regime-dependent rates (75\% at the null, 12.5\% at $\alpha{=}0.25$, rising to 87.5\% at $\alpha{=}0.75$). Each cell reports the fraction of 8 validated canary$\to$downstream pairs reaching BH-corrected significance ($q{=}0.05$) in the forward direction. $^\dagger$Moderate supplementary method (\S\ref{sec:ty_limitation}); FPR$_\text{null}$ pending (null condition not yet run through corrected pipeline). $^a$Seed-42 null-control rate under D105 $3\sigma$ calibration pending; 3-seed range 12.5--37.5\%.}
117	\label{tab:method_comparison}
118	\begin{tabular}{lcccccc}
119	\toprule
120	Method & $\alpha{=}0.0$ & $\alpha{=}0.25$ & $\alpha{=}0.50$ & $\alpha{=}0.75$ & $\alpha{=}1.0$ & FPR$_\text{null}$ \\
121	\midrule
122	Naive XCorr     & 75    & 12.5 & 37.5 & 87.5  & 0     & 75   \\
123	Diff.\ XCorr    & 0     & 37.5 & 87.5 & 75    & 75    & 0    \\
124	Threshold ($3\sigma$)$^a$ & ---   & 0    & 50   & 0     & 0     & ---  \\
125	Perm.\ Granger  & 0     & 0    & 75   & 75    & 75    & 0    \\
126	Toda--Yamamoto$^\dagger$  & ---   & 0    & 37.5 & 37.5  & 50    & ---  \\
127	\bottomrule
128	\end{tabular}
129	\end{table}
130	
131	
132	\subsection{Regime-Dependent Detectability}
133	\label{sec:regime}
134	
135	Beyond method choice, the contamination level~$\alpha$ determines whether a temporal lead exists to detect.
136	We present regime effects at two levels: raw metric drift (method-independent) and Granger-precedence detectability.
137	
138	\paragraph{Raw drift.}
139	Table~\ref{tab:drift_summary} shows that diversity collapse occurs at \emph{all} contamination levels, not only under full synthetic replacement.
140	Distinct-1 declines by 13.8\% even at $\alpha{=}0.0$ (attributable to fine-tuning on repeated real-data subsets).
141	A single-seed observation at $\alpha{=}0.10$ reveals a steep diversity cliff: distinct-1 drops by 39.6\%, nearly matching the 3-seed mean at $\alpha{=}0.25$ ($-40.3{\pm}0.3\%$); distinct-2 shows a comparable jump ($-56.4\%$ vs.\ $-56.4{\pm}0.7\%$ at $\alpha{=}0.25$).
142	Token entropy at $\alpha{=}0.10$, however, differs from the null by less than 1 percentage point ($-5.3\%$ vs.\ $-4.6{\pm}0.4\%$), constituting a canary blind spot in which diversity has already collapsed but no canary metric responds.
143	At higher contamination, distinct-1 decline continues: $-37.1{\pm}0.4\%$ ($\alpha{=}0.50$), $-32.3{\pm}0.5\%$ ($\alpha{=}0.75$), and $-27.8{\pm}1.6\%$ ($\alpha{=}1.0$).
144	The non-monotonic pattern (diversity declining \emph{more} at moderate~$\alpha$ than at extreme~$\alpha$) is confirmed by 3-seed replication at $\alpha{=}0.25$ (std${=}0.3\%$), indicating that this relationship between contamination level and collapse severity is robust rather than a seed-specific artifact.
145	
146	\begin{figure}[t]
147	\centering
148	\includegraphics[width=\linewidth]{figures/fig_dose_response.pdf}
149	\caption{Dose-response profile of permutation Granger forward detection rate (Pythia-410M, fp32, 12 contamination levels, direction-checked).
150	Four regimes emerge: blind ($\alpha{\leq}0.45$, 0/8), onset ($\alpha{=}0.50$, 75\%), synchronous dip ($\alpha{=}0.60$, 37.5\%; orange diamond), and detection ($\alpha{\geq}0.75$, 62.5--75\%).
151	The $\alpha{=}0.60$ dip is dual-seed confirmed (s42: 3/8, s43: 0/8).
152	Per-method comparison is in Figure~\ref{fig:consensus_heatmap}.}
153	\label{fig:regime_map}
154	\end{figure}
155	
156	\paragraph{Granger-precedence detectability.}
157	Despite ubiquitous drift, causal detectability is sharply regime-dependent (Figure~\ref{fig:regime_map}).
158	Permutation Granger tests (first-differenced, BH-corrected) find 0/8 pairs FDR-significant from $\alpha{=}0.00$ through $\alpha{=}0.45$ (including $\alpha{=}0.25$ where a faint single-pair signal appears at FDR $p{=}0.053$ but aggregate detection remains null, and $\alpha{=}0.35$/$0.40$/$0.45$ which confirm PermG fwd${=}$0/8), \textbf{6/8} at $\alpha{=}0.50$ (2~fp32 seeds, consistent), \textbf{3/8} and \textbf{0/8} at $\alpha{=}0.60$ (s42 and s43 respectively; dual-seed confirmed non-monotonic dip), and \textbf{6/8} at $\alpha{=}1.0$.
159	At $\alpha{=}0.75$ (3~seeds), permutation Granger finds 20/24 forward-direction pairs FDR-significant with 0/24 reverse, confirming directional asymmetry; however, method-level consensus varies by seed (Tier~3 pairs: 4, 3, and 1 across seeds), placing this regime in a transitional detection state.
160	Under Bonferroni correction, approximately 3/8 pairs per seed survive, consistent with the transitional nature of the $\alpha{=}0.75$ boundary where marginal signals are sensitive to correction stringency.
161	Within-$\alpha$ multi-seed analysis at $\alpha{=}1.0$ yields \textbf{24/24} canary$\to$diversity pairs FDR-significant across all four seeds, with 0/24 in the reverse direction, confirming temporal asymmetry.
162	Permutation Granger forward significance is the primary detection indicator (Figure~\ref{fig:regime_map}): it reaches 6/8 at $\alpha{=}0.50$, dips to 3/8 at $\alpha{=}0.60$ (synchronous collapse zone; see below), and recovers to 5--6/8 at $\alpha{\geq}0.75$.
163	The onset boundary lies at $\alpha{\approx}0.45$--$0.50$: finer-grained probing at $\alpha{=}0.35$, $0.40$, and $0.45$ yields PermG fwd${=}$0/8 at all three levels, extending the blind spot through $\alpha{=}0.45$.
164	A faint signal first appears at $\alpha{=}0.25$ (best-pair FDR $p{=}0.053$) but does not translate to aggregate detection; reliable detection begins at $\alpha{=}0.50$ (6/8, 2~seeds).
165	This near-discontinuous onset is consistent with theoretical expectations about signal-to-noise limits in short time series~\cite{boettiger2012limits}.
166	Sensitivity analysis confirms that treatment/null separation is robust to FDR threshold choice ($q{=}0.01$: 0/24 null, 0/24 treatment at $\alpha{=}0.75$; $q{=}0.10$: 0/24 null, 24/24 treatment; Appendix~\ref{app:robustness}).
167	Cross-architecture validation on GPT-2-medium confirms this boundary: at $\alpha{=}0.25$, at most 1/8 pairs reach $K{\geq}3$ ($3\sigma$), consistent with the null regime, despite substantially stronger canary drift (entropy $-32.8\%$ vs.\ Pythia $-4.7{\pm}0.5\%$), while at $\alpha{=}1.0$ all 6 canary$\to$diversity pairs reach significance (\S\ref{sec:discussion}).
168	Table~\ref{tab:cross_arch_regime} summarizes the regime map across both architectures.
169	At $\alpha{=}0.25$, GPT-2-medium yields 1/8 pairs at Tier~3 ($K{\geq}4/5$) and 7/8 at Tier~2 ($K{\geq}3/5$), consistent with Pythia's 0/8 Tier~3, 0/8 Tier~2 result at the same contamination level, placing both architectures in the null/low-detectability regime.
170	
171	\begin{table}[t]
172	\centering
173	\small
174	\caption{Cross-architecture regime map: lead-lag consensus tier and metric drift at $\alpha{=}0.25$ and $\alpha{=}1.0$. Tier~3: $K{\geq}4/5$ methods (or $K{\geq}3$ of 4 effective methods; \S\ref{sec:threshold_limitation}); Tier~2: $K{\geq}3/5$. Drift is generation~0$\to$10. GPT-2-medium $\alpha{=}0.25$: single seed (seed=42); Pythia $\alpha{=}0.25$: 3-seed mean${\pm}$std. The onset boundary ($\alpha{\approx}0.45$--$0.50$) is consistent across two transformer decoder-only model families of similar scale.}
175	\label{tab:cross_arch_regime}
176	\begin{tabular}{llcccccc}
177	\toprule
178	$\alpha$ & Model & Entropy & ECE & Distinct-1 & Distinct-2 & Perm.\ Granger & Tier~3 \\
179	\midrule
180	0.25 & Pythia-410M  & $-4.7{\pm}0.5$ & $+81.8{\pm}15.9$ & $-40.3{\pm}0.3$ & $-56.4{\pm}0.7$ & 0/8 & 0/8 \\
181	0.25 & GPT-2-medium & $-32.8$ & $+422$ & $-23.5$ & $-31.6$ & 0/8 & 1/8 \\
182	\midrule
183	1.00 & Pythia-410M  & $-60.8{\pm}1.2$ & $+3780{\pm}30$ & $-27.8{\pm}1.6$ & $-34.0{\pm}3.3$ & 6/8 & 6/8 \\
184	1.00 & GPT-2-medium & \multicolumn{6}{c}{(reported in \S\ref{sec:discussion}; 6/8 canary$\to$downstream pairs at Tier~3)} \\
185	\bottomrule
186	\end{tabular}
187	\end{table}
188	
189	\paragraph{Detectability at $\alpha{=}0.50$ and the transition zone.}
190	Under fp32 precision, $\alpha{=}0.50$ is reliably detected: permutation Granger finds 6/8 pairs FDR-significant across both seeds (Table~\ref{tab:method_comparison}).
191	The transition from undetectable to reliably detectable occurs between $\alpha{=}0.45$ and $\alpha{=}0.50$: finer-grained probing confirms PermG fwd${=}$0/8 at $\alpha{=}0.35$, $0.40$, and $0.45$, while $\alpha{=}0.50$ achieves 6/8 (2~seeds).
192	A faint single-pair signal first appears at $\alpha{=}0.25$ (entropy$\to$distinct-1: raw $p{=}0.007$, FDR-corrected $p{=}0.053$), but all aggregate indicators remain null through $\alpha{=}0.45$, placing the onset boundary at $\alpha{\approx}0.45$--$0.50$.
193	At $\alpha{=}0.50$, canary sensitivity remains metric-dependent: ECE achieves significance in both fp32 seeds, while token entropy remains below the FDR threshold ($p_{\text{fdr}}{\geq}0.086$), identifying ECE as the more sensitive canary near the onset boundary.
194	Figure~\ref{fig:consensus_heatmap} visualizes the method$\times\alpha$ interaction, revealing a block structure that separates correlation-based methods from causal methods as a function of regime.
195	
196	\paragraph{Quantifying the onset boundary.}
197	Sigmoid regression across the 12-point $\alpha$ grid quantifies the sharp onset observed above.
198	Fitting $P(\alpha) = 1/(1 + \exp(-k(\alpha - \alpha_c)))$ to the PermG forward detection rate yields a critical threshold $\alpha_c = 0.476$ with steepness $k \geq 200$ and transition width $\Delta\alpha \approx 0.02$ (Figure~\ref{fig:phase_transition}).
199	The sigmoid model explains 96.9\% of variance ($R^2 = 0.969$), substantially outperforming a power-law alternative ($R^2 = 0.808$; $\Delta\text{AIC} = 18.2$), confirming that the onset is near-discontinuous rather than gradual.
200	This transition is striking because effective contamination barely changes across the boundary: after 10 generations of iterative training, both $\alpha{=}0.45$ and $\alpha{=}0.50$ drive the cumulative synthetic fraction above 99\% ($C = 1{-}(1{-}\alpha)^{10}$: $99.75\%$ vs.\ $99.90\%$)---a difference of 0.15 percentage points---yet causal detectability jumps from 0/8 to 6/8.
201	We term this a \emph{detection phase transition}: causal coupling emerges abruptly at a critical contamination threshold ($\alpha_c{=}0.476$, $\Delta\alpha{\approx}0.02$) rather than scaling smoothly with contamination dose.
202	Within the $S \times R$ framework (\S\ref{sec:theory}), $\alpha_c{=}0.476$ localizes the point at which signal strength $S(\alpha)$ first crosses the detection floor, while the high steepness ($k \geq 200$) indicates that temporal resolution $R(\alpha)$ remains large at onset---the entropy--diversity lag has not yet begun to compress.
203	Cross-architecture comparison reveals no monotonic relationship between model scale and onset sensitivity (Qwen-0.8B $\approx$ Pythia-6.9B $>$ Pythia-410M $>$ Pythia-1.4B $>$ SmolLM3-3B), suggesting that architecture and pre-training data exert stronger influence than parameter count on detection onset.
204	
205	\begin{figure}[t]
206	\centering
207	% TODO: transfer fig_phase_transition.pdf from westd-17855
208	%\includegraphics[width=\linewidth]{figures/fig_phase_transition.pdf}
209	\caption{Sigmoid fit to the PermG forward detection rate across 12 contamination levels.
210	The fitted critical threshold $\alpha_c = 0.476$ with steepness $k \geq 200$ indicates a near-discontinuous onset of causal detectability.
211	Sigmoid $R^2 = 0.969$ vs.\ power-law $R^2 = 0.808$ ($\Delta\text{AIC} = 18.2$).}
212	\label{fig:phase_transition}
213	\end{figure}
214	
215	\paragraph{Non-monotonic dose-response: the synchronous collapse zone.}
216	Dual-seed replication at $\alpha{=}0.60$ reveals a non-monotonic dose-response in Granger detectability: PermG fwd drops to 3/8 (s42) and 0/8 (s43), below both $\alpha{=}0.50$ (6/8, 2~seeds) and $\alpha{=}0.75$ (5--6/8 per seed, 3~seeds).
217	This creates a four-regime structure in the dose-response profile: \emph{blind} ($\alpha{\leq}0.45$, 0/8), \emph{onset} ($\alpha{\approx}0.50$, 6/8), \emph{synchronous dip} ($\alpha{\approx}0.60$, 0--3/8), and \emph{detection} ($\alpha{\geq}0.75$, 5--6/8 per seed; 6/8 at $\alpha{=}1.0$).
218	The dip confirms the non-monotonic prediction of the $S \times R$ framework (\S\ref{sec:theory}): at $\alpha{=}0.60$, signal strength $S$ continues rising but temporal resolution $R$ drops sharply due to relaxation time matching, producing a local minimum in detectability.
219	The synchronous zone is mechanistically distinct from the blind spot: in the blind spot, canary drift is indistinguishable from the null; in the synchronous zone, both canary and downstream metrics drift substantially but without temporal offset.
220	Toda--Yamamoto achieves moderate detection across this range (3--4/8 at $\alpha{\geq}0.50$; \S\ref{sec:ty_limitation}), with its detection at $\alpha{=}0.60$ suggesting partial inter-method complementarity in the synchronous collapse zone where PermG drops to 0--3/8.
221	This non-monotonicity also implies that simple threshold-based triggers (such as the 15\% entropy criterion in \S\ref{sec:intervention}) may outperform formal Granger tests at intermediate contamination levels.
222	
223	\paragraph{Predictions for longer generation chains.}
224	The $S \times R$ framework (\S\ref{sec:theory}) generates testable predictions for longer observation windows ($T{=}20$).
225	Increased $T$ improves temporal resolution without changing signal strength, effectively increasing $R(\alpha)$ by providing more observation points for Granger tests to detect sub-generation lags.
226	We predict: (i)~at $\alpha{=}0.50$, PermG detection should increase from 6/8 to ${\geq}7/8$ as additional generations provide more statistical power for an already-present lead;
227	(ii)~at $\alpha{=}0.60$, the synchronous dip should attenuate or disappear, because finer temporal sampling allows Granger tests to resolve lags that are invisible at $T{=}11$;
228	(iii)~at $\alpha{=}1.0$, detection should remain at 6--8/8, as the strong signal is already saturated.
229	These predictions are submitted for future empirical verification with extended generation protocols.
230	
231	
232	\subsection{Case Study: Canary Prediction of Diversity Collapse}
233	\label{sec:case_study}
234	
235	Having established method sensitivity (Claim~3) and regime dependence (Claim~2), we present the conditions under which canary prediction succeeds (Claim~1).
236	We scope this claim precisely: canary metrics predict \emph{diversity collapse} (declining distinct-$n$), not model collapse broadly.
237	
238	\paragraph{Full synthetic replacement ($\alpha{=}1.0$, 4 seeds).}
239	Token entropy exhibits robust Granger-precedence over diversity collapse metrics, confirmed by 4 independent statistical methods (permutation Granger power${=}1.0$), 4 seeds, and cross-architecture replication on GPT-2-medium (Tier~3 consensus; \S\ref{sec:discussion}).
240	Cross-correlation peaks at lag$={+}1$ with $|r|{>}0.99$ (cross-seed standard deviation: 0.0), establishing a consistent one-generation lead.
241	Figure~\ref{fig:metric_trajectory} illustrates the one-generation offset between token entropy decline and distinct-1 decline, visible across all four seeds.
242	Permutation Granger tests (first-differenced) confirm all canary$\to$diversity pairs as FDR-significant across all four seeds, including distinct-3 (Appendix~\ref{app:distinct3}).
243	Reverse-direction tests (downstream$\to$canary) on WikiText-103 find \textbf{0/24} FDR-significant (all $p{>}0.49$), establishing directional asymmetry in this domain.\footnote{C4 exhibits domain-dependent directionality: at $\alpha{=}0.50$ (s42 fp32), PermG reverse reaches 7/8, indicating near-symmetric bidirectional coupling (\S\ref{sec:discussion}).}
244	
245	\begin{figure}[t]
246	\centering
247	\includegraphics[width=\linewidth]{figures/metric_trajectory.pdf}
248	\caption{Metric trajectories across 10 generations at $\alpha{=}1.0$ (Pythia-410M, 4~seeds shown as individual traces). Token entropy (top, blue) drops sharply at generation~1, while distinct-1 (bottom, red) begins declining at generations~2--3, establishing a visible one-generation canary lead. The consistent lag across all four seeds confirms that the temporal offset is robust rather than seed-specific. Shaded bands show the inter-seed range. This visual pattern corresponds to the statistical finding of 24/24 forward-direction and 0/24 reverse-direction FDR-significant pairs.}
249	\label{fig:metric_trajectory}
250	\end{figure}
251	
252	\paragraph{High contamination ($\alpha{=}0.75$, 3 seeds).}
253	Directional asymmetry is robustly confirmed across three independent seeds (permutation Granger: 20/24 forward pairs FDR-significant, 0/24 reverse).
254	However, method-level consensus varies by seed (Tier~3 pairs: 4, 3, and 1 across seeds 42, 43, 44), placing $\alpha{=}0.75$ squarely in the transitional detection regime.
255	Differenced cross-correlation finds 8/8 pairs significant in \emph{both} forward and reverse directions at each seed, confirming that this method alone cannot distinguish genuine directional precedence from shared dynamics, a seed-level demonstration of Pitfall~1 (\S\ref{sec:pitfalls}).
256	
257	\paragraph{ECE as a conditional secondary canary.}
258	ECE's forward consensus matches token entropy (both achieve PermG\_fwd 6/8 across all conditions), but the reverse profile diverges sharply.
259	Across 7 validated conditions at $\alpha{=}1.0$ (3 architectures $\times$ 2 scales $\times$ 2 domains), token entropy reverse direction yields \textbf{0/28} FDR-significant pairs (consistent with unidirectional forward causation at full synthetic replacement; domain-dependent bidirectionality emerges at lower $\alpha$, \S\ref{sec:discussion}), while ECE reverse direction yields \textbf{13/28} significant pairs, with 5/7 conditions containing at least one reverse-significant pair, all in the distinct$\to$ECE direction.
260	This bidirectional coupling is the core reason ECE is classified as a secondary canary: ECE and diversity exhibit mutual feedback, and the interpretability of ECE's causal direction is correspondingly limited.
261	This result also instantiates Claim~3 (method sensitivity): when only forward significance is considered, the two canary types appear equivalent; incorporating reverse-direction tests separates them. The choice of analysis dimension alters the canary classification itself.
262	
263	\paragraph{Failed canary candidates.}
264	Not all metrics serve as canaries.
265	Effective rank and Self-BLEU show no detectable lead-lag relationship with any downstream metric under any method or contamination level, and are excluded from the consensus framework.
266	Effective rank behavior is model-dependent in an unexpected way: in Pythia-410M, effective rank decreases during collapse (representational contraction), whereas in GPT-2-medium at $\alpha{=}0.25$ it \emph{increases} from 2.37 to 8.48 (+258\%).
267	The GPT-2-medium starting effective rank is near rank-2, suggesting the model's initial representation is already highly concentrated; iterative training disperses it rather than concentrating it further.
268	This opposite directionality across architectures precludes effective rank as a universal canary and motivates architecture-specific analysis (\S\ref{sec:discussion}).
269	
270	\paragraph{Consensus filtering.}
271	Of 16 canary$\to$downstream pairs tested at $\alpha{=}1.0$ (4 candidate canaries $\times$ 4 downstream metrics), \textbf{6 survive} the full consensus pipeline (PermG fwd ${\geq}6/8$, $S{\geq}3/4$ seeds): token entropy and ECE each predicting distinct-1 and distinct-2 (4 pairs; distinct-3 results in Appendix~\ref{app:distinct3} bring the total to~6).
272	The 10 eliminated pairs comprise all canary$\to$perplexity relationships (identified as spurious by the first-differencing diagnostic) and all effective-rank and Self-BLEU pairs (failed canaries).
273	The consensus framework reduces the naive 75\% forward-direction FPR to 0\%, matching the most conservative individual methods (Figure~\ref{fig:consensus_workflow}).
274	
275	
276	\subsection{Consensus Framework Validation}
277	\label{sec:consensus_validation}
278	
279	We validate the consensus framework's calibration using built-in experimental controls.
280	
281	\paragraph{False positive rate.}
282	At $\alpha{=}0.0$ (three seeds, 24 total pairs), no synthetic data is injected; any detected lead-lag association is a false positive.
283	Individual-method forward-direction FPR ranges from \textbf{75\%} (naive cross-correlation: 6/8) through 37.5\% (threshold) down to \textbf{0\%} (permutation Granger and differenced cross-correlation); Toda--Yamamoto's null-control FPR has not yet been evaluated through the corrected pipeline (\S\ref{sec:ty_limitation}).
284	The multi-method consensus at $K{\geq}3$ ($3\sigma$) achieves \textbf{FPR${=}$0\%} (0/24 pairs, three independent seeds), matching the best individual method (permutation Granger) while providing a formal benchmark for method reliability (Table~\ref{tab:fpr_fnr}).
285	
286	\paragraph{False negative rate.}
287	At $\alpha{=}1.0$, we define 6 effect-size reference pairs (token entropy and ECE $\to$ distinct-1/2/3) using criteria independent of the consensus methods: drift ratio ${\geq}3\times$ the $\alpha{=}0.0$ baseline (entropy $11.93\times$, ECE $73.12\times$) and canary onset strictly preceding downstream onset by ${\geq}1$ generation (\S\ref{sec:calibration}).
288	FNR is calibrated on a 4-method panel (excluding differenced cross-correlation to avoid circularity): at $K{\geq}3/4$, $S{\geq}3/4$, all~6 are recovered (\textbf{FNR${=}$0\%}).
289	Toda--Yamamoto's individual FNR is 50\% (4/8 detected at $\alpha{=}1.0$, seed~42), consistent with its moderate supplementary classification (\S\ref{sec:ty_limitation}).
290	Both FPR and FNR are validated on the joint method${\times}$seed dimension (FPR: 3~seeds at $\alpha{=}0.0$; FNR: 4~seeds at $\alpha{=}1.0$), with cross-seed FPR variance negligible (all three seeds yield 0/8 robust pairs at $K{\geq}3$).
291	Table~\ref{tab:fpr_fnr} reports the calibration results.
292	Table~\ref{tab:single-method-errors} complements this analysis by showing the practical consequences of relying on any single method: naive cross-correlation produces false positives at every $\alpha$ including the null control, while permutation Granger achieves correct verdicts at all levels with zero FPR.
293	
294	\begin{table}[t]
295	\centering
296	\caption{Single-method inference errors across contamination levels.
297	Each cell shows the verdict (significant or not) based on multi-seed majority ($\geq$2/3 seeds with $\geq$4/8 pairs significant).
298	\checkmark\ = correct, \textcolor{red}{FP} = false positive, \textcolor{blue}{FN} = false negative, $\circ$ = ambiguous ground truth (either verdict plausible).
299	Naive XCorr produces false positives at \emph{every} $\alpha$ including the null control. Permutation Granger achieves correct verdicts at all levels with zero FPR. $^\dagger$Rows marked pending have cross-script inconsistencies under audit.}
300	\label{tab:single-method-errors}
301	\resizebox{\columnwidth}{!}{%
302	\begin{tabular}{lccccc}
303	\toprule
304	 & \multicolumn{2}{c}{\textit{No signal}} & \textit{Ambiguous} & \multicolumn{2}{c}{\textit{Causal signal}} \\
305	\cmidrule(lr){2-3} \cmidrule(lr){4-4} \cmidrule(lr){5-6}
306	Method & $\alpha{=}0.00$ & $\alpha{=}0.25$ & $\alpha{=}0.50$ & $\alpha{=}0.75$ & $\alpha{=}1.00$ \\
307	\midrule
308	Naive XCorr
309	  & \textcolor{red}{FP}{\scriptsize\ 8,7,8}
310	  & \textcolor{red}{FP}{\scriptsize\ 8,8}
311	  & $\circ${\scriptsize\ 8,8,8}
312	  & \checkmark{\scriptsize\ 8,8,8}
313	  & \checkmark{\scriptsize\ 8,8,8} \\
314	Diff XCorr (FDR)$^\dagger$
315	  & --- & --- & --- & --- & --- \\
316	Threshold Onset$^\dagger$
317	  & --- & --- & --- & --- & --- \\
318	Perm Granger (FDR)
319	  & \checkmark{\scriptsize\ 0,0,0}
320	  & \checkmark{\scriptsize\ 0,0}
321	  & $\circ${\scriptsize\ 0,6,3}
322	  & \checkmark{\scriptsize\ 8,5,6}
323	  & \checkmark{\scriptsize\ 6,6,6} \\
324	TY Granger$^\dagger$
325	  & --- & --- & --- & --- & --- \\
326	\midrule
327	\textbf{Consensus ($K{\geq}3$)}$^\dagger$
328	  & --- & --- & --- & --- & --- \\
329	\bottomrule
330	\multicolumn{6}{l}{\footnotesize Subscript numbers: per-seed significant pair counts out of 8.} \\
331	\multicolumn{6}{l}{\footnotesize Seeds: $\alpha{=}0.00/0.50/0.75$: 42, 43, 44; $\alpha{=}0.25$: 43, 44; $\alpha{=}1.00$: 42, 43, 45.} \\
332	\end{tabular}%
333	}
334	\end{table}
335	
336	\paragraph{Bootstrap power analysis.}
337	To quantify detection power beyond binary FNR, we perform bootstrap power analysis ($B{=}1{,}000$ resamples from 4-seed data at $\alpha{=}1.0$).
338	Permutation Granger achieves power${=}1.0$ on genuine pairs (canary$\to$diversity) and power${=}0.0$ on spurious pairs (canary$\to$perplexity), providing clean separation.
339	Toda--Yamamoto achieves power${=}0.50$ on genuine pairs (4/8 detected at $\alpha{=}1.0$), consistent with its moderate supplementary classification (\S\ref{sec:ty_limitation}).
340	We note that bootstrap power${=}1.0$ reflects the effect size in our 4-seed data and should not be interpreted as a universal power guarantee; furthermore, the two methods use different data-generating processes for calibration (permutation Granger resamples observed $\alpha{=}1.0$ trajectories, while Toda--Yamamoto power was estimated under a generic VAR(2) simulation with $\beta{=}0.3$).
341	
342	\begin{table}[t]
343	\centering
344	\small
345	\caption{False positive and false negative rates for individual methods and the consensus framework (Pythia-410M). The consensus threshold $K{\geq}3$ ($3\sigma$, excluding threshold onset; \S\ref{sec:threshold_limitation}) achieves FPR${=}$0\% and FNR${=}$0\%, matching the best individual method (permutation Granger) while providing robustness against miscalibration of any single method. FPR: $\alpha{=}0.0$ null control (three seeds, $M{=}5$ methods); values are 3-seed means with ranges in parentheses where cross-seed variance is non-negligible. FNR: $\alpha{=}1.0$ against 6 effect-size reference pairs (4-method panel excluding differenced cross-correlation, 4~seeds). $^\dagger$Moderate supplementary method (\S\ref{sec:ty_limitation}); FPR pending (null condition not yet run through corrected pipeline); FNR from single-seed $\alpha{=}1.0$ (4/8 detected).}
346	\label{tab:fpr_fnr}
347	\begin{tabular}{lcc}
348	\toprule
349	Criterion & FPR ($\alpha{=}0.0$) & FNR ($\alpha{=}1.0$) \\
350	\midrule
351	Naive XCorr              & 100\%              & 0\%  \\
352	Differenced XCorr        & 37.5\%             & 0\%  \\
353	Threshold Onset          & 20.8\% (12.5--37.5) & 0\%  \\
354	Permutation Granger      & 0\%                & 0\%  \\
355	Toda--Yamamoto$^\dagger$  & ---                & 50\%   \\
356	\midrule
357	Consensus ($K{\geq}3$, $3\sigma$)      & 0\%    & 0\%  \\
358	Consensus ($K{\geq}3$, $S{\geq}3/4$)   & 0\%    & 0\%  \\
359	\bottomrule
360	\end{tabular}
361	\end{table}
362	
363	
364	\subsection{Cross-Architecture, Cross-Scale, and Cross-Domain Generalization}
365	\label{sec:generalization}
366	
367	The methodological pitfalls and consensus framework developed above are calibrated on a single model family (Pythia-410M, WikiText-103).
368	To test whether these findings transfer, we evaluate the lead-lag pattern along three generalization axes: architecture family (GPT-2-medium 345M, OPT-1.3B), model scale (Pythia-1.4B, $3.4\times$ parameters within the same family), and training domain (Pythia-1B trained on C4 rather than WikiText-103).
369	All conditions use $\alpha{=}1.0$; architecture conditions use a single seed, while scale and domain conditions use two seeds (s42, s43) to assess replicability.
370	
371	\begin{table}[t]
372	\centering
373	\small
374	\caption{Cross-architecture lead-lag detectability ($\alpha{=}1.0$, D105 unified pipeline, $3\sigma$ calibration, M035 direction-corrected).
375	PermG~fwd: permutation Granger forward-direction FDR-significant pairs (out of 8).
376	$K{\geq}3$: pairs where ${\geq}3$ of 5 methods reach FDR significance (direction-checked, $3\sigma$).
377	PermG~fwd ${\geq}6/8$ in 12/14 confirmed conditions; $K{\geq}3$ ${\geq}6/8$ in 10/14 (11/14 pending Padding-410M audit).
378	Exceptions: Pythia-1.4B (s42: 1/8$^\dagger$, s43: 3/8) and SmolLM3-3B (3/8$^\ddagger$).
379	Rows marked ``---'' are running experiments; final values will be filled without format changes.}
380	\label{tab:generalization}
381	\begin{tabular}{lrclcc}
382	\toprule
383	Model & Params & Seed & Domain & PermG (fwd) & $K{\geq}3$ \\
384	\midrule
385	\multicolumn{6}{l}{\emph{Baseline}} \\
386	Pythia-410M       & 410M & s42 & Wiki & 6/8            & 6/8            \\
387	Pythia-410M       & 410M & s43 & Wiki & 6/8            & 6/8            \\
388	\addlinespace
389	\multicolumn{6}{l}{\emph{Scale}} \\
390	Pythia-1.4B       & 1.4B & s42 & Wiki & \textbf{2/8}$^\dagger$ & \textbf{1/8}$^\dagger$  \\
391	Pythia-1.4B       & 1.4B & s43 & Wiki & 6/8            & 3/8     \\
392	Pythia-6.9B       & 6.9B & s42 & Wiki & 7/8$^*$        & 6/8            \\
393	Pythia-6.9B       & 6.9B & s43 & Wiki & ---            & ---            \\
394	\addlinespace
395	\multicolumn{6}{l}{\emph{Architecture}} \\
396	GPT-2-medium      & 345M & s42 & Wiki & 6/8            & 6/8            \\
397	GPT-2-medium      & 345M & s43 & Wiki & 6/8            & 6/8            \\
398	OPT-1.3B          & 1.3B & s42 & Wiki & 6/8            & 6/8            \\
399	OPT-1.3B          & 1.3B & s43 & Wiki & 6/8            & 6/8            \\
400	Qwen3.5-0.8B      & 0.8B & s42 & Wiki & 8/8            & 6/8            \\
401	Qwen3.5-0.8B      & 0.8B & s43 & Wiki & ---            & ---            \\
402	SmolLM3-3B        & 3.0B & s42 & Wiki & \textbf{3/8}$^\ddagger$ & \textbf{3/8}$^\ddagger$ \\
403	SmolLM3-3B        & 3.0B & s43 & Wiki & ---            & ---            \\
404	\addlinespace
405	\multicolumn{6}{l}{\emph{Tokenization}} \\
406	Padding-410M      & 410M & s42 & Wiki & 6/8            & 6/8$^{\S}$     \\
407	\addlinespace
408	\multicolumn{6}{l}{\emph{Domain}} \\
409	Pythia-1B         & 1.0B & s42 & C4   & 8/8            & 7/8            \\
410	Pythia-1B         & 1.0B & s43 & C4   & 7/8            & 6/8            \\
411	\bottomrule
412	\multicolumn{6}{l}{\footnotesize $^\dagger$Seed-sensitive: PermG s42 2/8, s43 6/8; $K{\geq}3$ s42 1/8, s43 3/8. Likely stochastic instability at this scale (\S\ref{sec:discussion}).} \\
413	\multicolumn{6}{l}{\footnotesize $^\ddagger$Canary metric splitting: only ECE$\to$downstream pairs detected (3/4); entropy$\to$downstream 0/4 (\S\ref{sec:smollm3}).} \\
414	\multicolumn{6}{l}{\footnotesize $^*$bf16 precision (model exceeds single-GPU fp32 capacity).} \\
415	\multicolumn{6}{l}{\footnotesize $^{\S}$Padding-410M $K{\geq}3$ pending supplementary audit (expected stable at 6/8).} \\
416	\multicolumn{6}{l}{\footnotesize Full method-level breakdown ($K{\geq}4$) in Appendix~\ref{app:cross_arch}.} \\
417	\end{tabular}
418	\end{table}
419	
420	\paragraph{Cross-condition robustness.}
421	Table~\ref{tab:generalization} confirms that the entropy-leads-diversity pattern is robust across 14 confirmed conditions (3 pending) spanning six model families (Pythia, GPT-2, OPT, Qwen, SmolLM3, Padding-variant), scales from 345M to 6.9B, and two training domains (WikiText-103, C4).
422	Permutation Granger forward significance reaches ${\geq}6/8$ in 12 of 14 conditions (85.7\%), with two exceptions: Pythia-1.4B seed~42 (2/8), a seed-dependent outlier that recovers to 6/8 in seed~43, and SmolLM3-3B (3/8), where only ECE$\to$downstream pairs are detected (see below).
423	$K{\geq}3$ multi-method consensus reaches ${\geq}6/8$ in 10 of 14 conditions (11/14 pending Padding-410M audit), with exceptions Pythia-1.4B (s42: 1/8, s43: 3/8) and SmolLM3-3B (3/8).
424	The concordance between PermG and $K{\geq}3$ confirms that multi-method consensus is robust across architectures.
425	The onset threshold $\alpha_c{\approx}0.50$ is robust across all six families: every architecture that achieves detection does so at or above $\alpha{=}0.50$, while none achieves reliable detection below this threshold, suggesting that the detection phase transition boundary is architecture-independent even though detection power above onset varies with model family.
426	With threshold onset power-limited and Toda--Yamamoto providing moderate supplementary signal (3--4/8 at $\alpha{\geq}0.50$; \S\ref{sec:ty_limitation}), $K{\geq}3$ draws on four contributing methods---a stronger standard than simple majority (\S\ref{sec:consensus}).
427	
428	\paragraph{Scale generalization.}
429	Scaling from 410M to 6.9B parameters confirms that the lead-lag pattern persists across a $17\times$ parameter range.
430	Pythia-6.9B achieves PermG fwd~7/8 (bf16), the strongest single-seed detection.
431	Within the Pythia family, 1.4B shows seed dependence: s42 yields only 2/8 (the sole outlier across all conditions), while s43 recovers to 6/8.
432	Qwen3.5-0.8B (PermG~fwd~8/8) extends the finding beyond the Pythia/GPT-2/OPT decoder-only family to an independently trained architecture with a different tokenizer.
433	
434	\paragraph{Domain generalization.}
435	Replacing WikiText-103 with C4 yields the strongest forward detection: Pythia-1B achieves PermG~fwd~8/8 in both seeds at $\alpha{=}1.0$, confirming that the lead-lag pattern is not an artifact of narrow topical distribution.
436	However, directional asymmetry does not transfer fully across domains.
437	At $\alpha{=}0.50$ (Pythia-410M, C4, s42 fp32), PermG reverse reaches 7/8 (compared to 0/8 in all WikiText conditions), indicating near-symmetric bidirectional coupling between canary and downstream metrics.
438	This domain-dependent directionality suggests that the unidirectional forward causation observed in WikiText may partly reflect domain-specific dynamics rather than a universal property of collapse; implications are discussed in \S\ref{sec:discussion}.
439	
440	\paragraph{Canary metric sensitivity: the SmolLM3-3B case.}
441	\label{sec:smollm3}
442	SmolLM3-3B (PermG fwd 3/8) reveals that canary metric choice is itself a dimension of method sensitivity.
443	Decomposing by canary type: ECE$\to$downstream achieves 3/4 significant pairs, while token entropy$\to$downstream achieves 0/4.
444	The root cause is that SmolLM3's token entropy exhibits non-monotonic oscillations across generations, violating the monotonic decline pattern that Granger tests exploit; ECE, by contrast, maintains its monotonic upward trajectory.
445	Multi-method consensus confirms the severity: entropy pairs activate only via naive and differenced cross-correlation (per-pair $K{=}2$), ECE pairs activate only via differenced cross-correlation and permutation Granger (per-pair $K{=}2$), and no pair exceeds two-method agreement---illustrating that even within a single architecture, the method panel fragments along canary metric boundaries.
446	This architecture-dependent canary sensitivity complements the finding that effective rank direction is model-dependent (\S\ref{sec:case_study}): no single canary metric is universally optimal across all architectures, enriching Claim~3 by adding canary metric selection as a further source of analytic variability.
447	
448	\subsection{Canary-Based Early Intervention}
449	\label{sec:intervention}
450	
451	To test whether the lead-lag relationship translates into practical utility, we implement a predictive cessation protocol: training with synthetic data ($\alpha{=}1.0$) continues until token entropy drops ${>}15\%$ relative to generation~0, at which point $\alpha$ is switched to $0.0$ (pure real data).
452	We compare against a reactive baseline that triggers only when distinct-1 drops ${>}10\%$---a downstream metric that, by the lead-lag hypothesis, should respond later.
453	
454	\paragraph{Pythia-410M.}
455	The predictive trigger fires at generation~1 in both seed-precision pairs tested (s42 fp32: entropy $3.234{\to}1.918$, ${\downarrow}40.7\%$; s43 bf16: $3.257{\to}2.523$, ${\downarrow}22.5\%$).
456	The reactive baseline triggers one generation later (generation~2, distinct-1 ${\downarrow}15.6\%$).
457	Predictive intervention reduces peak perplexity by 63\% relative to reactive ($56.99$ vs.\ $157.09$, s42 fp32) and achieves full recovery by generation~2 versus generation~4 for reactive.
458	The bf16 pair shows a milder perturbation (peak perplexity $24.65$ vs.\ $56.99$) consistent with stochastic rounding regularization, but the structural pattern---generation~1 trigger, generation~2 recovery---is identical.
459	Both conditions converge to the $\alpha{=}0.0$ baseline by generation~10.
460	
461	\paragraph{Cross-scale validation: Pythia-1.4B.}
462	Pythia-1.4B (s42 fp32) replicates the 410M pattern: token entropy drops $51.9\%$ at generation~1 ($2.946{\to}1.418$), exceeding the 15\% threshold, and recovers to $2.892$ by generation~2 ($98.2\%$ of baseline).
463	Perplexity spikes from $19.68$ to $65.37$ at the trigger generation and recovers to $17.44$ by generation~2 (stable at $17.60$ through generation~10).
464	The trigger generation, recovery timeline, and convergence behavior are identical across the $3.4\times$ scale gap (410M to 1.4B), confirming that the canary-based intervention mechanism is scale-independent: the 15\% entropy threshold generalizes without recalibration across model sizes.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "bd354e0c-092e-4fc6-bbba-fade3ad71384",
  "isSidechain": false,
  "promptId": "0bc1eef6-835a-4ee4-a8a1-06010792cb3b",
  "type": "user",
  "uuid": "49817fe8-f400-44c2-b28a-46569a4761d6",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/experiments.tex",
      "content": "\\section{Experiments}\n\\label{sec:experiments}\n\n\\subsection{Experimental Setup}\n\\label{sec:setup}\n\nWe study lead-lag analysis pitfalls in iterative training collapse using Pythia-410M \\cite{biderman2023pythia}, a 410M-parameter decoder-only language model.\nPythia provides a controlled setting: small enough for multi-seed experiments across six contamination levels, yet large enough to exhibit meaningful generation-over-generation degradation.\nCross-architecture validation uses GPT-2-medium (345M parameters, also decoder-only), a second transformer family of similar scale; results are reported in \\S\\ref{sec:method_sensitivity}, \\S\\ref{sec:regime}, and \\S\\ref{sec:discussion}.\nTraining data is drawn from WikiText-103 \\cite{merity2017pointer}, using 5{,}000-sample subsets per generation.\n\nOur protocol follows the replace paradigm of \\citet{shumailov2024curse}, adapted for mixed synthetic-real training at $\\alpha{<}1.0$.\nEach generation $t$ proceeds in three steps: (1)~fine-tune the generation-$(t{-}1)$ model for 5{,}000 steps on a mixture of $\\alpha$ fraction synthetic data and $(1{-}\\alpha)$ fraction real data (AdamW optimizer, learning rate $5 \\times 10^{-5}$, 500 warmup steps, weight decay $0.01$, batch size 4 for Pythia-410M, 32 for GPT-2-medium); (2)~generate 5{,}000 synthetic samples from the fine-tuned model (temperature $1.0$, top-$k{=}50$, max length 512 tokens); (3)~fully replace the synthetic pool.\nWe run $T{=}10$ generations (11 time points including the generation-0 baseline) across contamination levels $\\alpha \\in \\{0.00, 0.10, 0.25, 0.50, 0.75, 1.00\\}$.\nThe $\\alpha{=}1.0$ condition uses four random seeds $\\{42, 43, 44, 45\\}$; $\\alpha \\in \\{0.00, 0.25, 0.50, 0.75\\}$ each use three seeds $\\{42, 43, 44\\}$; $\\alpha{=}0.10$ uses a single seed (42, preliminary).\n\nWe track two \\emph{canary metrics} (cheap-to-compute statistics hypothesized to precede downstream degradation, inspired by early-warning signals in dynamical systems \\cite{scheffer2009early}) and three \\emph{downstream metrics}.\nCanary metrics are token entropy (next-token prediction entropy averaged over held-out samples) and expected calibration error (ECE).\nDownstream metrics are distinct-1 and distinct-2 ($n$-gram diversity \\cite{li2016diversity}, computed over all 5{,}000 generated samples per generation) and perplexity (evaluated on held-out real data).\nToken entropy is the mean next-token prediction entropy $H(p_\\theta | \\text{context})$ averaged over 1{,}000 held-out samples; ECE uses 15 equal-width bins.\nWe additionally evaluate effective rank and Self-BLEU as candidate canaries (\\S\\ref{sec:case_study}).\nResults for distinct-3 are reported in Appendix~\\ref{app:distinct3}.\nCode and data will be released upon publication.\n\nAll hypothesis tests apply Benjamini--Hochberg (BH) FDR correction at $q{=}0.05$.\nPermutation Granger causality tests use 5{,}000 permutations on first-differenced series \\cite{shojaie2022granger}.\nCross-correlation analysis uses a maximum lag of 5 generations.\nTable~\\ref{tab:drift_summary} summarizes raw metric drift from generation~0 to generation~10 across all six contamination levels.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Metric drift (\\%, generation~0$\\to$10) for Pythia-410M across contamination levels. Diversity collapse occurs at all $\\alpha$ levels, with the strongest decline at low-to-moderate contamination ($\\alpha{=}0.25$: distinct-1 $-40.3{\\pm}0.3\\%$) rather than full replacement ($\\alpha{=}1.0$: $-27.8{\\pm}1.6\\%$). $^\\dagger$$\\alpha{=}0.10$: single seed (seed~42, preliminary). $\\alpha{=}0.00$, $\\alpha{=}0.25$, $\\alpha{=}0.50$, $\\alpha{=}0.75$: 3-seed mean${\\pm}$std (seeds 42, 43, 44); $\\alpha{=}1.0$: 4-seed mean${\\pm}$std (seeds 42, 43, 44, 45).}\n\\label{tab:drift_summary}\n\\begin{tabular}{lccccc}\n\\toprule\n$\\alpha$ & Entropy & ECE & Distinct-1 & Distinct-2 & Perplexity \\\\\n\\midrule\n0.00 & $-4.6{\\pm}0.4$ & $+37.6{\\pm}14$ & $-14.1{\\pm}0.4$ & $-9.6{\\pm}0.4$ & $-20.6{\\pm}1.0$ \\\\\n0.10$^\\dagger$ & $-5.3$ & $+57$ & $-39.6$ & $-56.4$ & $-21.0$ \\\\\n0.25 & $-4.7{\\pm}0.5$ & $+81.8{\\pm}15.9$ & $-40.3{\\pm}0.3$ & $-56.4{\\pm}0.7$ & $-18.1{\\pm}0.8$ \\\\\n0.50 & $-18.0{\\pm}0.5$ & $+822.6{\\pm}18.3$ & $-37.1{\\pm}0.4$ & $-50.4{\\pm}1.0$ & $+21.0{\\pm}0.1$ \\\\\n0.75 & $-27.6{\\pm}0.2$ & $+1791{\\pm}18$ & $-32.3{\\pm}0.5$ & $-41.0{\\pm}1.0$ & $+182.6{\\pm}0.7$ \\\\\n1.00 & $-60.8{\\pm}1.2$ & $+3780{\\pm}30$ & $-27.8{\\pm}1.6$ & $-34.0{\\pm}3.3$ & $+3674{\\pm}45$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\subsection{Method Sensitivity Analysis}\n\\label{sec:method_sensitivity}\n\nWe open with Claim~3 (method sensitivity) because it conditions the interpretation of all subsequent results.\nIf different statistical methods yield contradictory conclusions on the same data, any single-method analysis is unreliable by construction.\n\n\\paragraph{Five-method ablation.}\nWe apply five lead-lag detection methods to the $\\alpha{=}1.0$ condition (4~seeds, 16 canary$\\to$downstream pairs).\nThe fraction of pairs reaching BH-corrected FDR significance varies dramatically by method: naive cross-correlation \\textbf{16/16} (100\\%), differenced cross-correlation \\textbf{14/16} (87.5\\%), threshold onset detection \\textbf{9/16} (56.3\\%), permutation Granger causality \\textbf{6/16} (37.5\\%), and Toda--Yamamoto Granger \\textbf{5/16} (31.3\\%; moderate supplementary, \\S\\ref{sec:ty_limitation}).\nMethod choice alone swings significance from \\textbf{100\\% to 37.5\\%} among the primary methods: 50--57\\% of pairs classified as significant under one method flip to non-significant under another.\nThe spurious-signal rate (the fraction of pairs detected by the most liberal method but not confirmed by the most conservative) is at least \\textbf{62.5\\%} across the primary methods.\nTable~\\ref{tab:method_comparison} reports significance rates restricted to 8 validated canary$\\to$downstream pairs (excluding failed candidates); the 16-pair rates above include effective rank and Self-BLEU to capture the full method-sensitivity landscape.\n\n\\paragraph{First-differencing diagnostic.}\nA single preprocessing decision can eliminate an entire analysis channel.\nFor canary$\\to$diversity pairs at $\\alpha{=}1.0$, all pairs retain unanimous FDR significance after first-differencing (24/24$\\to$24/24), confirming genuine temporal precedence rather than shared-trend confounding.\nFor canary$\\to$perplexity, however, undifferenced tests find near-universal significance ($F{=}16$--$36$) while differenced tests find \\textbf{zero} significant pairs ($F{\\approx}0$, $p{=}0.99$; Figure~\\ref{fig:differencing_dmax}a).\nThe apparent canary$\\to$perplexity relationship is entirely an artifact of co-trending.\nNotably, at $\\alpha{=}0.75$, differenced cross-correlation finds 8/8 pairs significant in \\emph{both} forward and reverse directions per seed, demonstrating that this method alone cannot distinguish genuine directional precedence from shared dynamics even after detrending.\n\n\\paragraph{Augmentation order sensitivity.}\nToda--Yamamoto Granger tests show extreme sensitivity to the augmentation order $d_{\\max}$ (Figure~\\ref{fig:differencing_dmax}b).\nAfter correcting the statsmodels API incompatibility (\\S\\ref{sec:ty_limitation}), TY achieves moderate detection (3--4/8 at $\\alpha{\\geq}0.50$) at the default $d_{\\max}{=}1$; however, the qualitative finding that this single hyperparameter can swing conclusions between near-universal significance and near-universal non-significance remains, consistent with known properties of the Toda--Yamamoto procedure~\\cite{toda1995statistical}.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\linewidth]{figures/differencing_dmax.pdf}\n\\caption{First-differencing diagnostic and augmentation order sensitivity (Pythia-410M, $\\alpha{=}1.0$, 4~seeds). \\textbf{(a)}~First-differencing eliminates the canary$\\to$perplexity channel: undifferenced tests find near-universal significance ($F{=}16$--$36$) while differenced tests find zero significant pairs ($F{\\approx}0$, $p{=}0.99$), exposing these associations as shared-trend artifacts. Canary$\\to$diversity pairs retain significance after differencing (24/24$\\to$24/24). \\textbf{(b)}~Toda--Yamamoto Granger significance rates vary dramatically with augmentation order $d_{\\max}$; after correcting the implementation (\\S\\ref{sec:ty_limitation}), TY achieves moderate detection at the default $d_{\\max}{=}1$, but the qualitative sensitivity to this hyperparameter persists.}\n\\label{fig:differencing_dmax}\n\\end{figure}\n\n\\paragraph{Inter-method agreement.}\nCohen's $\\kappa$, averaged over all method pairs, is \\textbf{0.185} (near chance; poor agreement); this value is consistent across contamination levels ($\\alpha{=}0.0$ through $\\alpha{=}1.0$), indicating that method disagreement is a structural property of the analysis rather than a regime-specific artifact.\nCross-architecture validation on GPT-2-medium (12 canary$\\to$downstream pairs) yields Fleiss' $\\kappa{=}0.091$, also in the ``slight agreement'' range, confirming that low inter-method agreement is not architecture-specific.\nRestricting to three informative methods (excluding naive cross-correlation, which anchors the permissive extreme, and Toda--Yamamoto, which provides moderate supplementary signal) raises $\\kappa$ to 0.667 (substantial agreement), indicating that the low full-panel $\\kappa$ is driven by the deliberate inclusion of methods spanning the entire permissive-to-conservative spectrum rather than by fundamental incoherence among methods.\nTable~\\ref{tab:method_comparison} extends the analysis across contamination levels.\nDirection checking (D111) itself constitutes a sensitivity dimension beyond the five statistical methods: restricting to forward-direction associations inverts naive cross-correlation's profile from uniformly high (${\\approx}100\\%$ undirected) to regime-dependent, revealing that much of its apparent signal was reverse-directional.\nAt $\\alpha{=}0.0$ (null control), naive cross-correlation still finds \\textbf{75\\%} (6/8) of forward-direction pairs significant---lower than the undirected 100\\%, but still a substantial FPR.\nPermutation Granger correctly finds 0\\%, achieving perfect null-control specificity.\nAt $\\alpha{=}0.50$ (fp32), permutation Granger finds 75\\% (6/8), while naive finds 37.5\\% (Figure~\\ref{fig:consensus_heatmap}; Table~\\ref{tab:method_comparison}).\n\n\\paragraph{Method$\\times$regime interaction.}\nTable~\\ref{tab:method_comparison} reveals that direction checking reshapes the method hierarchy across contamination levels.\nAt $\\alpha{=}0.25$, naive cross-correlation drops to 12.5\\% while permutation Granger remains at 0\\%, narrowing the gap visible in undirected analysis.\nAt $\\alpha{\\geq}0.75$, naive rises to 87.5\\% while permutation Granger reaches 75\\%; both methods detect, but naive's persistent 75\\% null-control FPR means its high-$\\alpha$ detections cannot be distinguished from false positives without the consensus framework.\nThis regime-dependent reversal, combined with the block structure visible in Figure~\\ref{fig:consensus_heatmap}, motivates the regime-dependent analysis in \\S\\ref{sec:regime}.\n\n\\paragraph{Why permutation Granger succeeds.}\nThe systematic comparison identifies PermG as the only method combining zero null-control FPR with consistent detection across all regimes where signal exists ($\\alpha{\\geq}0.50$).\nThree properties explain this outcome.\nFirst, the nonparametric permutation procedure inherently controls FPR by constructing the null distribution from the observed data rather than from distributional assumptions, making it robust to the non-stationarity that inflates false positives in correlation-based methods.\nSecond, Granger tests are directional by construction: they test whether past values of $X$ improve prediction of $Y$ beyond $Y$'s own history, naturally filtering the reverse-directional associations that inflate naive cross-correlation's FPR.\nThird, PermG does not require threshold calibration or augmentation order selection, avoiding the hyperparameter sensitivity observed in Toda--Yamamoto (Figure~\\ref{fig:differencing_dmax}b; \\S\\ref{sec:ty_limitation}) and the power limitations that reduce threshold onset to near-zero detection under $3\\sigma$ calibration (\\S\\ref{sec:threshold_limitation}).\nBy contrast, differenced cross-correlation retains 100\\% FDR significance in both forward \\emph{and} reverse directions at $\\alpha{=}0.75$, failing to distinguish genuine directional precedence from shared dynamics; and Toda--Yamamoto, while achieving moderate detection (3--4/8 at $\\alpha{\\geq}0.50$), remains sensitive to the augmentation order $d_{\\max}$ (\\S\\ref{sec:ty_limitation}).\nThese complementary failures, exposed through the MMCT evaluation framework, converge on a single recommendation: for short iterative training series ($T{\\leq}20$), permutation Granger causality should be the primary detection method.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\linewidth]{figures/consensus_heatmap.pdf}\n\\caption{Method$\\times$regime consensus heatmap (Pythia-410M, fp32, 12 contamination levels, direction-checked). Each cell shows the forward-direction detection rate (\\% of 8 pairs reaching FDR significance) for five individual methods (top) and two consensus thresholds (bottom, separated by white line). Direction checking dramatically reshapes method profiles: naive cross-correlation drops from near-100\\% (undirected) to regime-dependent rates with persistent 75\\% null-control FPR. Permutation Granger achieves FPR${=}$0\\% in the blind zone (green dashed box) and detects only at $\\alpha{\\geq}0.50$. The onset boundary ($\\alpha{\\approx}0.45$--$0.50$) is where method divergence is sharpest (Pitfall~3). \\emph{Note: figure will be regenerated with D120 canonical data including corrected TY rates (\\S\\ref{sec:ty_limitation}).}}\n\\label{fig:consensus_heatmap}\n\\end{figure}\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Forward-direction FDR significance rates (\\%) for five lead-lag methods across contamination levels (Pythia-410M, seed~42, fp32, direction-checked). Direction checking reshapes method profiles: naive cross-correlation drops from near-100\\% (undirected) to regime-dependent rates (75\\% at the null, 12.5\\% at $\\alpha{=}0.25$, rising to 87.5\\% at $\\alpha{=}0.75$). Each cell reports the fraction of 8 validated canary$\\to$downstream pairs reaching BH-corrected significance ($q{=}0.05$) in the forward direction. $^\\dagger$Moderate supplementary method (\\S\\ref{sec:ty_limitation}); FPR$_\\text{null}$ pending (null condition not yet run through corrected pipeline). $^a$Seed-42 null-control rate under D105 $3\\sigma$ calibration pending; 3-seed range 12.5--37.5\\%.}\n\\label{tab:method_comparison}\n\\begin{tabular}{lcccccc}\n\\toprule\nMethod & $\\alpha{=}0.0$ & $\\alpha{=}0.25$ & $\\alpha{=}0.50$ & $\\alpha{=}0.75$ & $\\alpha{=}1.0$ & FPR$_\\text{null}$ \\\\\n\\midrule\nNaive XCorr     & 75    & 12.5 & 37.5 & 87.5  & 0     & 75   \\\\\nDiff.\\ XCorr    & 0     & 37.5 & 87.5 & 75    & 75    & 0    \\\\\nThreshold ($3\\sigma$)$^a$ & ---   & 0    & 50   & 0     & 0     & ---  \\\\\nPerm.\\ Granger  & 0     & 0    & 75   & 75    & 75    & 0    \\\\\nToda--Yamamoto$^\\dagger$  & ---   & 0    & 37.5 & 37.5  & 50    & ---  \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\subsection{Regime-Dependent Detectability}\n\\label{sec:regime}\n\nBeyond method choice, the contamination level~$\\alpha$ determines whether a temporal lead exists to detect.\nWe present regime effects at two levels: raw metric drift (method-independent) and Granger-precedence detectability.\n\n\\paragraph{Raw drift.}\nTable~\\ref{tab:drift_summary} shows that diversity collapse occurs at \\emph{all} contamination levels, not only under full synthetic replacement.\nDistinct-1 declines by 13.8\\% even at $\\alpha{=}0.0$ (attributable to fine-tuning on repeated real-data subsets).\nA single-seed observation at $\\alpha{=}0.10$ reveals a steep diversity cliff: distinct-1 drops by 39.6\\%, nearly matching the 3-seed mean at $\\alpha{=}0.25$ ($-40.3{\\pm}0.3\\%$); distinct-2 shows a comparable jump ($-56.4\\%$ vs.\\ $-56.4{\\pm}0.7\\%$ at $\\alpha{=}0.25$).\nToken entropy at $\\alpha{=}0.10$, however, differs from the null by less than 1 percentage point ($-5.3\\%$ vs.\\ $-4.6{\\pm}0.4\\%$), constituting a canary blind spot in which diversity has already collapsed but no canary metric responds.\nAt higher contamination, distinct-1 decline continues: $-37.1{\\pm}0.4\\%$ ($\\alpha{=}0.50$), $-32.3{\\pm}0.5\\%$ ($\\alpha{=}0.75$), and $-27.8{\\pm}1.6\\%$ ($\\alpha{=}1.0$).\nThe non-monotonic pattern (diversity declining \\emph{more} at moderate~$\\alpha$ than at extreme~$\\alpha$) is confirmed by 3-seed replication at $\\alpha{=}0.25$ (std${=}0.3\\%$), indicating that this relationship between contamination level and collapse severity is robust rather than a seed-specific artifact.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\linewidth]{figures/fig_dose_response.pdf}\n\\caption{Dose-response profile of permutation Granger forward detection rate (Pythia-410M, fp32, 12 contamination levels, direction-checked).\nFour regimes emerge: blind ($\\alpha{\\leq}0.45$, 0/8), onset ($\\alpha{=}0.50$, 75\\%), synchronous dip ($\\alpha{=}0.60$, 37.5\\%; orange diamond), and detection ($\\alpha{\\geq}0.75$, 62.5--75\\%).\nThe $\\alpha{=}0.60$ dip is dual-seed confirmed (s42: 3/8, s43: 0/8).\nPer-method comparison is in Figure~\\ref{fig:consensus_heatmap}.}\n\\label{fig:regime_map}\n\\end{figure}\n\n\\paragraph{Granger-precedence detectability.}\nDespite ubiquitous drift, causal detectability is sharply regime-dependent (Figure~\\ref{fig:regime_map}).\nPermutation Granger tests (first-differenced, BH-corrected) find 0/8 pairs FDR-significant from $\\alpha{=}0.00$ through $\\alpha{=}0.45$ (including $\\alpha{=}0.25$ where a faint single-pair signal appears at FDR $p{=}0.053$ but aggregate detection remains null, and $\\alpha{=}0.35$/$0.40$/$0.45$ which confirm PermG fwd${=}$0/8), \\textbf{6/8} at $\\alpha{=}0.50$ (2~fp32 seeds, consistent), \\textbf{3/8} and \\textbf{0/8} at $\\alpha{=}0.60$ (s42 and s43 respectively; dual-seed confirmed non-monotonic dip), and \\textbf{6/8} at $\\alpha{=}1.0$.\nAt $\\alpha{=}0.75$ (3~seeds), permutation Granger finds 20/24 forward-direction pairs FDR-significant with 0/24 reverse, confirming directional asymmetry; however, method-level consensus varies by seed (Tier~3 pairs: 4, 3, and 1 across seeds), placing this regime in a transitional detection state.\nUnder Bonferroni correction, approximately 3/8 pairs per seed survive, consistent with the transitional nature of the $\\alpha{=}0.75$ boundary where marginal signals are sensitive to correction stringency.\nWithin-$\\alpha$ multi-seed analysis at $\\alpha{=}1.0$ yields \\textbf{24/24} canary$\\to$diversity pairs FDR-significant across all four seeds, with 0/24 in the reverse direction, confirming temporal asymmetry.\nPermutation Granger forward significance is the primary detection indicator (Figure~\\ref{fig:regime_map}): it reaches 6/8 at $\\alpha{=}0.50$, dips to 3/8 at $\\alpha{=}0.60$ (synchronous collapse zone; see below), and recovers to 5--6/8 at $\\alpha{\\geq}0.75$.\nThe onset boundary lies at $\\alpha{\\approx}0.45$--$0.50$: finer-grained probing at $\\alpha{=}0.35$, $0.40$, and $0.45$ yields PermG fwd${=}$0/8 at all three levels, extending the blind spot through $\\alpha{=}0.45$.\nA faint signal first appears at $\\alpha{=}0.25$ (best-pair FDR $p{=}0.053$) but does not translate to aggregate detection; reliable detection begins at $\\alpha{=}0.50$ (6/8, 2~seeds).\nThis near-discontinuous onset is consistent with theoretical expectations about signal-to-noise limits in short time series~\\cite{boettiger2012limits}.\nSensitivity analysis confirms that treatment/null separation is robust to FDR threshold choice ($q{=}0.01$: 0/24 null, 0/24 treatment at $\\alpha{=}0.75$; $q{=}0.10$: 0/24 null, 24/24 treatment; Appendix~\\ref{app:robustness}).\nCross-architecture validation on GPT-2-medium confirms this boundary: at $\\alpha{=}0.25$, at most 1/8 pairs reach $K{\\geq}3$ ($3\\sigma$), consistent with the null regime, despite substantially stronger canary drift (entropy $-32.8\\%$ vs.\\ Pythia $-4.7{\\pm}0.5\\%$), while at $\\alpha{=}1.0$ all 6 canary$\\to$diversity pairs reach significance (\\S\\ref{sec:discussion}).\nTable~\\ref{tab:cross_arch_regime} summarizes the regime map across both architectures.\nAt $\\alpha{=}0.25$, GPT-2-medium yields 1/8 pairs at Tier~3 ($K{\\geq}4/5$) and 7/8 at Tier~2 ($K{\\geq}3/5$), consistent with Pythia's 0/8 Tier~3, 0/8 Tier~2 result at the same contamination level, placing both architectures in the null/low-detectability regime.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Cross-architecture regime map: lead-lag consensus tier and metric drift at $\\alpha{=}0.25$ and $\\alpha{=}1.0$. Tier~3: $K{\\geq}4/5$ methods (or $K{\\geq}3$ of 4 effective methods; \\S\\ref{sec:threshold_limitation}); Tier~2: $K{\\geq}3/5$. Drift is generation~0$\\to$10. GPT-2-medium $\\alpha{=}0.25$: single seed (seed=42); Pythia $\\alpha{=}0.25$: 3-seed mean${\\pm}$std. The onset boundary ($\\alpha{\\approx}0.45$--$0.50$) is consistent across two transformer decoder-only model families of similar scale.}\n\\label{tab:cross_arch_regime}\n\\begin{tabular}{llcccccc}\n\\toprule\n$\\alpha$ & Model & Entropy & ECE & Distinct-1 & Distinct-2 & Perm.\\ Granger & Tier~3 \\\\\n\\midrule\n0.25 & Pythia-410M  & $-4.7{\\pm}0.5$ & $+81.8{\\pm}15.9$ & $-40.3{\\pm}0.3$ & $-56.4{\\pm}0.7$ & 0/8 & 0/8 \\\\\n0.25 & GPT-2-medium & $-32.8$ & $+422$ & $-23.5$ & $-31.6$ & 0/8 & 1/8 \\\\\n\\midrule\n1.00 & Pythia-410M  & $-60.8{\\pm}1.2$ & $+3780{\\pm}30$ & $-27.8{\\pm}1.6$ & $-34.0{\\pm}3.3$ & 6/8 & 6/8 \\\\\n1.00 & GPT-2-medium & \\multicolumn{6}{c}{(reported in \\S\\ref{sec:discussion}; 6/8 canary$\\to$downstream pairs at Tier~3)} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Detectability at $\\alpha{=}0.50$ and the transition zone.}\nUnder fp32 precision, $\\alpha{=}0.50$ is reliably detected: permutation Granger finds 6/8 pairs FDR-significant across both seeds (Table~\\ref{tab:method_comparison}).\nThe transition from undetectable to reliably detectable occurs between $\\alpha{=}0.45$ and $\\alpha{=}0.50$: finer-grained probing confirms PermG fwd${=}$0/8 at $\\alpha{=}0.35$, $0.40$, and $0.45$, while $\\alpha{=}0.50$ achieves 6/8 (2~seeds).\nA faint single-pair signal first appears at $\\alpha{=}0.25$ (entropy$\\to$distinct-1: raw $p{=}0.007$, FDR-corrected $p{=}0.053$), but all aggregate indicators remain null through $\\alpha{=}0.45$, placing the onset boundary at $\\alpha{\\approx}0.45$--$0.50$.\nAt $\\alpha{=}0.50$, canary sensitivity remains metric-dependent: ECE achieves significance in both fp32 seeds, while token entropy remains below the FDR threshold ($p_{\\text{fdr}}{\\geq}0.086$), identifying ECE as the more sensitive canary near the onset boundary.\nFigure~\\ref{fig:consensus_heatmap} visualizes the method$\\times\\alpha$ interaction, revealing a block structure that separates correlation-based methods from causal methods as a function of regime.\n\n\\paragraph{Quantifying the onset boundary.}\nSigmoid regression across the 12-point $\\alpha$ grid quantifies the sharp onset observed above.\nFitting $P(\\alpha) = 1/(1 + \\exp(-k(\\alpha - \\alpha_c)))$ to the PermG forward detection rate yields a critical threshold $\\alpha_c = 0.476$ with steepness $k \\geq 200$ and transition width $\\Delta\\alpha \\approx 0.02$ (Figure~\\ref{fig:phase_transition}).\nThe sigmoid model explains 96.9\\% of variance ($R^2 = 0.969$), substantially outperforming a power-law alternative ($R^2 = 0.808$; $\\Delta\\text{AIC} = 18.2$), confirming that the onset is near-discontinuous rather than gradual.\nThis transition is striking because effective contamination barely changes across the boundary: after 10 generations of iterative training, both $\\alpha{=}0.45$ and $\\alpha{=}0.50$ drive the cumulative synthetic fraction above 99\\% ($C = 1{-}(1{-}\\alpha)^{10}$: $99.75\\%$ vs.\\ $99.90\\%$)---a difference of 0.15 percentage points---yet causal detectability jumps from 0/8 to 6/8.\nWe term this a \\emph{detection phase transition}: causal coupling emerges abruptly at a critical contamination threshold ($\\alpha_c{=}0.476$, $\\Delta\\alpha{\\approx}0.02$) rather than scaling smoothly with contamination dose.\nWithin the $S \\times R$ framework (\\S\\ref{sec:theory}), $\\alpha_c{=}0.476$ localizes the point at which signal strength $S(\\alpha)$ first crosses the detection floor, while the high steepness ($k \\geq 200$) indicates that temporal resolution $R(\\alpha)$ remains large at onset---the entropy--diversity lag has not yet begun to compress.\nCross-architecture comparison reveals no monotonic relationship between model scale and onset sensitivity (Qwen-0.8B $\\approx$ Pythia-6.9B $>$ Pythia-410M $>$ Pythia-1.4B $>$ SmolLM3-3B), suggesting that architecture and pre-training data exert stronger influence than parameter count on detection onset.\n\n\\begin{figure}[t]\n\\centering\n% TODO: transfer fig_phase_transition.pdf from westd-17855\n%\\includegraphics[width=\\linewidth]{figures/fig_phase_transition.pdf}\n\\caption{Sigmoid fit to the PermG forward detection rate across 12 contamination levels.\nThe fitted critical threshold $\\alpha_c = 0.476$ with steepness $k \\geq 200$ indicates a near-discontinuous onset of causal detectability.\nSigmoid $R^2 = 0.969$ vs.\\ power-law $R^2 = 0.808$ ($\\Delta\\text{AIC} = 18.2$).}\n\\label{fig:phase_transition}\n\\end{figure}\n\n\\paragraph{Non-monotonic dose-response: the synchronous collapse zone.}\nDual-seed replication at $\\alpha{=}0.60$ reveals a non-monotonic dose-response in Granger detectability: PermG fwd drops to 3/8 (s42) and 0/8 (s43), below both $\\alpha{=}0.50$ (6/8, 2~seeds) and $\\alpha{=}0.75$ (5--6/8 per seed, 3~seeds).\nThis creates a four-regime structure in the dose-response profile: \\emph{blind} ($\\alpha{\\leq}0.45$, 0/8), \\emph{onset} ($\\alpha{\\approx}0.50$, 6/8), \\emph{synchronous dip} ($\\alpha{\\approx}0.60$, 0--3/8), and \\emph{detection} ($\\alpha{\\geq}0.75$, 5--6/8 per seed; 6/8 at $\\alpha{=}1.0$).\nThe dip confirms the non-monotonic prediction of the $S \\times R$ framework (\\S\\ref{sec:theory}): at $\\alpha{=}0.60$, signal strength $S$ continues rising but temporal resolution $R$ drops sharply due to relaxation time matching, producing a local minimum in detectability.\nThe synchronous zone is mechanistically distinct from the blind spot: in the blind spot, canary drift is indistinguishable from the null; in the synchronous zone, both canary and downstream metrics drift substantially but without temporal offset.\nToda--Yamamoto achieves moderate detection across this range (3--4/8 at $\\alpha{\\geq}0.50$; \\S\\ref{sec:ty_limitation}), with its detection at $\\alpha{=}0.60$ suggesting partial inter-method complementarity in the synchronous collapse zone where PermG drops to 0--3/8.\nThis non-monotonicity also implies that simple threshold-based triggers (such as the 15\\% entropy criterion in \\S\\ref{sec:intervention}) may outperform formal Granger tests at intermediate contamination levels.\n\n\\paragraph{Predictions for longer generation chains.}\nThe $S \\times R$ framework (\\S\\ref{sec:theory}) generates testable predictions for longer observation windows ($T{=}20$).\nIncreased $T$ improves temporal resolution without changing signal strength, effectively increasing $R(\\alpha)$ by providing more observation points for Granger tests to detect sub-generation lags.\nWe predict: (i)~at $\\alpha{=}0.50$, PermG detection should increase from 6/8 to ${\\geq}7/8$ as additional generations provide more statistical power for an already-present lead;\n(ii)~at $\\alpha{=}0.60$, the synchronous dip should attenuate or disappear, because finer temporal sampling allows Granger tests to resolve lags that are invisible at $T{=}11$;\n(iii)~at $\\alpha{=}1.0$, detection should remain at 6--8/8, as the strong signal is already saturated.\nThese predictions are submitted for future empirical verification with extended generation protocols.\n\n\n\\subsection{Case Study: Canary Prediction of Diversity Collapse}\n\\label{sec:case_study}\n\nHaving established method sensitivity (Claim~3) and regime dependence (Claim~2), we present the conditions under which canary prediction succeeds (Claim~1).\nWe scope this claim precisely: canary metrics predict \\emph{diversity collapse} (declining distinct-$n$), not model collapse broadly.\n\n\\paragraph{Full synthetic replacement ($\\alpha{=}1.0$, 4 seeds).}\nToken entropy exhibits robust Granger-precedence over diversity collapse metrics, confirmed by 4 independent statistical methods (permutation Granger power${=}1.0$), 4 seeds, and cross-architecture replication on GPT-2-medium (Tier~3 consensus; \\S\\ref{sec:discussion}).\nCross-correlation peaks at lag$={+}1$ with $|r|{>}0.99$ (cross-seed standard deviation: 0.0), establishing a consistent one-generation lead.\nFigure~\\ref{fig:metric_trajectory} illustrates the one-generation offset between token entropy decline and distinct-1 decline, visible across all four seeds.\nPermutation Granger tests (first-differenced) confirm all canary$\\to$diversity pairs as FDR-significant across all four seeds, including distinct-3 (Appendix~\\ref{app:distinct3}).\nReverse-direction tests (downstream$\\to$canary) on WikiText-103 find \\textbf{0/24} FDR-significant (all $p{>}0.49$), establishing directional asymmetry in this domain.\\footnote{C4 exhibits domain-dependent directionality: at $\\alpha{=}0.50$ (s42 fp32), PermG reverse reaches 7/8, indicating near-symmetric bidirectional coupling (\\S\\ref{sec:discussion}).}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\linewidth]{figures/metric_trajectory.pdf}\n\\caption{Metric trajectories across 10 generations at $\\alpha{=}1.0$ (Pythia-410M, 4~seeds shown as individual traces). Token entropy (top, blue) drops sharply at generation~1, while distinct-1 (bottom, red) begins declining at generations~2--3, establishing a visible one-generation canary lead. The consistent lag across all four seeds confirms that the temporal offset is robust rather than seed-specific. Shaded bands show the inter-seed range. This visual pattern corresponds to the statistical finding of 24/24 forward-direction and 0/24 reverse-direction FDR-significant pairs.}\n\\label{fig:metric_trajectory}\n\\end{figure}\n\n\\paragraph{High contamination ($\\alpha{=}0.75$, 3 seeds).}\nDirectional asymmetry is robustly confirmed across three independent seeds (permutation Granger: 20/24 forward pairs FDR-significant, 0/24 reverse).\nHowever, method-level consensus varies by seed (Tier~3 pairs: 4, 3, and 1 across seeds 42, 43, 44), placing $\\alpha{=}0.75$ squarely in the transitional detection regime.\nDifferenced cross-correlation finds 8/8 pairs significant in \\emph{both} forward and reverse directions at each seed, confirming that this method alone cannot distinguish genuine directional precedence from shared dynamics, a seed-level demonstration of Pitfall~1 (\\S\\ref{sec:pitfalls}).\n\n\\paragraph{ECE as a conditional secondary canary.}\nECE's forward consensus matches token entropy (both achieve PermG\\_fwd 6/8 across all conditions), but the reverse profile diverges sharply.\nAcross 7 validated conditions at $\\alpha{=}1.0$ (3 architectures $\\times$ 2 scales $\\times$ 2 domains), token entropy reverse direction yields \\textbf{0/28} FDR-significant pairs (consistent with unidirectional forward causation at full synthetic replacement; domain-dependent bidirectionality emerges at lower $\\alpha$, \\S\\ref{sec:discussion}), while ECE reverse direction yields \\textbf{13/28} significant pairs, with 5/7 conditions containing at least one reverse-significant pair, all in the distinct$\\to$ECE direction.\nThis bidirectional coupling is the core reason ECE is classified as a secondary canary: ECE and diversity exhibit mutual feedback, and the interpretability of ECE's causal direction is correspondingly limited.\nThis result also instantiates Claim~3 (method sensitivity): when only forward significance is considered, the two canary types appear equivalent; incorporating reverse-direction tests separates them. The choice of analysis dimension alters the canary classification itself.\n\n\\paragraph{Failed canary candidates.}\nNot all metrics serve as canaries.\nEffective rank and Self-BLEU show no detectable lead-lag relationship with any downstream metric under any method or contamination level, and are excluded from the consensus framework.\nEffective rank behavior is model-dependent in an unexpected way: in Pythia-410M, effective rank decreases during collapse (representational contraction), whereas in GPT-2-medium at $\\alpha{=}0.25$ it \\emph{increases} from 2.37 to 8.48 (+258\\%).\nThe GPT-2-medium starting effective rank is near rank-2, suggesting the model's initial representation is already highly concentrated; iterative training disperses it rather than concentrating it further.\nThis opposite directionality across architectures precludes effective rank as a universal canary and motivates architecture-specific analysis (\\S\\ref{sec:discussion}).\n\n\\paragraph{Consensus filtering.}\nOf 16 canary$\\to$downstream pairs tested at $\\alpha{=}1.0$ (4 candidate canaries $\\times$ 4 downstream metrics), \\textbf{6 survive} the full consensus pipeline (PermG fwd ${\\geq}6/8$, $S{\\geq}3/4$ seeds): token entropy and ECE each predicting distinct-1 and distinct-2 (4 pairs; distinct-3 results in Appendix~\\ref{app:distinct3} bring the total to~6).\nThe 10 eliminated pairs comprise all canary$\\to$perplexity relationships (identified as spurious by the first-differencing diagnostic) and all effective-rank and Self-BLEU pairs (failed canaries).\nThe consensus framework reduces the naive 75\\% forward-direction FPR to 0\\%, matching the most conservative individual methods (Figure~\\ref{fig:consensus_workflow}).\n\n\n\\subsection{Consensus Framework Validation}\n\\label{sec:consensus_validation}\n\nWe validate the consensus framework's calibration using built-in experimental controls.\n\n\\paragraph{False positive rate.}\nAt $\\alpha{=}0.0$ (three seeds, 24 total pairs), no synthetic data is injected; any detected lead-lag association is a false positive.\nIndividual-method forward-direction FPR ranges from \\textbf{75\\%} (naive cross-correlation: 6/8) through 37.5\\% (threshold) down to \\textbf{0\\%} (permutation Granger and differenced cross-correlation); Toda--Yamamoto's null-control FPR has not yet been evaluated through the corrected pipeline (\\S\\ref{sec:ty_limitation}).\nThe multi-method consensus at $K{\\geq}3$ ($3\\sigma$) achieves \\textbf{FPR${=}$0\\%} (0/24 pairs, three independent seeds), matching the best individual method (permutation Granger) while providing a formal benchmark for method reliability (Table~\\ref{tab:fpr_fnr}).\n\n\\paragraph{False negative rate.}\nAt $\\alpha{=}1.0$, we define 6 effect-size reference pairs (token entropy and ECE $\\to$ distinct-1/2/3) using criteria independent of the consensus methods: drift ratio ${\\geq}3\\times$ the $\\alpha{=}0.0$ baseline (entropy $11.93\\times$, ECE $73.12\\times$) and canary onset strictly preceding downstream onset by ${\\geq}1$ generation (\\S\\ref{sec:calibration}).\nFNR is calibrated on a 4-method panel (excluding differenced cross-correlation to avoid circularity): at $K{\\geq}3/4$, $S{\\geq}3/4$, all~6 are recovered (\\textbf{FNR${=}$0\\%}).\nToda--Yamamoto's individual FNR is 50\\% (4/8 detected at $\\alpha{=}1.0$, seed~42), consistent with its moderate supplementary classification (\\S\\ref{sec:ty_limitation}).\nBoth FPR and FNR are validated on the joint method${\\times}$seed dimension (FPR: 3~seeds at $\\alpha{=}0.0$; FNR: 4~seeds at $\\alpha{=}1.0$), with cross-seed FPR variance negligible (all three seeds yield 0/8 robust pairs at $K{\\geq}3$).\nTable~\\ref{tab:fpr_fnr} reports the calibration results.\nTable~\\ref{tab:single-method-errors} complements this analysis by showing the practical consequences of relying on any single method: naive cross-correlation produces false positives at every $\\alpha$ including the null control, while permutation Granger achieves correct verdicts at all levels with zero FPR.\n\n\\begin{table}[t]\n\\centering\n\\caption{Single-method inference errors across contamination levels.\nEach cell shows the verdict (significant or not) based on multi-seed majority ($\\geq$2/3 seeds with $\\geq$4/8 pairs significant).\n\\checkmark\\ = correct, \\textcolor{red}{FP} = false positive, \\textcolor{blue}{FN} = false negative, $\\circ$ = ambiguous ground truth (either verdict plausible).\nNaive XCorr produces false positives at \\emph{every} $\\alpha$ including the null control. Permutation Granger achieves correct verdicts at all levels with zero FPR. $^\\dagger$Rows marked pending have cross-script inconsistencies under audit.}\n\\label{tab:single-method-errors}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccccc}\n\\toprule\n & \\multicolumn{2}{c}{\\textit{No signal}} & \\textit{Ambiguous} & \\multicolumn{2}{c}{\\textit{Causal signal}} \\\\\n\\cmidrule(lr){2-3} \\cmidrule(lr){4-4} \\cmidrule(lr){5-6}\nMethod & $\\alpha{=}0.00$ & $\\alpha{=}0.25$ & $\\alpha{=}0.50$ & $\\alpha{=}0.75$ & $\\alpha{=}1.00$ \\\\\n\\midrule\nNaive XCorr\n  & \\textcolor{red}{FP}{\\scriptsize\\ 8,7,8}\n  & \\textcolor{red}{FP}{\\scriptsize\\ 8,8}\n  & $\\circ${\\scriptsize\\ 8,8,8}\n  & \\checkmark{\\scriptsize\\ 8,8,8}\n  & \\checkmark{\\scriptsize\\ 8,8,8} \\\\\nDiff XCorr (FDR)$^\\dagger$\n  & --- & --- & --- & --- & --- \\\\\nThreshold Onset$^\\dagger$\n  & --- & --- & --- & --- & --- \\\\\nPerm Granger (FDR)\n  & \\checkmark{\\scriptsize\\ 0,0,0}\n  & \\checkmark{\\scriptsize\\ 0,0}\n  & $\\circ${\\scriptsize\\ 0,6,3}\n  & \\checkmark{\\scriptsize\\ 8,5,6}\n  & \\checkmark{\\scriptsize\\ 6,6,6} \\\\\nTY Granger$^\\dagger$\n  & --- & --- & --- & --- & --- \\\\\n\\midrule\n\\textbf{Consensus ($K{\\geq}3$)}$^\\dagger$\n  & --- & --- & --- & --- & --- \\\\\n\\bottomrule\n\\multicolumn{6}{l}{\\footnotesize Subscript numbers: per-seed significant pair counts out of 8.} \\\\\n\\multicolumn{6}{l}{\\footnotesize Seeds: $\\alpha{=}0.00/0.50/0.75$: 42, 43, 44; $\\alpha{=}0.25$: 43, 44; $\\alpha{=}1.00$: 42, 43, 45.} \\\\\n\\end{tabular}%\n}\n\\end{table}\n\n\\paragraph{Bootstrap power analysis.}\nTo quantify detection power beyond binary FNR, we perform bootstrap power analysis ($B{=}1{,}000$ resamples from 4-seed data at $\\alpha{=}1.0$).\nPermutation Granger achieves power${=}1.0$ on genuine pairs (canary$\\to$diversity) and power${=}0.0$ on spurious pairs (canary$\\to$perplexity), providing clean separation.\nToda--Yamamoto achieves power${=}0.50$ on genuine pairs (4/8 detected at $\\alpha{=}1.0$), consistent with its moderate supplementary classification (\\S\\ref{sec:ty_limitation}).\nWe note that bootstrap power${=}1.0$ reflects the effect size in our 4-seed data and should not be interpreted as a universal power guarantee; furthermore, the two methods use different data-generating processes for calibration (permutation Granger resamples observed $\\alpha{=}1.0$ trajectories, while Toda--Yamamoto power was estimated under a generic VAR(2) simulation with $\\beta{=}0.3$).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{False positive and false negative rates for individual methods and the consensus framework (Pythia-410M). The consensus threshold $K{\\geq}3$ ($3\\sigma$, excluding threshold onset; \\S\\ref{sec:threshold_limitation}) achieves FPR${=}$0\\% and FNR${=}$0\\%, matching the best individual method (permutation Granger) while providing robustness against miscalibration of any single method. FPR: $\\alpha{=}0.0$ null control (three seeds, $M{=}5$ methods); values are 3-seed means with ranges in parentheses where cross-seed variance is non-negligible. FNR: $\\alpha{=}1.0$ against 6 effect-size reference pairs (4-method panel excluding differenced cross-correlation, 4~seeds). $^\\dagger$Moderate supplementary method (\\S\\ref{sec:ty_limitation}); FPR pending (null condition not yet run through corrected pipeline); FNR from single-seed $\\alpha{=}1.0$ (4/8 detected).}\n\\label{tab:fpr_fnr}\n\\begin{tabular}{lcc}\n\\toprule\nCriterion & FPR ($\\alpha{=}0.0$) & FNR ($\\alpha{=}1.0$) \\\\\n\\midrule\nNaive XCorr              & 100\\%              & 0\\%  \\\\\nDifferenced XCorr        & 37.5\\%             & 0\\%  \\\\\nThreshold Onset          & 20.8\\% (12.5--37.5) & 0\\%  \\\\\nPermutation Granger      & 0\\%                & 0\\%  \\\\\nToda--Yamamoto$^\\dagger$  & ---                & 50\\%   \\\\\n\\midrule\nConsensus ($K{\\geq}3$, $3\\sigma$)      & 0\\%    & 0\\%  \\\\\nConsensus ($K{\\geq}3$, $S{\\geq}3/4$)   & 0\\%    & 0\\%  \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\subsection{Cross-Architecture, Cross-Scale, and Cross-Domain Generalization}\n\\label{sec:generalization}\n\nThe methodological pitfalls and consensus framework developed above are calibrated on a single model family (Pythia-410M, WikiText-103).\nTo test whether these findings transfer, we evaluate the lead-lag pattern along three generalization axes: architecture family (GPT-2-medium 345M, OPT-1.3B), model scale (Pythia-1.4B, $3.4\\times$ parameters within the same family), and training domain (Pythia-1B trained on C4 rather than WikiText-103).\nAll conditions use $\\alpha{=}1.0$; architecture conditions use a single seed, while scale and domain conditions use two seeds (s42, s43) to assess replicability.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Cross-architecture lead-lag detectability ($\\alpha{=}1.0$, D105 unified pipeline, $3\\sigma$ calibration, M035 direction-corrected).\nPermG~fwd: permutation Granger forward-direction FDR-significant pairs (out of 8).\n$K{\\geq}3$: pairs where ${\\geq}3$ of 5 methods reach FDR significance (direction-checked, $3\\sigma$).\nPermG~fwd ${\\geq}6/8$ in 12/14 confirmed conditions; $K{\\geq}3$ ${\\geq}6/8$ in 10/14 (11/14 pending Padding-410M audit).\nExceptions: Pythia-1.4B (s42: 1/8$^\\dagger$, s43: 3/8) and SmolLM3-3B (3/8$^\\ddagger$).\nRows marked ``---'' are running experiments; final values will be filled without format changes.}\n\\label{tab:generalization}\n\\begin{tabular}{lrclcc}\n\\toprule\nModel & Params & Seed & Domain & PermG (fwd) & $K{\\geq}3$ \\\\\n\\midrule\n\\multicolumn{6}{l}{\\emph{Baseline}} \\\\\nPythia-410M       & 410M & s42 & Wiki & 6/8            & 6/8            \\\\\nPythia-410M       & 410M & s43 & Wiki & 6/8            & 6/8            \\\\\n\\addlinespace\n\\multicolumn{6}{l}{\\emph{Scale}} \\\\\nPythia-1.4B       & 1.4B & s42 & Wiki & \\textbf{2/8}$^\\dagger$ & \\textbf{1/8}$^\\dagger$  \\\\\nPythia-1.4B       & 1.4B & s43 & Wiki & 6/8            & 3/8     \\\\\nPythia-6.9B       & 6.9B & s42 & Wiki & 7/8$^*$        & 6/8            \\\\\nPythia-6.9B       & 6.9B & s43 & Wiki & ---            & ---            \\\\\n\\addlinespace\n\\multicolumn{6}{l}{\\emph{Architecture}} \\\\\nGPT-2-medium      & 345M & s42 & Wiki & 6/8            & 6/8            \\\\\nGPT-2-medium      & 345M & s43 & Wiki & 6/8            & 6/8            \\\\\nOPT-1.3B          & 1.3B & s42 & Wiki & 6/8            & 6/8            \\\\\nOPT-1.3B          & 1.3B & s43 & Wiki & 6/8            & 6/8            \\\\\nQwen3.5-0.8B      & 0.8B & s42 & Wiki & 8/8            & 6/8            \\\\\nQwen3.5-0.8B      & 0.8B & s43 & Wiki & ---            & ---            \\\\\nSmolLM3-3B        & 3.0B & s42 & Wiki & \\textbf{3/8}$^\\ddagger$ & \\textbf{3/8}$^\\ddagger$ \\\\\nSmolLM3-3B        & 3.0B & s43 & Wiki & ---            & ---            \\\\\n\\addlinespace\n\\multicolumn{6}{l}{\\emph{Tokenization}} \\\\\nPadding-410M      & 410M & s42 & Wiki & 6/8            & 6/8$^{\\S}$     \\\\\n\\addlinespace\n\\multicolumn{6}{l}{\\emph{Domain}} \\\\\nPythia-1B         & 1.0B & s42 & C4   & 8/8            & 7/8            \\\\\nPythia-1B         & 1.0B & s43 & C4   & 7/8            & 6/8            \\\\\n\\bottomrule\n\\multicolumn{6}{l}{\\footnotesize $^\\dagger$Seed-sensitive: PermG s42 2/8, s43 6/8; $K{\\geq}3$ s42 1/8, s43 3/8. Likely stochastic instability at this scale (\\S\\ref{sec:discussion}).} \\\\\n\\multicolumn{6}{l}{\\footnotesize $^\\ddagger$Canary metric splitting: only ECE$\\to$downstream pairs detected (3/4); entropy$\\to$downstream 0/4 (\\S\\ref{sec:smollm3}).} \\\\\n\\multicolumn{6}{l}{\\footnotesize $^*$bf16 precision (model exceeds single-GPU fp32 capacity).} \\\\\n\\multicolumn{6}{l}{\\footnotesize $^{\\S}$Padding-410M $K{\\geq}3$ pending supplementary audit (expected stable at 6/8).} \\\\\n\\multicolumn{6}{l}{\\footnotesize Full method-level breakdown ($K{\\geq}4$) in Appendix~\\ref{app:cross_arch}.} \\\\\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Cross-condition robustness.}\nTable~\\ref{tab:generalization} confirms that the entropy-leads-diversity pattern is robust across 14 confirmed conditions (3 pending) spanning six model families (Pythia, GPT-2, OPT, Qwen, SmolLM3, Padding-variant), scales from 345M to 6.9B, and two training domains (WikiText-103, C4).\nPermutation Granger forward significance reaches ${\\geq}6/8$ in 12 of 14 conditions (85.7\\%), with two exceptions: Pythia-1.4B seed~42 (2/8), a seed-dependent outlier that recovers to 6/8 in seed~43, and SmolLM3-3B (3/8), where only ECE$\\to$downstream pairs are detected (see below).\n$K{\\geq}3$ multi-method consensus reaches ${\\geq}6/8$ in 10 of 14 conditions (11/14 pending Padding-410M audit), with exceptions Pythia-1.4B (s42: 1/8, s43: 3/8) and SmolLM3-3B (3/8).\nThe concordance between PermG and $K{\\geq}3$ confirms that multi-method consensus is robust across architectures.\nThe onset threshold $\\alpha_c{\\approx}0.50$ is robust across all six families: every architecture that achieves detection does so at or above $\\alpha{=}0.50$, while none achieves reliable detection below this threshold, suggesting that the detection phase transition boundary is architecture-independent even though detection power above onset varies with model family.\nWith threshold onset power-limited and Toda--Yamamoto providing moderate supplementary signal (3--4/8 at $\\alpha{\\geq}0.50$; \\S\\ref{sec:ty_limitation}), $K{\\geq}3$ draws on four contributing methods---a stronger standard than simple majority (\\S\\ref{sec:consensus}).\n\n\\paragraph{Scale generalization.}\nScaling from 410M to 6.9B parameters confirms that the lead-lag pattern persists across a $17\\times$ parameter range.\nPythia-6.9B achieves PermG fwd~7/8 (bf16), the strongest single-seed detection.\nWithin the Pythia family, 1.4B shows seed dependence: s42 yields only 2/8 (the sole outlier across all conditions), while s43 recovers to 6/8.\nQwen3.5-0.8B (PermG~fwd~8/8) extends the finding beyond the Pythia/GPT-2/OPT decoder-only family to an independently trained architecture with a different tokenizer.\n\n\\paragraph{Domain generalization.}\nReplacing WikiText-103 with C4 yields the strongest forward detection: Pythia-1B achieves PermG~fwd~8/8 in both seeds at $\\alpha{=}1.0$, confirming that the lead-lag pattern is not an artifact of narrow topical distribution.\nHowever, directional asymmetry does not transfer fully across domains.\nAt $\\alpha{=}0.50$ (Pythia-410M, C4, s42 fp32), PermG reverse reaches 7/8 (compared to 0/8 in all WikiText conditions), indicating near-symmetric bidirectional coupling between canary and downstream metrics.\nThis domain-dependent directionality suggests that the unidirectional forward causation observed in WikiText may partly reflect domain-specific dynamics rather than a universal property of collapse; implications are discussed in \\S\\ref{sec:discussion}.\n\n\\paragraph{Canary metric sensitivity: the SmolLM3-3B case.}\n\\label{sec:smollm3}\nSmolLM3-3B (PermG fwd 3/8) reveals that canary metric choice is itself a dimension of method sensitivity.\nDecomposing by canary type: ECE$\\to$downstream achieves 3/4 significant pairs, while token entropy$\\to$downstream achieves 0/4.\nThe root cause is that SmolLM3's token entropy exhibits non-monotonic oscillations across generations, violating the monotonic decline pattern that Granger tests exploit; ECE, by contrast, maintains its monotonic upward trajectory.\nMulti-method consensus confirms the severity: entropy pairs activate only via naive and differenced cross-correlation (per-pair $K{=}2$), ECE pairs activate only via differenced cross-correlation and permutation Granger (per-pair $K{=}2$), and no pair exceeds two-method agreement---illustrating that even within a single architecture, the method panel fragments along canary metric boundaries.\nThis architecture-dependent canary sensitivity complements the finding that effective rank direction is model-dependent (\\S\\ref{sec:case_study}): no single canary metric is universally optimal across all architectures, enriching Claim~3 by adding canary metric selection as a further source of analytic variability.\n\n\\subsection{Canary-Based Early Intervention}\n\\label{sec:intervention}\n\nTo test whether the lead-lag relationship translates into practical utility, we implement a predictive cessation protocol: training with synthetic data ($\\alpha{=}1.0$) continues until token entropy drops ${>}15\\%$ relative to generation~0, at which point $\\alpha$ is switched to $0.0$ (pure real data).\nWe compare against a reactive baseline that triggers only when distinct-1 drops ${>}10\\%$---a downstream metric that, by the lead-lag hypothesis, should respond later.\n\n\\paragraph{Pythia-410M.}\nThe predictive trigger fires at generation~1 in both seed-precision pairs tested (s42 fp32: entropy $3.234{\\to}1.918$, ${\\downarrow}40.7\\%$; s43 bf16: $3.257{\\to}2.523$, ${\\downarrow}22.5\\%$).\nThe reactive baseline triggers one generation later (generation~2, distinct-1 ${\\downarrow}15.6\\%$).\nPredictive intervention reduces peak perplexity by 63\\% relative to reactive ($56.99$ vs.\\ $157.09$, s42 fp32) and achieves full recovery by generation~2 versus generation~4 for reactive.\nThe bf16 pair shows a milder perturbation (peak perplexity $24.65$ vs.\\ $56.99$) consistent with stochastic rounding regularization, but the structural pattern---generation~1 trigger, generation~2 recovery---is identical.\nBoth conditions converge to the $\\alpha{=}0.0$ baseline by generation~10.\n\n\\paragraph{Cross-scale validation: Pythia-1.4B.}\nPythia-1.4B (s42 fp32) replicates the 410M pattern: token entropy drops $51.9\\%$ at generation~1 ($2.946{\\to}1.418$), exceeding the 15\\% threshold, and recovers to $2.892$ by generation~2 ($98.2\\%$ of baseline).\nPerplexity spikes from $19.68$ to $65.37$ at the trigger generation and recovers to $17.44$ by generation~2 (stable at $17.60$ through generation~10).\nThe trigger generation, recovery timeline, and convergence behavior are identical across the $3.4\\times$ scale gap (410M to 1.4B), confirming that the canary-based intervention mechanism is scale-independent: the 15\\% entropy threshold generalizes without recalibration across model sizes.",
      "numLines": 464,
      "startLine": 1,
      "totalLines": 464
    }
  },
  "sourceToolAssistantUUID": "bd354e0c-092e-4fc6-bbba-fade3ad71384",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Tool call

_source line 761 · 2026-05-20T10:04:43.967Z_

<details open><summary>🔧 Tool call — Read · `toolu_017EKN878hXKhkcqQP6TZjJH`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "49817fe8-f400-44c2-b28a-46569a4761d6",
  "isSidechain": false,
  "requestId": "req_011CbDdbjfTscrvQ98HLDD8A",
  "type": "assistant",
  "uuid": "5fedf337-8bf6-4a4b-962b-1b09dac37bbc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019Xoa2Yo79oG4AZ6f48eGVL",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7918,
      "cache_read_input_tokens": 38655,
      "output_tokens": 233,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 7918,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 233,
          "cache_read_input_tokens": 38655,
          "cache_creation_input_tokens": 7918,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 7918
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

_source line 762_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Director 指令] [Reframe — D130] 论文从 Methodology Paper 转型为 Detection Phase Transition Discovery Paper  投稿目标：EMNLP 2026 ARR June cycle，8 页 main text + unlimited references + appendix。当前 37 页需大幅压缩。  ## 核心…",
  "leafUuid": "5fedf337-8bf6-4a4b-962b-1b09dac37bbc",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


### Runtime record

_source line 763_

```json
{
  "type": "ai-title",
  "aiTitle": "Correct effective_rank framework and add phase transition citations",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


### Tool result

_source line 764 · 2026-05-20T10:04:44.253Z_

<details><summary>↩ Tool result · `toolu_017EKN878hXKhkcqQP6TZjJH`</summary>

```text
1	\section{Method}
2	\label{sec:method}
3	
4	The experiments in \S\ref{sec:method_sensitivity}--\ref{sec:consensus_validation} reveal that lead-lag conclusions in iterative training collapse are fragile along multiple axes.
5	This section distills three methodological pitfalls (\S\ref{sec:pitfalls}), proposes a multi-method consensus framework to quantify their impact and identify the most reliable individual method (\S\ref{sec:consensus}), and calibrates the framework's error rates using built-in experimental controls (\S\ref{sec:calibration}).
6	
7	
8	\subsection{Methodological Pitfalls in Lead-Lag Analysis}
9	\label{sec:pitfalls}
10	
11	We identify three pitfalls that, individually or in combination, can produce incorrect conclusions about temporal precedence in iterative training systems.
12	Each is documented below with representative data from our experiments; full results appear in \S\ref{sec:experiments}.
13	
14	\paragraph{Pitfall 1: Method sensitivity.}
15	Applied to the same data ($\alpha{=}1.0$, 4~seeds, 16 canary$\to$downstream pairs: 4 candidate canaries $\times$ 4 downstream metrics, including candidates later excluded per \S\ref{sec:case_study}), five lead-lag detection methods yield FDR significance rates ranging from 100\% (naive cross-correlation) to 37.5\% (permutation Granger), with Toda--Yamamoto achieving moderate rates (3--4/8 at $\alpha{\geq}0.50$); inter-method agreement is Cohen's $\kappa{=}0.185$, indicating poor agreement (\S\ref{sec:method_sensitivity}).
16	The spurious-signal rate (the fraction of pairs flagged by the most liberal method but not confirmed by the most conservative) is at least 62.5\% across the primary methods.
17	This pitfall is dangerous because method choice alone can determine whether a lead-lag relationship is deemed present or absent.
18	In a literature where single-method analyses are the norm, the implicit assumption that method choice does not matter is demonstrably false.
19	
20	\paragraph{Pitfall 2: Spurious regression under shared trends.}
21	A single preprocessing decision, first-differencing to remove shared non-stationary trends~\cite{granger1974spurious}, can eliminate an entire analysis channel.
22	At $\alpha{=}1.0$, canary$\to$perplexity pairs appear near-universally significant in undifferenced analysis ($F{=}16$--$36$) but yield $F{\approx}0$, $p{=}0.99$ after differencing (Figure~\ref{fig:differencing_dmax}a; \S\ref{sec:method_sensitivity}).
23	In contrast, canary$\to$diversity pairs retain unanimous FDR significance after differencing (24/24$\to$24/24).
24	Without the differencing diagnostic, an analyst would conclude that canaries predict perplexity, a conclusion entirely driven by co-trending rather than temporal precedence.
25	The danger lies in the selective nature of this confound: only by applying the diagnostic can one determine which channels are genuine and which are artifacts of shared non-stationarity.
26	
27	\paragraph{Pitfall 3: Regime dependence.}
28	Even after fixing the statistical method, the contamination level~$\alpha$ determines whether a lead-lag relationship is detectable.
29	Permutation Granger tests (first-differenced, BH FDR-corrected at $q{=}0.05$) find 6/8 pairs FDR-significant at both $\alpha{=}0.50$ (2~fp32 seeds, consistent) and $\alpha{=}1.0$, but 0/8 through $\alpha{=}0.45$ (\S\ref{sec:regime}).
30	The transition zone at $\alpha{\approx}0.45$--$0.50$ is where method divergence is most dangerous: correlation-based methods find significance across all levels while causal methods remain null through $\alpha{=}0.45$ (a faint single-pair signal appears at $\alpha{=}0.25$, FDR $p{=}0.053$, but does not reach aggregate detection), creating the maximum risk of spurious conclusions when only a single (liberal) method is used.
31	This regime dependence is consistent with theoretical expectations about signal-to-noise limits in short ecological time series \cite{boettiger2012limits}, and suggests that detectability boundaries should be explicitly mapped rather than assumed.
32	
33	
34	\subsection{Multi-Method Consensus Framework}
35	\label{sec:consensus}
36	
37	The pitfalls above motivate a multi-method consensus approach inspired by specification curve analysis \cite{simonsohn2020specification} and multi-method validation in early-warning signal detection \cite{scheffer2009early}: rather than relying on any single method, we apply multiple independent methods to quantify how analytic choices determine conclusions, using agreement thresholds as diagnostic benchmarks.
38	
39	\paragraph{Formal definition.}
40	Given $M$ lead-lag detection methods $\{m_1, \ldots, m_M\}$ and $N$ independent random seeds, a canary$\to$downstream pair $(X, Y)$ is classified as \textsc{robust} if and only if:
41	\begin{enumerate}
42	    \item At least $K$ of $M$ methods judge the pair FDR-significant, where each method independently applies Benjamini--Hochberg correction at $q{=}0.05$; and
43	    \item At least $S$ of $N$ seeds replicate this conclusion.
44	\end{enumerate}
45	The thresholds $(K, S)$ control the trade-off between false positive and false negative rates.
46	Methods with different inductive biases (correlation-based methods that detect any temporal association versus Granger-type methods that test directional predictive improvement \cite{granger1969investigating}) provide complementary evidence.
47	Their convergence on a given pair constitutes stronger evidence than agreement among methods sharing the same statistical assumptions.
48	We note that Granger precedence establishes temporal predictive improvement, not true causality \cite{shojaie2022granger}; our framework inherits this limitation.
49	
50	\paragraph{Method tiering.}
51	The five methods are organized into two tiers based on empirical reliability.
52	Three \emph{primary} methods---naive cross-correlation, differenced cross-correlation, and permutation Granger causality---produce consistent results across independent analysis pipelines and exhibit adequate statistical power at $T{=}11$ generations.
53	Two methods are classified as \emph{supplementary}: threshold onset detection due to power limitations at $T{=}11$ under corrected $3\sigma$ calibration (\S\ref{sec:threshold_limitation}), and Toda--Yamamoto Granger causality, which achieves moderate detection (3--4/8 at $\alpha{\geq}0.50$) but with reduced power relative to the primary methods (\S\ref{sec:ty_limitation}).
54	The consensus panel thus comprises four contributing methods (three primary, one moderate supplementary), with threshold onset near-inoperative at $T{=}11$.
55	The consensus threshold $K{\geq}3$ out of 5 methods requires agreement among at least the three primary methods or two primary methods plus TY, making $K{\geq}3$ a \emph{stronger} standard than a simple majority vote would suggest.
56	
57	\paragraph{Sequential filtering pipeline.}
58	In practice, the $K$-of-$M$ voting operates over all five methods applied independently to each pair; the sequential pipeline below describes the order in which results are examined, enabling early termination and interpretable diagnostics at each stage (Figure~\ref{fig:consensus_workflow}):
59	\begin{enumerate}
60	    \item \textbf{Naive correlation scan.} Cross-correlation at maximum lag~5 with BH correction serves as a permissive baseline; all pairs with any temporal association pass.
61	    \item \textbf{First-differencing diagnostic.} Cross-correlation is recomputed on first-differenced series, testing whether temporal associations survive removal of shared linear trends. Pairs that lose significance are flagged as potential spurious regressions.
62	    \item \textbf{Permutation Granger causality.} Permutation-based Granger causality tests \cite{shojaie2022granger} on first-differenced series (5{,}000 permutations, BH correction at $q{=}0.05$) assess directional predictive improvement: whether past values of $X$ improve prediction of $Y$ beyond $Y$'s own history.
63	    \item \textbf{Multi-seed replication.} The conclusion must hold across $S$ of $N$ independent training seeds, filtering seed-specific artifacts.
64	\end{enumerate}
65	At $\alpha{=}1.0$, this pipeline progressively filters: 16 pairs pass Stage~1, 14 survive Stage~2 (differencing removes 2 marginal canary$\to$perplexity pairs), 6 survive Stage~3 (Granger testing eliminates remaining canary$\to$perplexity pairs and failed canary candidates), and all~6 survive Stage~4 (multi-seed replication confirms all Granger-significant pairs).
66	
67	\begin{figure}[t]
68	\centering
69	\includegraphics[width=\linewidth]{figures/consensus_workflow.pdf}
70	\caption{Sequential filtering pipeline of the multi-method consensus framework. Starting from all candidate canary$\to$downstream pairs, the pipeline applies four stages: (1)~naive cross-correlation scan (permissive baseline), (2)~first-differencing diagnostic (removes shared-trend artifacts), (3)~permutation Granger causality (tests directional predictive improvement), and (4)~multi-seed replication (filters seed-specific artifacts). At $\alpha{=}1.0$ (Pythia-410M), the pipeline reduces 16 candidate pairs to 6 robust pairs: 16$\to$14$\to$6$\to$6. The $K$-of-$M$ consensus vote operates in parallel across all five methods; the sequential ordering provides interpretable diagnostics at each stage.}
71	\label{fig:consensus_workflow}
72	\end{figure}
73	
74	\paragraph{Practical guidance.}
75	The consensus thresholds $(K, S)$ should be chosen to match the analyst's tolerance for false positives versus false negatives.
76	Table~\ref{tab:practical_guidance} provides four recommended tiers, calibrated against our experimental controls (\S\ref{sec:calibration}).
77	Tier~3 ($K{\geq}4/5$, $S{\geq}3/4$) achieves the best trade-off under the full 5-method panel: zero false positives while recovering all six reference pairs; however, threshold onset's near-zero power at $3\sigma$ (\S\ref{sec:threshold_limitation}) makes it near-inoperative, and Toda--Yamamoto provides moderate supplementary signal (3--4/8 at $\alpha{\geq}0.50$; \S\ref{sec:ty_limitation}), making $K{\geq}3$ the operationally relevant consensus threshold.
78	With four contributing methods (three primary plus TY), $K{\geq}3$ draws on a broader evidence base than the three primary methods alone; TY's moderate detection at $\alpha{\geq}0.50$ strengthens consensus conclusions where it contributes a positive vote.
79	Cross-architecture validation confirms $K{\geq}3$ reaches ${\geq}6/8$ in 10 of 14 architecture-seed combinations (\S\ref{sec:generalization}).
80	Method subset ablation confirms that this threshold is uniquely optimal: at $K{=}3/5$, the null-control FPR is 37.5\% (unacceptable); at $K{=}4/5$, FPR drops to 0\% while retaining 6/6 reference-pair sensitivity; at $K{=}5/5$, FPR remains 0\% but sensitivity falls to 3/6.
81	Shapley value analysis (exact enumeration of all 32 coalitions; Figure~\ref{fig:shapley}) identifies naive cross-correlation as the sole positive contributor to FPR (Shapley(FPR)${=}{+}0.348$) and permutation Granger as the strongest FPR suppressor (Shapley(FPR)${=}{-}0.194$), the only method combining 0\% null-control FPR with high sensitivity.
82	Toda--Yamamoto's Shapley contribution (FNR${=}{-}0.158$) reflects moderate supplementary value: it reduces consensus FNR without introducing false positives (\S\ref{sec:ty_limitation}).
83	
84	\begin{figure}[t]
85	\centering
86	\includegraphics[width=\linewidth]{figures/shapley_method_contribution.pdf}
87	\caption{Shapley value decomposition of method contributions to consensus FPR and FNR (exact enumeration of all $2^5{=}32$ coalitions, $K{=}\max(1,|S|{-}1)$). FPR is computed at $\alpha{=}0.0$ (3~seeds $\times$ 8~pairs${=}$24 observations); FNR at $\alpha{=}1.0$ (4~seeds, 6 reference pairs). Naive cross-correlation is the only positive FPR contributor (${+}0.348$); permutation Granger is the strongest FPR suppressor (${-}0.194$). Toda--Yamamoto contributes moderate FNR suppression (Shapley FNR${=}{-}0.158$) as a supplementary method (\S\ref{sec:ty_limitation}).}
88	\label{fig:shapley}
89	\end{figure}
90	Tier~4 requires unanimity across methods and seeds, which incurs elevated false negative rates; TY's moderate detection (3--4/8) means that requiring $5/5$ unanimity is substantially more restrictive than $4/5$, particularly at intermediate contamination levels where TY may not contribute a positive vote.
91	
92	\begin{table}[t]
93	\centering
94	\small
95	\caption{Practical guidance tiers for lead-lag consensus analysis. Tier~3 ($K{\geq}4/5$, $S{\geq}3/4$) is uniquely optimal under the full 5-method panel; with threshold onset power-limited (\S\ref{sec:threshold_limitation}) and Toda--Yamamoto providing moderate supplementary signal (\S\ref{sec:ty_limitation}), $K{\geq}3$ draws on four contributing methods. FPR is calibrated at $\alpha{=}0.0$ (null control, $M{=}5$ methods, $N{=}3$ seeds, Pythia-410M). FNR is calibrated at $\alpha{=}1.0$ against 6 effect-size reference pairs using a 4-method panel (excluding differenced cross-correlation); $N{=}4$ seeds (\S\ref{sec:calibration}).}
96	\label{tab:practical_guidance}
97	\begin{tabular}{llcccc}
98	\toprule
99	Tier & Use Case & $K/M$ & $S/N$ & FPR & FNR \\
100	\midrule
101	1 & Exploratory     & ${\geq}1/5$ & ${\geq}1/N$ & 100\%  & 0\%    \\
102	2 & Screening       & ${\geq}3/5$ & ${\geq}2/N$ & 37.5\% & 0\%    \\
103	3 & Confirmatory    & ${\geq}4/5$ & ${\geq}3/N$ & 0\%    & 0\%    \\
104	4 & Conservative    & $5/5$       & $N/N$        & 0\%    & 50\% \\
105	\bottomrule
106	\end{tabular}
107	\end{table}
108	
109	
110	\subsection{Empirical Calibration}
111	\label{sec:calibration}
112	
113	We calibrate the framework using two built-in experimental controls.
114	Full numerical results are reported in Table~\ref{tab:fpr_fnr}.
115	
116	\paragraph{False positive rate.}
117	The $\alpha{=}0.0$ condition serves as a null control: no synthetic data is injected, so any detected lead-lag association is a false positive.
118	At $K{=}1$ (any single method suffices), FPR${=}$75\%: naive cross-correlation flags 6/8 forward-direction pairs.
119	At $K{=}2$, FPR drops to ${\leq}$37.5\%; at $K{=}3$, to ${\leq}$12.5\%; and at $K{\geq}4$, FPR${=}$0\%.
120	The consensus framework at Tier~3 matches the false positive performance of the best individual method (permutation Granger, 0\%) while providing robustness against miscalibration of any single method.
121	
122	\paragraph{False negative rate.}
123	At $\alpha{=}1.0$ with 4~seeds, we define six \emph{effect-size reference pairs} using criteria independent of the consensus methods:
124	\begin{enumerate}
125	    \item[(a)] The canary$\to$downstream drift ratio at $\alpha{=}1.0$ must exceed $3\times$ the $\alpha{=}0.0$ baseline drift (canary ratios: entropy $11.93\times$, ECE $73.12\times$, both far above threshold); and
126	    \item[(b)] Canary onset must strictly precede downstream onset by at least one generation (canary onset: generation~1; diversity onset: generations~3--9).
127	\end{enumerate}
128	These criteria yield token entropy and ECE each predicting distinct-1, distinct-2, and distinct-3~\cite{li2016diversity}.
129	The perplexity channel is excluded because its onset (generation~1) coincides with canary onset, consistent with, but not derived from, the differencing diagnostic finding that canary$\to$perplexity associations are spurious (\S\ref{sec:method_sensitivity}).
130	The effect-size threshold is robust: at $2\times$, $3\times$, and $5\times$ the baseline drift, the reference set remains identical (6~pairs), because canary ratios ($11.93\times$ and $73.12\times$) far exceed all thresholds.
131	
132	FNR is calibrated using a 4-method panel excluding differenced cross-correlation, which shares statistical properties with detrending-based criteria and could introduce circularity.
133	At $K{\geq}3/4$, $S{\geq}3/4$, all six reference pairs are recovered (FNR${=}$0\%).
134	At $K{=}4/4$, $S{=}4/4$, FNR rises to 50\%, reflecting TY's moderate detection power (4/8 at $\alpha{=}1.0$; \S\ref{sec:ty_limitation}).
135	
136	\paragraph{Symmetric calibration.}
137	Both FPR and FNR are validated on the joint method${\times}$seed dimension: FPR across 3~seeds at $\alpha{=}0.0$ (0/24 pairs at $K{\geq}3$, $3\sigma$) and FNR across 4~seeds at $\alpha{=}1.0$ (6/6 reference pairs recovered at $K{\geq}3/4$, $S{\geq}3/4$).
138	Cross-seed FPR variance is negligible: all three null-control seeds yield 0/8 robust pairs at $K{\geq}3$ ($3\sigma$), confirming seed-independent performance.
139	
140	
141	\paragraph{Threshold onset detection: power limitations at $3\sigma$.}
142	\label{sec:threshold_limitation}
143	Post-hoc validation of the threshold onset implementation (M028) revealed that the published $2\sigma$ calibration was mislabeled as $3\sigma$.
144	Under corrected $3\sigma$ calibration, threshold onset yields 0/8 significant pairs in 8 of 12 cross-architecture conditions (Table~\ref{tab:generalization}) and at most 2/8 in the remainder, reducing it to a near-zero-power method at $T{=}11$ generations; any threshold onset detections should therefore be interpreted as lower-bound estimates.
145	This low power is expected: with only 10 generation-over-generation differences, the null variance estimate has few degrees of freedom, and a $3\sigma$ exceedance threshold becomes overly conservative.
146	We retain threshold onset as a supplementary method for completeness and report its results transparently, but adopt permutation Granger forward significance as the primary detection indicator in cross-architecture analyses.
147	
148	\paragraph{Toda--Yamamoto Granger: moderate supplementary signal.}
149	\label{sec:ty_limitation}
150	Post-hoc analysis identified a statsmodels API incompatibility that initially produced artificially low Toda--Yamamoto detection rates.
151	After correcting the implementation, TY achieves moderate detection: 3/8 forward-direction pairs at $\alpha{=}0.50$ (seed~42), 3/8 at $\alpha{=}0.75$, and 4/8 at $\alpha{=}1.0$ (Table~\ref{tab:method_comparison}).
152	These rates are lower than permutation Granger (6--8/8) but confirm that TY captures genuine signal at $\alpha{\geq}0.50$, consistent with the method's theoretical motivation~\cite{toda1995statistical}.
153	TY is classified as a moderate supplementary method: it contributes to the consensus panel but does not serve as a primary detection indicator due to reduced statistical power at $T{=}11$ (the augmentation order $d_{\max}$ consumes additional degrees of freedom) and sensitivity to the $d_{\max}$ hyperparameter (Figure~\ref{fig:differencing_dmax}b).
154	With TY providing moderate signal, the consensus panel comprises four contributing methods (three primary plus TY as supplementary), strengthening the $K{\geq}3$ threshold: at $\alpha{=}0.50$ (seed~42), $K{\geq}3$ rises from 5/8 to 6/8 with TY's corrected contribution.
155	At $\alpha{\geq}0.50$, $K{\geq}4$ consensus (4 of 5 methods agree) emerges in 3/8 pairs, demonstrating that multi-method agreement extends beyond the primary trio.
156	
157	\subsection{Multi-Method Consensus Test (MMCT)}
158	\label{sec:mmct}
159	
160	The uniform threshold ($K{\geq}4/5$) achieves FPR${=}$0\% and FNR${=}$0\% on reference extremes (\S\ref{sec:calibration}), but this ad-hoc threshold lacks formal statistical grounding: null-calibrated permutation testing assigns $p{=}0.16$ to $K{\geq}4/5$, failing to reach significance at conventional levels.
161	The threshold also treats all methods equally, despite the heterogeneous error profiles documented in \S\ref{sec:pitfalls}: naive cross-correlation has 75\% forward-direction null-control FPR while permutation Granger has 0\%.
162	We formalize the \emph{Multi-Method Consensus Test} (MMCT), a weighted consensus framework that assigns each method influence proportional to its empirical specificity, following the specification curve tradition~\cite{simonsohn2020specification} in which analytical choices are systematically varied and aggregated rather than arbitrarily fixed~\cite{bell2022modeling}.
163	MMCT serves as an evaluation framework rather than an end in itself: its primary function is to enable systematic comparison of detection methods under controlled conditions, identifying which individual methods are reliable and why others fail.
164	We do not claim a novel statistical method; MMCT is a consensus testing protocol adapted to the specific constraints of iterative training analysis: short series ($T{=}5$--$20$), non-stationarity by design, and heterogeneous method sensitivities.
165	
166	\paragraph{FPR-inverse weighting.}
167	Let $\hat{\text{FPR}}_k$ denote the empirical false positive rate of method $m_k$, estimated from $N_0$ null-control observations at $\alpha{=}0.0$ across $S$ seeds.
168	Each method receives weight
169	\begin{equation}
170	    w_k = \frac{1}{\max(\hat{\text{FPR}}_k,\; \epsilon)},
171	    \label{eq:fpr_weight}
172	\end{equation}
173	where $\epsilon{=}0.01$ prevents division by zero.
174	Methods with low FPR (e.g., permutation Granger at 0\%, receiving $w_k{=}100$) dominate the consensus; methods with high FPR (e.g., naive cross-correlation at 75\%, receiving $w_k{\approx}1.3$) are effectively downweighted.
175	
176	\paragraph{Consensus score.}
177	Given $M$ methods that return binary decisions $d_k \in \{0, 1\}$ (FDR-significant or not) for a candidate pair $(X, Y)$, the weighted consensus score is:
178	\begin{equation}
179	    W(X \to Y) = \frac{\sum_{k=1}^{M} w_k \cdot d_k}{\sum_{k=1}^{M} w_k}.
180	    \label{eq:consensus_score}
181	\end{equation}
182	When all weights equal~1 (uniform mode), $W$ reduces to $K/M$, and thresholding at $W \geq 4/5$ recovers the uniform $K{\geq}4$ rule exactly.
183	
184	\paragraph{Statistical testing.}
185	The null distribution of $W$ is estimated from the $\alpha{=}0.0$ control condition, where no synthetic contamination is present and any detected lead-lag association is a false positive.
186	The $N_0$ null-control pairs yield a reference distribution $\{W_0^{(j)}\}_{j=1}^{N_0}$, and the MMCT $p$-value is:
187	\begin{equation}
188	    p_{\text{MMCT}} = \frac{|\{j : W_0^{(j)} \geq W_{\text{obs}}\}|}{N_0}.
189	    \label{eq:pvalue}
190	\end{equation}
191	We reject the null of no lead-lag relationship at significance level $\alpha_{\text{test}}$.
192	
193	\paragraph{Bidirectional filtering.}
194	MMCT tests both directions independently: $W(X \to Y)$ and $W(Y \to X)$.
195	A stricter bidirectional mode requires forward significance with reverse non-significance.
196	Empirically, bidirectional and forward-only detection rates are identical across all contamination levels tested, indicating that pairs reaching weighted consensus in the forward direction consistently fail to reach consensus in reverse.
197	We therefore adopt forward-only (weighted pair forward) as the default MMCT configuration.
198	Algorithm~\ref{alg:mmct} summarizes the procedure.
199	
200	\begin{algorithm}[t]
201	\caption{Multi-Method Consensus Test (MMCT)}
202	\label{alg:mmct}
203	\begin{algorithmic}[1]
204	\Require Methods $\{m_1, \ldots, m_M\}$; pair $(X, Y)$; null pairs $\{(X_0^{(j)}, Y_0^{(j)})\}_{j=1}^{N_0}$; floor $\epsilon$; level $\alpha_{\text{test}}$
205	\Ensure Decision $d$, score $W$, $p$-value
206	\Statex \textbf{Phase 1: Estimate weights from null control}
207	\For{$k = 1, \ldots, M$}
208	    \State $\hat{\mathrm{FPR}}_k \gets$ null-control rejection rate of $m_k$
209	    \State $w_k \gets 1 / \max(\hat{\mathrm{FPR}}_k, \epsilon)$
210	\EndFor
211	\Statex \textbf{Phase 2: Compute weighted consensus}
212	\For{$k = 1, \ldots, M$}
213	    \State $d_k \gets m_k(X, Y)$ \Comment{1 if FDR-significant}
214	\EndFor
215	\State $W \gets \sum_k w_k d_k \;/\; \sum_k w_k$
216	\Statex \textbf{Phase 3: Null-distribution $p$-value}
217	\For{$j = 1, \ldots, N_0$}
218	    \State $W_0^{(j)} \gets$ consensus score of $(X_0^{(j)}, Y_0^{(j)})$
219	\EndFor
220	\State $p \gets |\{j : W_0^{(j)} \geq W\}| / N_0$
221	\State \Return $\mathbb{1}[p < \alpha_{\text{test}}]$, $W$, $p$
222	\end{algorithmic}
223	\end{algorithm}
224	
225	\paragraph{Empirical comparison.}
226	Table~\ref{tab:mmct_ablation} compares per-method detection rates across contamination levels, revealing the systematic comparison that motivates our method recommendation.
227	The five methods exhibit sharply divergent dose-response profiles: naive cross-correlation maintains elevated FPR at the null (75\%) but rises to 87.5\% at $\alpha{=}0.75$; differenced cross-correlation achieves zero null-control FPR but detects in both forward and reverse directions, failing to provide directional separation; threshold onset detects only at $\alpha{=}0.50$ (50\%) and returns to zero at $\alpha{=}0.75$ under $3\sigma$ calibration; Toda--Yamamoto achieves moderate detection at $\alpha{\geq}0.50$ (37.5\%) with zero null-control FPR but lower sensitivity than permutation Granger.
228	Permutation Granger alone provides the cleanest dose-response profile, with a sharp step function from 0/8 (blind spot, $\alpha{\leq}0.45$) to 6/8 (onset, $\alpha{=}0.50$, dual-seed confirmed) and reliable detection at $\alpha{\geq}0.75$ (Table~\ref{tab:method_comparison}; \S\ref{sec:regime}).
229	
230	Permutation Granger produces binary per-pair verdicts that yield a near-discontinuous onset of detection: a faint signal at $\alpha{=}0.25$ (best pair FDR $p{=}0.053$) that does not reach aggregate detection through $\alpha{=}0.45$, then an abrupt jump to 6/8 at $\alpha{=}0.50$ (fp32), with a non-monotonic dip at $\alpha{=}0.60$ (s42: 3/8, s43: 0/8; dual-seed confirmed synchronous collapse zone; \S\ref{sec:regime}).
231	This step-function profile, combined with zero null-control FPR and Shapley FPR suppression of $-0.194$, identifies PermG as the recommended individual detection method.
232	Cross-architecture validation confirms PermG fwd ${\geq}6/8$ in 12 of 14 conditions, with multi-method consensus ($K{\geq}3$) reaching ${\geq}6/8$ in 10 of 14 (\S\ref{sec:generalization}).
233	MMCT weighted consensus further captures graded detection strength even where individual methods remain below threshold, providing formal $p$-values that the uniform $K$-of-$M$ threshold lacks; however, the systematic comparison reveals that PermG alone provides comparable or superior detection to the full consensus framework at all contamination levels tested.
234	With TY contributing as a fourth method, full 5/5 consensus becomes achievable: at $\alpha{=}0.50$ (seed~42), the ECE$\to$distinct-3 pair reaches significance across all five methods, demonstrating that the consensus panel can converge unanimously even near the onset boundary when the canary--downstream coupling is strong.
235	
236	\begin{table}[t]
237	\centering
238	\small
239	\caption{Per-method forward-direction detection rates across contamination levels (Pythia-410M, seed~42, fp32). Each cell reports the fraction of 8 canary$\to$downstream pairs reaching BH-corrected significance ($q{=}0.05$). Per-method dose-response reveals the systematic comparison that identifies PermG as the recommended method (\S\ref{sec:case_study}). Cross-condition results at $\alpha{=}1.0$ are reported in Table~\ref{tab:mmct_cross}. $^\dagger$Moderate supplementary method (\S\ref{sec:ty_limitation}); FPR$_\text{null}$ pending (null condition not yet run through corrected pipeline).}
240	\label{tab:mmct_ablation}
241	\begin{tabular}{lcccc}
242	\toprule
243	Method & FPR$_\text{null}$ & $\alpha{=}0.25$ & $\alpha{=}0.50$ & $\alpha{=}0.75$ \\
244	\midrule
245	Naive XCorr              & 75   & 12.5 & 37.5 & 87.5 \\
246	Diff.\ XCorr             & 0    & 37.5 & 87.5 & 75   \\
247	Threshold ($3\sigma$)    & ---  & 0    & 50   & 0    \\
248	Perm.\ Granger           & 0    & 0    & 75   & 75   \\
249	Toda--Yamamoto$^\dagger$ & ---  & 0    & 37.5 & 37.5 \\
250	\bottomrule
251	\end{tabular}
252	\end{table}
253	
254	\paragraph{Backward compatibility.}
255	Setting all weights $w_k{=}1$ reduces MMCT to the uniform $K$-of-$M$ threshold, making the existing consensus framework (\S\ref{sec:consensus}) a special case.
256	Descriptively, $K{\geq}4/5$ achieves FPR${=}$0\% and FNR${=}$0\% on reference extremes (\S\ref{sec:calibration}); however, null-calibrated testing assigns $p{=}0.16$ to this threshold, indicating that it does not reach conventional significance levels.
257	MMCT weighted consensus resolves this gap by providing formal $p$-values (Eq.~\ref{eq:pvalue}) grounded in the empirical null distribution.
258	
259	\paragraph{Cross-condition stability.}
260	Table~\ref{tab:mmct_cross} reports MMCT weighted consensus across all seven experimental conditions at $\alpha{=}1.0$.
261	Detection ranges from 4/8 to 8/8 while FPR remains 0 at the null control across all conditions, confirming that FPR-inverse weighting generalizes beyond the calibration setup.
262	GPT-2-medium achieves the highest detection rate (8/8), consistent with its stronger per-method signal, demonstrating that MMCT's FPR-inverse weighting extracts graded detection strength that binary per-method verdicts miss.
263	
264	\begin{table}[t]
265	\centering
266	\small
267	\caption{MMCT weighted forward consensus across experimental conditions ($\alpha{=}1.0$, FPR-inverse weighting). Each cell reports significant canary$\to$downstream pairs out of 8 (2~canaries $\times$ 4~downstream metrics). All conditions maintain FPR${=}$0 at $\alpha{=}0.0$. Values may be updated pending parameter consistency verification.}
268	\label{tab:mmct_cross}
269	\begin{tabular}{lc}
270	\toprule
271	Condition & Sig / 8 \\
272	\midrule
273	Baseline (Pythia-410M / Wiki)     & 5/8 \\
274	Architecture: GPT-2-medium / Wiki & \textbf{8/8} \\
275	Architecture: OPT-1.3B / Wiki     & 5/8 \\
276	Scale: Pythia-1.4B / Wiki (s42)   & 4/8 \\
277	Scale: Pythia-1.4B / Wiki (s43)   & 4/8 \\
278	Domain: Pythia-1B / C4 (s42)      & 5/8 \\
279	Domain: Pythia-1B / C4 (s43)      & 4/8 \\
280	\bottomrule
281	\end{tabular}
282	\end{table}
283	
284	\subsection{Theoretical Motivation: Why Entropy Leads Diversity}
285	\label{sec:theory}
286	
287	The empirical lead-lag relationship between token entropy and lexical diversity (\S\ref{sec:regime}) admits a simple theoretical motivation grounded in the distinct mathematical properties of continuous and discrete summary statistics.
288	We present three arguments that, taken together, predict the observed temporal ordering and its dependence on contamination strength.
289	These arguments provide intuition rather than formal proof; the dose-response experiments in \S\ref{sec:regime} test the resulting predictions empirically.
290	
291	\paragraph{Continuous versus discrete response.}
292	Token entropy $H(p_t^{(g)}) = -\sum_v p_v \log p_v$ is a continuous functional of the token distribution $p_t^{(g)}$ at generation $g$: any infinitesimal shift in $p_t^{(g)}$ produces a proportional change in $H$.
293	Distinct-$n$ diversity $D_k^{(g)}$, by contrast, is a counting statistic.
294	An $n$-gram contributes to $D_k^{(g)}$ only when its probability exceeds an effective sampling threshold $\tau_n \approx 1/N$, where $N$ is the number of generated tokens.
295	Below $\tau_n$, the $n$-gram is absent from finite samples regardless of its true probability.
296	$D_k^{(g)}$ therefore responds to distributional change in discrete steps: it remains constant while probabilities drift within the interval above $\tau_n$, then drops abruptly when a probability crosses the threshold.
297	Because $H$ tracks every distributional perturbation while $D_k^{(g)}$ remains silent until a threshold crossing occurs, entropy is sensitive to distributional change strictly before diversity registers it.
298	
299	\paragraph{Predicted detectability regimes.}
300	The continuous-versus-discrete asymmetry determines not just the ordering of responses but the \emph{detectability} of their temporal offset.
301	We model Granger-type detectability as the product of two competing factors:
302	\begin{equation}
303	    \text{Detectability}(\alpha) \;\propto\; S(\alpha) \times R(\alpha),
304	    \label{eq:detectability}
305	\end{equation}
306	where $S(\alpha)$ is the \emph{signal strength} (the magnitude of distributional shift induced by contamination) and $R(\alpha)$ is the \emph{temporal resolution} (the generational gap between the entropy response and the diversity response).
307	
308	$S(\alpha)$ increases monotonically with $\alpha$: more synthetic data induces larger distributional shifts.
309	$R(\alpha)$, by contrast, is non-monotonic.
310	At low $\alpha$, entropy and diversity respond in different generations ($R$ large); at a critical intermediate $\alpha$, \emph{relaxation time matching} occurs---the perturbation strength aligns the entropy and diversity relaxation times so that both metrics shift within the same generation, driving $R \to 0$.
311	At high $\alpha$, the perturbation is severe enough that entropy collapses within generation~0$\to$1 (the continuous-functional advantage saturates immediately), while diversity still requires generation~1$\to$2 to fully manifest the loss---tail $n$-grams near $\tau_n$ persist temporarily before crossing the threshold---and the one-generation lead recovers ($R$ large again).
312	
313	The competition between $S$ and $R$ predicts four regimes:
314	\begin{enumerate}
315	\item \textbf{Blind} ($\alpha \leq 0.45$).
316	$S$ falls below the detection floor; $S \times R \approx 0$ regardless of $R$.
317	\item \textbf{Onset} ($\alpha \approx 0.50$).
318	$S$ crosses the detection threshold while $R$ remains high (entropy leads diversity by a full generation); $S \times R$ is sufficient for detection.
319	Between the blind and onset regimes, the framework predicts a \emph{canary-only window} in which entropy shifts detectably but no $n$-grams have yet crossed $\tau_n$; we lack the $\alpha$ resolution to confirm this (our grid jumps from $0.25$ to $0.50$) and leave verification to future work with finer spacing in $[0.10, 0.45]$.
320	\item \textbf{Synchronous dip} ($\alpha \approx 0.60$).
321	$S$ continues increasing, but $R$ drops sharply: relaxation time matching at this $\alpha$ compresses the entropy--diversity lag to near zero, producing a local minimum in $S \times R$.
322	\item \textbf{Detection} ($\alpha \geq 0.75$).
323	$S$ grows large enough to dominate the product despite reduced $R$; the continuous-functional advantage reasserts across generations, and $S \times R$ recovers.
324	\end{enumerate}
325	These four regimes align with the empirical dose-response (\S\ref{sec:regime}): blind at $\alpha{\leq}0.45$ (PermG 0/8), onset at $\alpha{=}0.50$ (6/8, dual-seed), synchronous dip at $\alpha{=}0.60$ (0--3/8, dual-seed), and detection at $\alpha{\geq}0.75$ (5--6/8 per seed, three seeds; 6/8 per seed at $\alpha{=}1.0$, four seeds).
326	The non-monotonic profile is a prediction of the $S \times R$ framework, not an anomaly requiring post-hoc explanation; indeed, non-monotonic dose-response curves are well-documented across disciplines.
327	The four-regime profile mirrors the hormetic dose-response in toxicology, where intermediate doses produce qualitatively different effects from both low and high doses~\cite{calabrese2003hormesis}.
328	The temporal resolution collapse at intermediate $\alpha$ ($R \to 0$) corresponds to the known failure of Granger-type tests under contemporaneous coupling~\cite{deshpande2010instantaneous}: when entropy and diversity shift within the same generation (lag${=}0$), the causal test loses statistical power by construction, not by methodological deficiency.
329	The detection dip is also consistent with critical speeding-up phenomena in ecological regime shifts, where early-warning indicators exhibit non-monotonic behavior near phase boundaries rather than the monotonic rise predicted by classical critical slowing down~\cite{titus2020speeding}.
330	We emphasize that the $S \times R$ model provides qualitative intuition, not quantitative derivation; the regime boundaries depend on model capacity, dataset properties, and sample size $N$.
331	
332	\paragraph{Detection threshold vs.\ accumulated contamination.}
333	The detection phase transition at $\alpha_c{=}0.476$ (\S\ref{sec:regime}) reveals that Granger detectability depends on the \emph{per-generation} mixing ratio $\alpha$, not on cumulative contamination.
334	After $G{=}10$ generations, cumulative synthetic fraction reaches $C(\alpha, G) = 1 - (1{-}\alpha)^G$: at $\alpha{=}0.45$, $C = 99.75\%$; at $\alpha{=}0.50$, $C = 99.90\%$---a difference of 0.15 percentage points---yet PermG detection jumps from 0/8 to 6/8.
335	The explanation lies in the per-generation signal.
336	PermG detects temporal lead-lag from the time series of inter-generation entropy shifts $\{\Delta h^{(g)}\}_{g=1}^G$, where $\Delta h^{(g)} \propto \alpha \cdot d_{\mathrm{TV}}(p_g^{\mathrm{model}}, p^{\mathrm{real}})$ captures the per-episode perturbation scaled by the distributional gap at generation~$g$.
337	The critical threshold $\alpha_c$ corresponds to the per-generation signal-to-noise ratio crossing the detection floor: below $\alpha_c$, each episode's signal is too faint for the Granger test to distinguish from noise at $T{=}11$, regardless of how many episodes accumulate.
338	This overturns the implicit assumption in data poisoning research that detection difficulty scales with total contamination; our results show that two training runs with nearly identical cumulative exposure ($99.75\%$ vs.\ $99.90\%$) produce categorically different detection outcomes.
339	
340	\paragraph{Connection to effective rank and detection layers.}
341	The link between entropy and diversity can be made more concrete through effective rank~\cite{roy2007effective}: $\mathrm{erank}(P) = \exp(H(P / \|P\|_1))$ measures the number of dimensions carrying substantial probability mass.
342	A decline in $H$ contracts $\mathrm{erank}(P)$, pushing tail tokens below $\tau_n$ and eliminating the $n$-grams they participate in.
343	This yields a mechanistic chain---$H$ decreases $\to$ $\mathrm{erank}$ contracts $\to$ tail probabilities cross $\tau_n$ $\to$ $D_k^{(g)}$ drops---in which entropy responds first.
344	This chain mediates the temporal resolution factor $R(\alpha)$: at intermediate $\alpha$ (${\approx}0.60$), relaxation time matching compresses the erank-mediated cascade into a single generation ($R \to 0$); at higher $\alpha$, the severity of entropy collapse outpaces the cascade, restoring the generational offset ($R$ large; \S\ref{sec:regime}).
345	
346	Effective rank is a \emph{distributional dimensionality} indicator---it detects contraction of the distribution's effective degrees of freedom---and is conceptually distinct from both distributional instability (variance inflation) and classical critical slowing down (CSD) indicators (rising autocorrelation) that characterize dynamical stability near tipping points~\cite{scheffer2009early,dakos2012methods}.
347	These layers, together with the causal coupling layer captured by Granger-type tests, form four complementary detection channels ordered by onset threshold (\S\ref{sec:discussion}).
348	The distinction matters because the layers can diverge: \citet{truong2025entropy} show that entropy collapse can be a first-order phase transition under convex feedback dynamics, in which CSD indicators remain bounded before the critical point and provide no advance warning.
349	In such regimes, distributional dimensionality may register contraction before dynamical indicators respond---or, as our experiments show (\S\ref{sec:case_study}), may fail entirely in an architecture-dependent manner.
350	
351	\paragraph{Phase transition theory and the onset boundary.}
352	The onset at $\alpha{\approx}0.50$---quantified empirically as $\alpha_c{=}0.476$ via sigmoid regression (\S\ref{sec:regime})---may reflect a critical mixing threshold analogous to the scaling law of \citet{gu2024cmr} for continual pre-training.
353	The non-monotonic dip at $\alpha{=}0.60$ (\S\ref{sec:regime}) is consistent with the two universality classes of \citet{truong2025entropy}: if the transition is first-order (Class~1, irreversible, exponent $\nu{=}1$), the abrupt simultaneous shift in canary and downstream metrics suppresses the temporal lead that Granger tests exploit, while smoother second-order dynamics (Class~2, reversible, $\nu{=}1/2$) at neighboring $\alpha$ values preserve it.
354	These connections are speculative and require finer $\alpha$ resolution and direct estimation of feedback nonlinearity to validate.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "5fedf337-8bf6-4a4b-962b-1b09dac37bbc",
  "isSidechain": false,
  "promptId": "0bc1eef6-835a-4ee4-a8a1-06010792cb3b",
  "type": "user",
  "uuid": "1e5ede98-de7b-434a-9094-f7720da5b1da",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/method.tex",
      "content": "\\section{Method}\n\\label{sec:method}\n\nThe experiments in \\S\\ref{sec:method_sensitivity}--\\ref{sec:consensus_validation} reveal that lead-lag conclusions in iterative training collapse are fragile along multiple axes.\nThis section distills three methodological pitfalls (\\S\\ref{sec:pitfalls}), proposes a multi-method consensus framework to quantify their impact and identify the most reliable individual method (\\S\\ref{sec:consensus}), and calibrates the framework's error rates using built-in experimental controls (\\S\\ref{sec:calibration}).\n\n\n\\subsection{Methodological Pitfalls in Lead-Lag Analysis}\n\\label{sec:pitfalls}\n\nWe identify three pitfalls that, individually or in combination, can produce incorrect conclusions about temporal precedence in iterative training systems.\nEach is documented below with representative data from our experiments; full results appear in \\S\\ref{sec:experiments}.\n\n\\paragraph{Pitfall 1: Method sensitivity.}\nApplied to the same data ($\\alpha{=}1.0$, 4~seeds, 16 canary$\\to$downstream pairs: 4 candidate canaries $\\times$ 4 downstream metrics, including candidates later excluded per \\S\\ref{sec:case_study}), five lead-lag detection methods yield FDR significance rates ranging from 100\\% (naive cross-correlation) to 37.5\\% (permutation Granger), with Toda--Yamamoto achieving moderate rates (3--4/8 at $\\alpha{\\geq}0.50$); inter-method agreement is Cohen's $\\kappa{=}0.185$, indicating poor agreement (\\S\\ref{sec:method_sensitivity}).\nThe spurious-signal rate (the fraction of pairs flagged by the most liberal method but not confirmed by the most conservative) is at least 62.5\\% across the primary methods.\nThis pitfall is dangerous because method choice alone can determine whether a lead-lag relationship is deemed present or absent.\nIn a literature where single-method analyses are the norm, the implicit assumption that method choice does not matter is demonstrably false.\n\n\\paragraph{Pitfall 2: Spurious regression under shared trends.}\nA single preprocessing decision, first-differencing to remove shared non-stationary trends~\\cite{granger1974spurious}, can eliminate an entire analysis channel.\nAt $\\alpha{=}1.0$, canary$\\to$perplexity pairs appear near-universally significant in undifferenced analysis ($F{=}16$--$36$) but yield $F{\\approx}0$, $p{=}0.99$ after differencing (Figure~\\ref{fig:differencing_dmax}a; \\S\\ref{sec:method_sensitivity}).\nIn contrast, canary$\\to$diversity pairs retain unanimous FDR significance after differencing (24/24$\\to$24/24).\nWithout the differencing diagnostic, an analyst would conclude that canaries predict perplexity, a conclusion entirely driven by co-trending rather than temporal precedence.\nThe danger lies in the selective nature of this confound: only by applying the diagnostic can one determine which channels are genuine and which are artifacts of shared non-stationarity.\n\n\\paragraph{Pitfall 3: Regime dependence.}\nEven after fixing the statistical method, the contamination level~$\\alpha$ determines whether a lead-lag relationship is detectable.\nPermutation Granger tests (first-differenced, BH FDR-corrected at $q{=}0.05$) find 6/8 pairs FDR-significant at both $\\alpha{=}0.50$ (2~fp32 seeds, consistent) and $\\alpha{=}1.0$, but 0/8 through $\\alpha{=}0.45$ (\\S\\ref{sec:regime}).\nThe transition zone at $\\alpha{\\approx}0.45$--$0.50$ is where method divergence is most dangerous: correlation-based methods find significance across all levels while causal methods remain null through $\\alpha{=}0.45$ (a faint single-pair signal appears at $\\alpha{=}0.25$, FDR $p{=}0.053$, but does not reach aggregate detection), creating the maximum risk of spurious conclusions when only a single (liberal) method is used.\nThis regime dependence is consistent with theoretical expectations about signal-to-noise limits in short ecological time series \\cite{boettiger2012limits}, and suggests that detectability boundaries should be explicitly mapped rather than assumed.\n\n\n\\subsection{Multi-Method Consensus Framework}\n\\label{sec:consensus}\n\nThe pitfalls above motivate a multi-method consensus approach inspired by specification curve analysis \\cite{simonsohn2020specification} and multi-method validation in early-warning signal detection \\cite{scheffer2009early}: rather than relying on any single method, we apply multiple independent methods to quantify how analytic choices determine conclusions, using agreement thresholds as diagnostic benchmarks.\n\n\\paragraph{Formal definition.}\nGiven $M$ lead-lag detection methods $\\{m_1, \\ldots, m_M\\}$ and $N$ independent random seeds, a canary$\\to$downstream pair $(X, Y)$ is classified as \\textsc{robust} if and only if:\n\\begin{enumerate}\n    \\item At least $K$ of $M$ methods judge the pair FDR-significant, where each method independently applies Benjamini--Hochberg correction at $q{=}0.05$; and\n    \\item At least $S$ of $N$ seeds replicate this conclusion.\n\\end{enumerate}\nThe thresholds $(K, S)$ control the trade-off between false positive and false negative rates.\nMethods with different inductive biases (correlation-based methods that detect any temporal association versus Granger-type methods that test directional predictive improvement \\cite{granger1969investigating}) provide complementary evidence.\nTheir convergence on a given pair constitutes stronger evidence than agreement among methods sharing the same statistical assumptions.\nWe note that Granger precedence establishes temporal predictive improvement, not true causality \\cite{shojaie2022granger}; our framework inherits this limitation.\n\n\\paragraph{Method tiering.}\nThe five methods are organized into two tiers based on empirical reliability.\nThree \\emph{primary} methods---naive cross-correlation, differenced cross-correlation, and permutation Granger causality---produce consistent results across independent analysis pipelines and exhibit adequate statistical power at $T{=}11$ generations.\nTwo methods are classified as \\emph{supplementary}: threshold onset detection due to power limitations at $T{=}11$ under corrected $3\\sigma$ calibration (\\S\\ref{sec:threshold_limitation}), and Toda--Yamamoto Granger causality, which achieves moderate detection (3--4/8 at $\\alpha{\\geq}0.50$) but with reduced power relative to the primary methods (\\S\\ref{sec:ty_limitation}).\nThe consensus panel thus comprises four contributing methods (three primary, one moderate supplementary), with threshold onset near-inoperative at $T{=}11$.\nThe consensus threshold $K{\\geq}3$ out of 5 methods requires agreement among at least the three primary methods or two primary methods plus TY, making $K{\\geq}3$ a \\emph{stronger} standard than a simple majority vote would suggest.\n\n\\paragraph{Sequential filtering pipeline.}\nIn practice, the $K$-of-$M$ voting operates over all five methods applied independently to each pair; the sequential pipeline below describes the order in which results are examined, enabling early termination and interpretable diagnostics at each stage (Figure~\\ref{fig:consensus_workflow}):\n\\begin{enumerate}\n    \\item \\textbf{Naive correlation scan.} Cross-correlation at maximum lag~5 with BH correction serves as a permissive baseline; all pairs with any temporal association pass.\n    \\item \\textbf{First-differencing diagnostic.} Cross-correlation is recomputed on first-differenced series, testing whether temporal associations survive removal of shared linear trends. Pairs that lose significance are flagged as potential spurious regressions.\n    \\item \\textbf{Permutation Granger causality.} Permutation-based Granger causality tests \\cite{shojaie2022granger} on first-differenced series (5{,}000 permutations, BH correction at $q{=}0.05$) assess directional predictive improvement: whether past values of $X$ improve prediction of $Y$ beyond $Y$'s own history.\n    \\item \\textbf{Multi-seed replication.} The conclusion must hold across $S$ of $N$ independent training seeds, filtering seed-specific artifacts.\n\\end{enumerate}\nAt $\\alpha{=}1.0$, this pipeline progressively filters: 16 pairs pass Stage~1, 14 survive Stage~2 (differencing removes 2 marginal canary$\\to$perplexity pairs), 6 survive Stage~3 (Granger testing eliminates remaining canary$\\to$perplexity pairs and failed canary candidates), and all~6 survive Stage~4 (multi-seed replication confirms all Granger-significant pairs).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\linewidth]{figures/consensus_workflow.pdf}\n\\caption{Sequential filtering pipeline of the multi-method consensus framework. Starting from all candidate canary$\\to$downstream pairs, the pipeline applies four stages: (1)~naive cross-correlation scan (permissive baseline), (2)~first-differencing diagnostic (removes shared-trend artifacts), (3)~permutation Granger causality (tests directional predictive improvement), and (4)~multi-seed replication (filters seed-specific artifacts). At $\\alpha{=}1.0$ (Pythia-410M), the pipeline reduces 16 candidate pairs to 6 robust pairs: 16$\\to$14$\\to$6$\\to$6. The $K$-of-$M$ consensus vote operates in parallel across all five methods; the sequential ordering provides interpretable diagnostics at each stage.}\n\\label{fig:consensus_workflow}\n\\end{figure}\n\n\\paragraph{Practical guidance.}\nThe consensus thresholds $(K, S)$ should be chosen to match the analyst's tolerance for false positives versus false negatives.\nTable~\\ref{tab:practical_guidance} provides four recommended tiers, calibrated against our experimental controls (\\S\\ref{sec:calibration}).\nTier~3 ($K{\\geq}4/5$, $S{\\geq}3/4$) achieves the best trade-off under the full 5-method panel: zero false positives while recovering all six reference pairs; however, threshold onset's near-zero power at $3\\sigma$ (\\S\\ref{sec:threshold_limitation}) makes it near-inoperative, and Toda--Yamamoto provides moderate supplementary signal (3--4/8 at $\\alpha{\\geq}0.50$; \\S\\ref{sec:ty_limitation}), making $K{\\geq}3$ the operationally relevant consensus threshold.\nWith four contributing methods (three primary plus TY), $K{\\geq}3$ draws on a broader evidence base than the three primary methods alone; TY's moderate detection at $\\alpha{\\geq}0.50$ strengthens consensus conclusions where it contributes a positive vote.\nCross-architecture validation confirms $K{\\geq}3$ reaches ${\\geq}6/8$ in 10 of 14 architecture-seed combinations (\\S\\ref{sec:generalization}).\nMethod subset ablation confirms that this threshold is uniquely optimal: at $K{=}3/5$, the null-control FPR is 37.5\\% (unacceptable); at $K{=}4/5$, FPR drops to 0\\% while retaining 6/6 reference-pair sensitivity; at $K{=}5/5$, FPR remains 0\\% but sensitivity falls to 3/6.\nShapley value analysis (exact enumeration of all 32 coalitions; Figure~\\ref{fig:shapley}) identifies naive cross-correlation as the sole positive contributor to FPR (Shapley(FPR)${=}{+}0.348$) and permutation Granger as the strongest FPR suppressor (Shapley(FPR)${=}{-}0.194$), the only method combining 0\\% null-control FPR with high sensitivity.\nToda--Yamamoto's Shapley contribution (FNR${=}{-}0.158$) reflects moderate supplementary value: it reduces consensus FNR without introducing false positives (\\S\\ref{sec:ty_limitation}).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\linewidth]{figures/shapley_method_contribution.pdf}\n\\caption{Shapley value decomposition of method contributions to consensus FPR and FNR (exact enumeration of all $2^5{=}32$ coalitions, $K{=}\\max(1,|S|{-}1)$). FPR is computed at $\\alpha{=}0.0$ (3~seeds $\\times$ 8~pairs${=}$24 observations); FNR at $\\alpha{=}1.0$ (4~seeds, 6 reference pairs). Naive cross-correlation is the only positive FPR contributor (${+}0.348$); permutation Granger is the strongest FPR suppressor (${-}0.194$). Toda--Yamamoto contributes moderate FNR suppression (Shapley FNR${=}{-}0.158$) as a supplementary method (\\S\\ref{sec:ty_limitation}).}\n\\label{fig:shapley}\n\\end{figure}\nTier~4 requires unanimity across methods and seeds, which incurs elevated false negative rates; TY's moderate detection (3--4/8) means that requiring $5/5$ unanimity is substantially more restrictive than $4/5$, particularly at intermediate contamination levels where TY may not contribute a positive vote.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Practical guidance tiers for lead-lag consensus analysis. Tier~3 ($K{\\geq}4/5$, $S{\\geq}3/4$) is uniquely optimal under the full 5-method panel; with threshold onset power-limited (\\S\\ref{sec:threshold_limitation}) and Toda--Yamamoto providing moderate supplementary signal (\\S\\ref{sec:ty_limitation}), $K{\\geq}3$ draws on four contributing methods. FPR is calibrated at $\\alpha{=}0.0$ (null control, $M{=}5$ methods, $N{=}3$ seeds, Pythia-410M). FNR is calibrated at $\\alpha{=}1.0$ against 6 effect-size reference pairs using a 4-method panel (excluding differenced cross-correlation); $N{=}4$ seeds (\\S\\ref{sec:calibration}).}\n\\label{tab:practical_guidance}\n\\begin{tabular}{llcccc}\n\\toprule\nTier & Use Case & $K/M$ & $S/N$ & FPR & FNR \\\\\n\\midrule\n1 & Exploratory     & ${\\geq}1/5$ & ${\\geq}1/N$ & 100\\%  & 0\\%    \\\\\n2 & Screening       & ${\\geq}3/5$ & ${\\geq}2/N$ & 37.5\\% & 0\\%    \\\\\n3 & Confirmatory    & ${\\geq}4/5$ & ${\\geq}3/N$ & 0\\%    & 0\\%    \\\\\n4 & Conservative    & $5/5$       & $N/N$        & 0\\%    & 50\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\subsection{Empirical Calibration}\n\\label{sec:calibration}\n\nWe calibrate the framework using two built-in experimental controls.\nFull numerical results are reported in Table~\\ref{tab:fpr_fnr}.\n\n\\paragraph{False positive rate.}\nThe $\\alpha{=}0.0$ condition serves as a null control: no synthetic data is injected, so any detected lead-lag association is a false positive.\nAt $K{=}1$ (any single method suffices), FPR${=}$75\\%: naive cross-correlation flags 6/8 forward-direction pairs.\nAt $K{=}2$, FPR drops to ${\\leq}$37.5\\%; at $K{=}3$, to ${\\leq}$12.5\\%; and at $K{\\geq}4$, FPR${=}$0\\%.\nThe consensus framework at Tier~3 matches the false positive performance of the best individual method (permutation Granger, 0\\%) while providing robustness against miscalibration of any single method.\n\n\\paragraph{False negative rate.}\nAt $\\alpha{=}1.0$ with 4~seeds, we define six \\emph{effect-size reference pairs} using criteria independent of the consensus methods:\n\\begin{enumerate}\n    \\item[(a)] The canary$\\to$downstream drift ratio at $\\alpha{=}1.0$ must exceed $3\\times$ the $\\alpha{=}0.0$ baseline drift (canary ratios: entropy $11.93\\times$, ECE $73.12\\times$, both far above threshold); and\n    \\item[(b)] Canary onset must strictly precede downstream onset by at least one generation (canary onset: generation~1; diversity onset: generations~3--9).\n\\end{enumerate}\nThese criteria yield token entropy and ECE each predicting distinct-1, distinct-2, and distinct-3~\\cite{li2016diversity}.\nThe perplexity channel is excluded because its onset (generation~1) coincides with canary onset, consistent with, but not derived from, the differencing diagnostic finding that canary$\\to$perplexity associations are spurious (\\S\\ref{sec:method_sensitivity}).\nThe effect-size threshold is robust: at $2\\times$, $3\\times$, and $5\\times$ the baseline drift, the reference set remains identical (6~pairs), because canary ratios ($11.93\\times$ and $73.12\\times$) far exceed all thresholds.\n\nFNR is calibrated using a 4-method panel excluding differenced cross-correlation, which shares statistical properties with detrending-based criteria and could introduce circularity.\nAt $K{\\geq}3/4$, $S{\\geq}3/4$, all six reference pairs are recovered (FNR${=}$0\\%).\nAt $K{=}4/4$, $S{=}4/4$, FNR rises to 50\\%, reflecting TY's moderate detection power (4/8 at $\\alpha{=}1.0$; \\S\\ref{sec:ty_limitation}).\n\n\\paragraph{Symmetric calibration.}\nBoth FPR and FNR are validated on the joint method${\\times}$seed dimension: FPR across 3~seeds at $\\alpha{=}0.0$ (0/24 pairs at $K{\\geq}3$, $3\\sigma$) and FNR across 4~seeds at $\\alpha{=}1.0$ (6/6 reference pairs recovered at $K{\\geq}3/4$, $S{\\geq}3/4$).\nCross-seed FPR variance is negligible: all three null-control seeds yield 0/8 robust pairs at $K{\\geq}3$ ($3\\sigma$), confirming seed-independent performance.\n\n\n\\paragraph{Threshold onset detection: power limitations at $3\\sigma$.}\n\\label{sec:threshold_limitation}\nPost-hoc validation of the threshold onset implementation (M028) revealed that the published $2\\sigma$ calibration was mislabeled as $3\\sigma$.\nUnder corrected $3\\sigma$ calibration, threshold onset yields 0/8 significant pairs in 8 of 12 cross-architecture conditions (Table~\\ref{tab:generalization}) and at most 2/8 in the remainder, reducing it to a near-zero-power method at $T{=}11$ generations; any threshold onset detections should therefore be interpreted as lower-bound estimates.\nThis low power is expected: with only 10 generation-over-generation differences, the null variance estimate has few degrees of freedom, and a $3\\sigma$ exceedance threshold becomes overly conservative.\nWe retain threshold onset as a supplementary method for completeness and report its results transparently, but adopt permutation Granger forward significance as the primary detection indicator in cross-architecture analyses.\n\n\\paragraph{Toda--Yamamoto Granger: moderate supplementary signal.}\n\\label{sec:ty_limitation}\nPost-hoc analysis identified a statsmodels API incompatibility that initially produced artificially low Toda--Yamamoto detection rates.\nAfter correcting the implementation, TY achieves moderate detection: 3/8 forward-direction pairs at $\\alpha{=}0.50$ (seed~42), 3/8 at $\\alpha{=}0.75$, and 4/8 at $\\alpha{=}1.0$ (Table~\\ref{tab:method_comparison}).\nThese rates are lower than permutation Granger (6--8/8) but confirm that TY captures genuine signal at $\\alpha{\\geq}0.50$, consistent with the method's theoretical motivation~\\cite{toda1995statistical}.\nTY is classified as a moderate supplementary method: it contributes to the consensus panel but does not serve as a primary detection indicator due to reduced statistical power at $T{=}11$ (the augmentation order $d_{\\max}$ consumes additional degrees of freedom) and sensitivity to the $d_{\\max}$ hyperparameter (Figure~\\ref{fig:differencing_dmax}b).\nWith TY providing moderate signal, the consensus panel comprises four contributing methods (three primary plus TY as supplementary), strengthening the $K{\\geq}3$ threshold: at $\\alpha{=}0.50$ (seed~42), $K{\\geq}3$ rises from 5/8 to 6/8 with TY's corrected contribution.\nAt $\\alpha{\\geq}0.50$, $K{\\geq}4$ consensus (4 of 5 methods agree) emerges in 3/8 pairs, demonstrating that multi-method agreement extends beyond the primary trio.\n\n\\subsection{Multi-Method Consensus Test (MMCT)}\n\\label{sec:mmct}\n\nThe uniform threshold ($K{\\geq}4/5$) achieves FPR${=}$0\\% and FNR${=}$0\\% on reference extremes (\\S\\ref{sec:calibration}), but this ad-hoc threshold lacks formal statistical grounding: null-calibrated permutation testing assigns $p{=}0.16$ to $K{\\geq}4/5$, failing to reach significance at conventional levels.\nThe threshold also treats all methods equally, despite the heterogeneous error profiles documented in \\S\\ref{sec:pitfalls}: naive cross-correlation has 75\\% forward-direction null-control FPR while permutation Granger has 0\\%.\nWe formalize the \\emph{Multi-Method Consensus Test} (MMCT), a weighted consensus framework that assigns each method influence proportional to its empirical specificity, following the specification curve tradition~\\cite{simonsohn2020specification} in which analytical choices are systematically varied and aggregated rather than arbitrarily fixed~\\cite{bell2022modeling}.\nMMCT serves as an evaluation framework rather than an end in itself: its primary function is to enable systematic comparison of detection methods under controlled conditions, identifying which individual methods are reliable and why others fail.\nWe do not claim a novel statistical method; MMCT is a consensus testing protocol adapted to the specific constraints of iterative training analysis: short series ($T{=}5$--$20$), non-stationarity by design, and heterogeneous method sensitivities.\n\n\\paragraph{FPR-inverse weighting.}\nLet $\\hat{\\text{FPR}}_k$ denote the empirical false positive rate of method $m_k$, estimated from $N_0$ null-control observations at $\\alpha{=}0.0$ across $S$ seeds.\nEach method receives weight\n\\begin{equation}\n    w_k = \\frac{1}{\\max(\\hat{\\text{FPR}}_k,\\; \\epsilon)},\n    \\label{eq:fpr_weight}\n\\end{equation}\nwhere $\\epsilon{=}0.01$ prevents division by zero.\nMethods with low FPR (e.g., permutation Granger at 0\\%, receiving $w_k{=}100$) dominate the consensus; methods with high FPR (e.g., naive cross-correlation at 75\\%, receiving $w_k{\\approx}1.3$) are effectively downweighted.\n\n\\paragraph{Consensus score.}\nGiven $M$ methods that return binary decisions $d_k \\in \\{0, 1\\}$ (FDR-significant or not) for a candidate pair $(X, Y)$, the weighted consensus score is:\n\\begin{equation}\n    W(X \\to Y) = \\frac{\\sum_{k=1}^{M} w_k \\cdot d_k}{\\sum_{k=1}^{M} w_k}.\n    \\label{eq:consensus_score}\n\\end{equation}\nWhen all weights equal~1 (uniform mode), $W$ reduces to $K/M$, and thresholding at $W \\geq 4/5$ recovers the uniform $K{\\geq}4$ rule exactly.\n\n\\paragraph{Statistical testing.}\nThe null distribution of $W$ is estimated from the $\\alpha{=}0.0$ control condition, where no synthetic contamination is present and any detected lead-lag association is a false positive.\nThe $N_0$ null-control pairs yield a reference distribution $\\{W_0^{(j)}\\}_{j=1}^{N_0}$, and the MMCT $p$-value is:\n\\begin{equation}\n    p_{\\text{MMCT}} = \\frac{|\\{j : W_0^{(j)} \\geq W_{\\text{obs}}\\}|}{N_0}.\n    \\label{eq:pvalue}\n\\end{equation}\nWe reject the null of no lead-lag relationship at significance level $\\alpha_{\\text{test}}$.\n\n\\paragraph{Bidirectional filtering.}\nMMCT tests both directions independently: $W(X \\to Y)$ and $W(Y \\to X)$.\nA stricter bidirectional mode requires forward significance with reverse non-significance.\nEmpirically, bidirectional and forward-only detection rates are identical across all contamination levels tested, indicating that pairs reaching weighted consensus in the forward direction consistently fail to reach consensus in reverse.\nWe therefore adopt forward-only (weighted pair forward) as the default MMCT configuration.\nAlgorithm~\\ref{alg:mmct} summarizes the procedure.\n\n\\begin{algorithm}[t]\n\\caption{Multi-Method Consensus Test (MMCT)}\n\\label{alg:mmct}\n\\begin{algorithmic}[1]\n\\Require Methods $\\{m_1, \\ldots, m_M\\}$; pair $(X, Y)$; null pairs $\\{(X_0^{(j)}, Y_0^{(j)})\\}_{j=1}^{N_0}$; floor $\\epsilon$; level $\\alpha_{\\text{test}}$\n\\Ensure Decision $d$, score $W$, $p$-value\n\\Statex \\textbf{Phase 1: Estimate weights from null control}\n\\For{$k = 1, \\ldots, M$}\n    \\State $\\hat{\\mathrm{FPR}}_k \\gets$ null-control rejection rate of $m_k$\n    \\State $w_k \\gets 1 / \\max(\\hat{\\mathrm{FPR}}_k, \\epsilon)$\n\\EndFor\n\\Statex \\textbf{Phase 2: Compute weighted consensus}\n\\For{$k = 1, \\ldots, M$}\n    \\State $d_k \\gets m_k(X, Y)$ \\Comment{1 if FDR-significant}\n\\EndFor\n\\State $W \\gets \\sum_k w_k d_k \\;/\\; \\sum_k w_k$\n\\Statex \\textbf{Phase 3: Null-distribution $p$-value}\n\\For{$j = 1, \\ldots, N_0$}\n    \\State $W_0^{(j)} \\gets$ consensus score of $(X_0^{(j)}, Y_0^{(j)})$\n\\EndFor\n\\State $p \\gets |\\{j : W_0^{(j)} \\geq W\\}| / N_0$\n\\State \\Return $\\mathbb{1}[p < \\alpha_{\\text{test}}]$, $W$, $p$\n\\end{algorithmic}\n\\end{algorithm}\n\n\\paragraph{Empirical comparison.}\nTable~\\ref{tab:mmct_ablation} compares per-method detection rates across contamination levels, revealing the systematic comparison that motivates our method recommendation.\nThe five methods exhibit sharply divergent dose-response profiles: naive cross-correlation maintains elevated FPR at the null (75\\%) but rises to 87.5\\% at $\\alpha{=}0.75$; differenced cross-correlation achieves zero null-control FPR but detects in both forward and reverse directions, failing to provide directional separation; threshold onset detects only at $\\alpha{=}0.50$ (50\\%) and returns to zero at $\\alpha{=}0.75$ under $3\\sigma$ calibration; Toda--Yamamoto achieves moderate detection at $\\alpha{\\geq}0.50$ (37.5\\%) with zero null-control FPR but lower sensitivity than permutation Granger.\nPermutation Granger alone provides the cleanest dose-response profile, with a sharp step function from 0/8 (blind spot, $\\alpha{\\leq}0.45$) to 6/8 (onset, $\\alpha{=}0.50$, dual-seed confirmed) and reliable detection at $\\alpha{\\geq}0.75$ (Table~\\ref{tab:method_comparison}; \\S\\ref{sec:regime}).\n\nPermutation Granger produces binary per-pair verdicts that yield a near-discontinuous onset of detection: a faint signal at $\\alpha{=}0.25$ (best pair FDR $p{=}0.053$) that does not reach aggregate detection through $\\alpha{=}0.45$, then an abrupt jump to 6/8 at $\\alpha{=}0.50$ (fp32), with a non-monotonic dip at $\\alpha{=}0.60$ (s42: 3/8, s43: 0/8; dual-seed confirmed synchronous collapse zone; \\S\\ref{sec:regime}).\nThis step-function profile, combined with zero null-control FPR and Shapley FPR suppression of $-0.194$, identifies PermG as the recommended individual detection method.\nCross-architecture validation confirms PermG fwd ${\\geq}6/8$ in 12 of 14 conditions, with multi-method consensus ($K{\\geq}3$) reaching ${\\geq}6/8$ in 10 of 14 (\\S\\ref{sec:generalization}).\nMMCT weighted consensus further captures graded detection strength even where individual methods remain below threshold, providing formal $p$-values that the uniform $K$-of-$M$ threshold lacks; however, the systematic comparison reveals that PermG alone provides comparable or superior detection to the full consensus framework at all contamination levels tested.\nWith TY contributing as a fourth method, full 5/5 consensus becomes achievable: at $\\alpha{=}0.50$ (seed~42), the ECE$\\to$distinct-3 pair reaches significance across all five methods, demonstrating that the consensus panel can converge unanimously even near the onset boundary when the canary--downstream coupling is strong.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Per-method forward-direction detection rates across contamination levels (Pythia-410M, seed~42, fp32). Each cell reports the fraction of 8 canary$\\to$downstream pairs reaching BH-corrected significance ($q{=}0.05$). Per-method dose-response reveals the systematic comparison that identifies PermG as the recommended method (\\S\\ref{sec:case_study}). Cross-condition results at $\\alpha{=}1.0$ are reported in Table~\\ref{tab:mmct_cross}. $^\\dagger$Moderate supplementary method (\\S\\ref{sec:ty_limitation}); FPR$_\\text{null}$ pending (null condition not yet run through corrected pipeline).}\n\\label{tab:mmct_ablation}\n\\begin{tabular}{lcccc}\n\\toprule\nMethod & FPR$_\\text{null}$ & $\\alpha{=}0.25$ & $\\alpha{=}0.50$ & $\\alpha{=}0.75$ \\\\\n\\midrule\nNaive XCorr              & 75   & 12.5 & 37.5 & 87.5 \\\\\nDiff.\\ XCorr             & 0    & 37.5 & 87.5 & 75   \\\\\nThreshold ($3\\sigma$)    & ---  & 0    & 50   & 0    \\\\\nPerm.\\ Granger           & 0    & 0    & 75   & 75   \\\\\nToda--Yamamoto$^\\dagger$ & ---  & 0    & 37.5 & 37.5 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Backward compatibility.}\nSetting all weights $w_k{=}1$ reduces MMCT to the uniform $K$-of-$M$ threshold, making the existing consensus framework (\\S\\ref{sec:consensus}) a special case.\nDescriptively, $K{\\geq}4/5$ achieves FPR${=}$0\\% and FNR${=}$0\\% on reference extremes (\\S\\ref{sec:calibration}); however, null-calibrated testing assigns $p{=}0.16$ to this threshold, indicating that it does not reach conventional significance levels.\nMMCT weighted consensus resolves this gap by providing formal $p$-values (Eq.~\\ref{eq:pvalue}) grounded in the empirical null distribution.\n\n\\paragraph{Cross-condition stability.}\nTable~\\ref{tab:mmct_cross} reports MMCT weighted consensus across all seven experimental conditions at $\\alpha{=}1.0$.\nDetection ranges from 4/8 to 8/8 while FPR remains 0 at the null control across all conditions, confirming that FPR-inverse weighting generalizes beyond the calibration setup.\nGPT-2-medium achieves the highest detection rate (8/8), consistent with its stronger per-method signal, demonstrating that MMCT's FPR-inverse weighting extracts graded detection strength that binary per-method verdicts miss.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{MMCT weighted forward consensus across experimental conditions ($\\alpha{=}1.0$, FPR-inverse weighting). Each cell reports significant canary$\\to$downstream pairs out of 8 (2~canaries $\\times$ 4~downstream metrics). All conditions maintain FPR${=}$0 at $\\alpha{=}0.0$. Values may be updated pending parameter consistency verification.}\n\\label{tab:mmct_cross}\n\\begin{tabular}{lc}\n\\toprule\nCondition & Sig / 8 \\\\\n\\midrule\nBaseline (Pythia-410M / Wiki)     & 5/8 \\\\\nArchitecture: GPT-2-medium / Wiki & \\textbf{8/8} \\\\\nArchitecture: OPT-1.3B / Wiki     & 5/8 \\\\\nScale: Pythia-1.4B / Wiki (s42)   & 4/8 \\\\\nScale: Pythia-1.4B / Wiki (s43)   & 4/8 \\\\\nDomain: Pythia-1B / C4 (s42)      & 5/8 \\\\\nDomain: Pythia-1B / C4 (s43)      & 4/8 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Theoretical Motivation: Why Entropy Leads Diversity}\n\\label{sec:theory}\n\nThe empirical lead-lag relationship between token entropy and lexical diversity (\\S\\ref{sec:regime}) admits a simple theoretical motivation grounded in the distinct mathematical properties of continuous and discrete summary statistics.\nWe present three arguments that, taken together, predict the observed temporal ordering and its dependence on contamination strength.\nThese arguments provide intuition rather than formal proof; the dose-response experiments in \\S\\ref{sec:regime} test the resulting predictions empirically.\n\n\\paragraph{Continuous versus discrete response.}\nToken entropy $H(p_t^{(g)}) = -\\sum_v p_v \\log p_v$ is a continuous functional of the token distribution $p_t^{(g)}$ at generation $g$: any infinitesimal shift in $p_t^{(g)}$ produces a proportional change in $H$.\nDistinct-$n$ diversity $D_k^{(g)}$, by contrast, is a counting statistic.\nAn $n$-gram contributes to $D_k^{(g)}$ only when its probability exceeds an effective sampling threshold $\\tau_n \\approx 1/N$, where $N$ is the number of generated tokens.\nBelow $\\tau_n$, the $n$-gram is absent from finite samples regardless of its true probability.\n$D_k^{(g)}$ therefore responds to distributional change in discrete steps: it remains constant while probabilities drift within the interval above $\\tau_n$, then drops abruptly when a probability crosses the threshold.\nBecause $H$ tracks every distributional perturbation while $D_k^{(g)}$ remains silent until a threshold crossing occurs, entropy is sensitive to distributional change strictly before diversity registers it.\n\n\\paragraph{Predicted detectability regimes.}\nThe continuous-versus-discrete asymmetry determines not just the ordering of responses but the \\emph{detectability} of their temporal offset.\nWe model Granger-type detectability as the product of two competing factors:\n\\begin{equation}\n    \\text{Detectability}(\\alpha) \\;\\propto\\; S(\\alpha) \\times R(\\alpha),\n    \\label{eq:detectability}\n\\end{equation}\nwhere $S(\\alpha)$ is the \\emph{signal strength} (the magnitude of distributional shift induced by contamination) and $R(\\alpha)$ is the \\emph{temporal resolution} (the generational gap between the entropy response and the diversity response).\n\n$S(\\alpha)$ increases monotonically with $\\alpha$: more synthetic data induces larger distributional shifts.\n$R(\\alpha)$, by contrast, is non-monotonic.\nAt low $\\alpha$, entropy and diversity respond in different generations ($R$ large); at a critical intermediate $\\alpha$, \\emph{relaxation time matching} occurs---the perturbation strength aligns the entropy and diversity relaxation times so that both metrics shift within the same generation, driving $R \\to 0$.\nAt high $\\alpha$, the perturbation is severe enough that entropy collapses within generation~0$\\to$1 (the continuous-functional advantage saturates immediately), while diversity still requires generation~1$\\to$2 to fully manifest the loss---tail $n$-grams near $\\tau_n$ persist temporarily before crossing the threshold---and the one-generation lead recovers ($R$ large again).\n\nThe competition between $S$ and $R$ predicts four regimes:\n\\begin{enumerate}\n\\item \\textbf{Blind} ($\\alpha \\leq 0.45$).\n$S$ falls below the detection floor; $S \\times R \\approx 0$ regardless of $R$.\n\\item \\textbf{Onset} ($\\alpha \\approx 0.50$).\n$S$ crosses the detection threshold while $R$ remains high (entropy leads diversity by a full generation); $S \\times R$ is sufficient for detection.\nBetween the blind and onset regimes, the framework predicts a \\emph{canary-only window} in which entropy shifts detectably but no $n$-grams have yet crossed $\\tau_n$; we lack the $\\alpha$ resolution to confirm this (our grid jumps from $0.25$ to $0.50$) and leave verification to future work with finer spacing in $[0.10, 0.45]$.\n\\item \\textbf{Synchronous dip} ($\\alpha \\approx 0.60$).\n$S$ continues increasing, but $R$ drops sharply: relaxation time matching at this $\\alpha$ compresses the entropy--diversity lag to near zero, producing a local minimum in $S \\times R$.\n\\item \\textbf{Detection} ($\\alpha \\geq 0.75$).\n$S$ grows large enough to dominate the product despite reduced $R$; the continuous-functional advantage reasserts across generations, and $S \\times R$ recovers.\n\\end{enumerate}\nThese four regimes align with the empirical dose-response (\\S\\ref{sec:regime}): blind at $\\alpha{\\leq}0.45$ (PermG 0/8), onset at $\\alpha{=}0.50$ (6/8, dual-seed), synchronous dip at $\\alpha{=}0.60$ (0--3/8, dual-seed), and detection at $\\alpha{\\geq}0.75$ (5--6/8 per seed, three seeds; 6/8 per seed at $\\alpha{=}1.0$, four seeds).\nThe non-monotonic profile is a prediction of the $S \\times R$ framework, not an anomaly requiring post-hoc explanation; indeed, non-monotonic dose-response curves are well-documented across disciplines.\nThe four-regime profile mirrors the hormetic dose-response in toxicology, where intermediate doses produce qualitatively different effects from both low and high doses~\\cite{calabrese2003hormesis}.\nThe temporal resolution collapse at intermediate $\\alpha$ ($R \\to 0$) corresponds to the known failure of Granger-type tests under contemporaneous coupling~\\cite{deshpande2010instantaneous}: when entropy and diversity shift within the same generation (lag${=}0$), the causal test loses statistical power by construction, not by methodological deficiency.\nThe detection dip is also consistent with critical speeding-up phenomena in ecological regime shifts, where early-warning indicators exhibit non-monotonic behavior near phase boundaries rather than the monotonic rise predicted by classical critical slowing down~\\cite{titus2020speeding}.\nWe emphasize that the $S \\times R$ model provides qualitative intuition, not quantitative derivation; the regime boundaries depend on model capacity, dataset properties, and sample size $N$.\n\n\\paragraph{Detection threshold vs.\\ accumulated contamination.}\nThe detection phase transition at $\\alpha_c{=}0.476$ (\\S\\ref{sec:regime}) reveals that Granger detectability depends on the \\emph{per-generation} mixing ratio $\\alpha$, not on cumulative contamination.\nAfter $G{=}10$ generations, cumulative synthetic fraction reaches $C(\\alpha, G) = 1 - (1{-}\\alpha)^G$: at $\\alpha{=}0.45$, $C = 99.75\\%$; at $\\alpha{=}0.50$, $C = 99.90\\%$---a difference of 0.15 percentage points---yet PermG detection jumps from 0/8 to 6/8.\nThe explanation lies in the per-generation signal.\nPermG detects temporal lead-lag from the time series of inter-generation entropy shifts $\\{\\Delta h^{(g)}\\}_{g=1}^G$, where $\\Delta h^{(g)} \\propto \\alpha \\cdot d_{\\mathrm{TV}}(p_g^{\\mathrm{model}}, p^{\\mathrm{real}})$ captures the per-episode perturbation scaled by the distributional gap at generation~$g$.\nThe critical threshold $\\alpha_c$ corresponds to the per-generation signal-to-noise ratio crossing the detection floor: below $\\alpha_c$, each episode's signal is too faint for the Granger test to distinguish from noise at $T{=}11$, regardless of how many episodes accumulate.\nThis overturns the implicit assumption in data poisoning research that detection difficulty scales with total contamination; our results show that two training runs with nearly identical cumulative exposure ($99.75\\%$ vs.\\ $99.90\\%$) produce categorically different detection outcomes.\n\n\\paragraph{Connection to effective rank and detection layers.}\nThe link between entropy and diversity can be made more concrete through effective rank~\\cite{roy2007effective}: $\\mathrm{erank}(P) = \\exp(H(P / \\|P\\|_1))$ measures the number of dimensions carrying substantial probability mass.\nA decline in $H$ contracts $\\mathrm{erank}(P)$, pushing tail tokens below $\\tau_n$ and eliminating the $n$-grams they participate in.\nThis yields a mechanistic chain---$H$ decreases $\\to$ $\\mathrm{erank}$ contracts $\\to$ tail probabilities cross $\\tau_n$ $\\to$ $D_k^{(g)}$ drops---in which entropy responds first.\nThis chain mediates the temporal resolution factor $R(\\alpha)$: at intermediate $\\alpha$ (${\\approx}0.60$), relaxation time matching compresses the erank-mediated cascade into a single generation ($R \\to 0$); at higher $\\alpha$, the severity of entropy collapse outpaces the cascade, restoring the generational offset ($R$ large; \\S\\ref{sec:regime}).\n\nEffective rank is a \\emph{distributional dimensionality} indicator---it detects contraction of the distribution's effective degrees of freedom---and is conceptually distinct from both distributional instability (variance inflation) and classical critical slowing down (CSD) indicators (rising autocorrelation) that characterize dynamical stability near tipping points~\\cite{scheffer2009early,dakos2012methods}.\nThese layers, together with the causal coupling layer captured by Granger-type tests, form four complementary detection channels ordered by onset threshold (\\S\\ref{sec:discussion}).\nThe distinction matters because the layers can diverge: \\citet{truong2025entropy} show that entropy collapse can be a first-order phase transition under convex feedback dynamics, in which CSD indicators remain bounded before the critical point and provide no advance warning.\nIn such regimes, distributional dimensionality may register contraction before dynamical indicators respond---or, as our experiments show (\\S\\ref{sec:case_study}), may fail entirely in an architecture-dependent manner.\n\n\\paragraph{Phase transition theory and the onset boundary.}\nThe onset at $\\alpha{\\approx}0.50$---quantified empirically as $\\alpha_c{=}0.476$ via sigmoid regression (\\S\\ref{sec:regime})---may reflect a critical mixing threshold analogous to the scaling law of \\citet{gu2024cmr} for continual pre-training.\nThe non-monotonic dip at $\\alpha{=}0.60$ (\\S\\ref{sec:regime}) is consistent with the two universality classes of \\citet{truong2025entropy}: if the transition is first-order (Class~1, irreversible, exponent $\\nu{=}1$), the abrupt simultaneous shift in canary and downstream metrics suppresses the temporal lead that Granger tests exploit, while smoother second-order dynamics (Class~2, reversible, $\\nu{=}1/2$) at neighboring $\\alpha$ values preserve it.\nThese connections are speculative and require finer $\\alpha$ resolution and direct estimation of feedback nonlinearity to validate.",
      "numLines": 354,
      "startLine": 1,
      "totalLines": 354
    }
  },
  "sourceToolAssistantUUID": "5fedf337-8bf6-4a4b-962b-1b09dac37bbc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Runtime record

_source line 765_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Director 指令] [Reframe — D130] 论文从 Methodology Paper 转型为 Detection Phase Transition Discovery Paper  投稿目标：EMNLP 2026 ARR June cycle，8 页 main text + unlimited references + appendix。当前 37 页需大幅压缩。  ## 核心…",
  "leafUuid": "1e5ede98-de7b-434a-9094-f7720da5b1da",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


### Runtime record

_source line 766_

```json
{
  "type": "ai-title",
  "aiTitle": "Correct effective_rank framework and add phase transition citations",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


### Tool call

_source line 767 · 2026-05-20T10:04:49.532Z_

<details open><summary>🔧 Tool call — Read · `toolu_01AoQhGLQnrFSTLbAZUtnutQ`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1e5ede98-de7b-434a-9094-f7720da5b1da",
  "isSidechain": false,
  "requestId": "req_011CbDdc6rvs2h3eQocptdzN",
  "type": "assistant",
  "uuid": "295d1c21-a000-4dbe-ac24-bb3e3b1573ce",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FQ92ZR5eZQWbG8x9P7E4V3",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 33355,
      "cache_read_input_tokens": 46573,
      "output_tokens": 307,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 33355,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 307,
          "cache_read_input_tokens": 46573,
          "cache_creation_input_tokens": 33355,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 33355
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

_source line 768 · 2026-05-20T10:04:49.796Z_

<details><summary>↩ Tool result · `toolu_01AoQhGLQnrFSTLbAZUtnutQ`</summary>

```text
1	\section{Discussion}\label{sec:discussion}
2	
3	\paragraph{Granger precedence is not causation.}
4	Granger causality tests whether past values of one series improve prediction of another beyond its own history; it does not establish true causation~\cite{granger1969investigating,shojaie2022granger}.
5	Bivariate Granger tests cannot exclude confounders: an unobserved process (such as a latent distributional shift in the training data) could independently drive both token entropy and diversity metrics, producing spurious lead-lag associations even when no direct relationship exists.
6	Our multi-method consensus framework inherits this limitation in full.
7	Throughout this paper, ``Granger precedence'' denotes predictive improvement in a time-series forecasting sense, not a causal mechanism.
8	This distinction is why we scope our central claim to ``token entropy Granger-precedes diversity collapse'' rather than asserting that token entropy \emph{causes} diversity collapse.
9	
10	\paragraph{Calibration scope and generalization.}
11	All FPR and FNR calibration results reported in this work are specific to our experimental setup: Pythia-410M~\cite{biderman2023pythia}, a WikiText-103 subset, $T{=}10$ generation cycles, and six contamination levels ($\alpha \in \{0.0, 0.10, 0.25, 0.50, 0.75, 1.0\}$).
12	Generalization to other model architectures, datasets, or training protocols requires independent validation.
13	The consensus framework's structure (multi-method agreement combined with multi-seed replication) is intended to be applicable beyond this specific setting, but the operating thresholds are empirically calibrated and may require re-tuning under different conditions.
14	For instance, architectures with different tokenizer granularity or training dynamics could shift the balance between false positive and false negative rates.
15	Cross-architecture validation across 14 confirmed conditions spanning six model families confirms that the entropy-leads-diversity pattern generalizes: permutation Granger forward significance reaches ${\geq}6/8$ in 12 of 14 architecture-seed combinations (Table~\ref{tab:generalization}); SmolLM3-3B (3/8) diverges due to canary metric splitting (\S\ref{sec:generalization}).
16	$K{\geq}3$ multi-method consensus reaches ${\geq}6/8$ in 10 of 14 conditions (11/14 pending Padding-410M audit), confirming that multi-method agreement generalizes beyond the calibration setup; Pythia-1.4B (s42: 1/8, s43: 3/8) and SmolLM3-3B (3/8) reflect scale-dependent seed sensitivity and canary metric splitting rather than framework failure.
17	Reverse-direction tests at $\alpha{=}1.0$ reveal a canary-specific asymmetry: token entropy exhibits 0/28 reverse significance across all 7 validated conditions (consistent with unidirectional Granger precedence at full synthetic replacement), while ECE shows 13/28 reverse-significant pairs (5/7 conditions), all in the distinct$\to$ECE direction. This pattern confirms bidirectional feedback between calibration and diversity.
18	The unidirectionality of token entropy is domain-dependent: at $\alpha{=}0.50$ on C4 (s42 fp32), PermG reverse reaches 7/8, indicating near-symmetric bidirectional coupling absent from all WikiText conditions at any contamination level (see below).
19	GPT-2-medium seed~43 exhibits the most pronounced bidirectional coupling: PermG reverse reaches 4/8, the highest of any condition, yet the forward signal (6/8) still exceeds the reverse, preserving net directionality.
20	Under extreme collapse ($\alpha{=}1.0$), the mutual feedback between diversity loss and calibration drift can strengthen the reverse channel without eliminating the forward lead, consistent with a model in which diversity collapse feeds back into calibration but does so with a lag that preserves the temporal ordering established in the forward direction.
21	Full-panel inter-method agreement remains low (Fleiss' $\kappa{=}0.091$) but rises to $\kappa{=}0.667$ among the three informative methods (\S\ref{sec:method_sensitivity}), confirming that the consensus framework's structure transfers across architectures even if operating thresholds require architecture-specific calibration.
22	At $\alpha{=}0.25$, GPT-2-medium yields 0/8 pairs at PermG fwd significance, placing it in the same null regime as Pythia and confirming that the detectability boundary is consistent across architectures.
23	The full GPT-2-medium drift profile at $\alpha{=}0.25$ is: entropy $-32.8\%$, ECE $+422\%$, perplexity $-44.5\%$, distinct-1 $-23.5\%$, distinct-2 $-31.6\%$, distinct-3 $-30.2\%$, MAUVE $0.0315 \to 0.0282$ ($-10.5\%$).
24	Compared to Pythia ($-4.7{\pm}0.5\%$ entropy, $-40.3{\pm}0.3\%$ distinct-1), GPT-2-medium shows substantially stronger canary drift but milder diversity decline, likely due to its $8\times$ larger batch size exposing more data per step.
25	The stronger canary signal approaches detectability (permutation Granger $F{=}64.09$, $p{=}0.081$ for entropy$\to$distinct-1, compared to $p{>}0.5$ in Pythia), suggesting that the regime boundary may shift with increased effective sample size, but single-seed $T{=}10$ power remains insufficient for Confirmatory claims.
26	Toda--Yamamoto Granger achieves 0/8 at $\alpha{=}0.25$ (consistent with the null regime) and moderate detection (3--4/8) only at $\alpha{\geq}0.50$ (\S\ref{sec:ty_limitation}).
27	
28	\paragraph{From ad-hoc consensus to method recommendation.}
29	The primary value of the multi-method framework is not the consensus vote itself but the systematic comparison it enables.
30	By applying five methods with different inductive biases to the same data, the framework reveals \emph{why} each method succeeds or fails: naive cross-correlation inflates FPR because it captures reverse-directional associations; differenced cross-correlation cannot distinguish forward from reverse precedence; threshold onset lacks power at $T{=}11$ under $3\sigma$ calibration (\S\ref{sec:threshold_limitation}); and Toda--Yamamoto achieves moderate detection (3--4/8) but remains sensitive to the augmentation order $d_{\max}$ (\S\ref{sec:ty_limitation}).
31	This process of elimination converges on permutation Granger as the recommended method: it is the only one combining zero null-control FPR, consistent detection at $\alpha{\geq}0.50$, and clean directional separation on WikiText (24/24 forward, 0/24 reverse at $\alpha{=}1.0$).
32	The MMCT weighted consensus (\S\ref{sec:mmct}) provides formal $p$-values grounded in the empirical null distribution, maintaining FPR${=}$0\%; however, the practical recommendation is simpler: for short iterative training series, permutation Granger alone provides reliable detection without requiring the full consensus machinery.
33	Multi-method consensus ($K{\geq}3$) remains useful as a robustness check, reaching ${\geq}6/8$ in 10 of 14 cross-architecture conditions (\S\ref{sec:generalization}), but threshold onset is power-limited and Toda--Yamamoto provides moderate supplementary signal (\S\ref{sec:ty_limitation}), with four contributing methods supporting the $K{\geq}3$ threshold.
34	
35	\paragraph{Short time-series constraint.}
36	With $T{=}10$ generation cycles (11 data points per series), our time-series analyses operate near the lower bound of what standard methods require.
37	This series length is typical for iterative training studies, where each generation involves a complete training run, but it severely limits statistical power.
38	After correcting a statsmodels API incompatibility (\S\ref{sec:ty_limitation}), Toda--Yamamoto achieves moderate detection (3--4/8 at $\alpha{\geq}0.50$), confirming that its lower rates reflect genuine power limitations at $T{=}11$ rather than implementation error.
39	This finding aligns with \citet{boettiger2012limits}, who demonstrated that early-warning signals have limited detection power in short time series.
40	Longer generation chains would improve power for all methods but impose substantial computational cost; this trade-off between statistical power and compute budget is inherent to iterative training research and cannot be resolved by methodological improvements alone.
41	However, observation window sensitivity analysis provides reassurance: the $4/5$ consensus classification stabilizes at $T{\geq}5$, well below our observation window of $T{=}10$, with identical results from $T{=}5$ through $T{=}10$ (Appendix~\ref{app:window_sensitivity}).
42	After implementation correction, Toda--Yamamoto's window sensitivity is consistent with its moderate detection profile: TY consensus stabilizes at $T{\geq}6$, slightly later than the primary methods ($T{\geq}5$), reflecting the additional degrees of freedom consumed by the augmentation order $d_{\max}$ (\S\ref{sec:ty_limitation}).
43	
44	\paragraph{Four-layer detection taxonomy.}
45	Our results suggest a layered taxonomy for detecting iterative training degradation, ordered by onset threshold:
46	(1)~\emph{Distributional dimensionality} (effective rank): detects contraction of the distribution's effective degrees of freedom, with onset at $\alpha{\approx}0.10$ (established);
47	(2)~\emph{Distributional instability} (entropy variance): detects inflated fluctuations in canary metrics across generations, with suggestive onset at $\alpha{\approx}0.25$ (a $10\times$ variance inflation from $0.004$ to $0.04$), well before causal coupling emerges;
48	(3)~\emph{Causal coupling} (Granger-type tests): detects temporal precedence between canary and downstream metrics, with onset at $\alpha_c{\approx}0.50$ (the detection phase transition established in \S\ref{sec:regime}); and
49	(4)~\emph{Dynamical stability} (AC1): suggestive evidence of autocorrelation shifts near the onset boundary (see below), but not statistically conclusive at $T{=}11$.
50	Layers~1 and~3 are established; Layers~2 and~4 are suggestive and require longer generation protocols for confirmation ($T{\geq}50$; \citealt{dakos2012methods}).
51	These four layers are complementary rather than redundant: dimensionality collapse and distributional instability precede causal detectability by a wide margin, and the layers can diverge across architectures.
52	
53	\paragraph{Suggestive CSD signatures at the onset boundary.}
54	Exploratory analysis of classical critical slowing down indicators reveals patterns consistent with---but not confirmatory of---CSD predictions at the detection phase transition.
55	Token entropy AC1 exhibits a $+0.30$ jump at the onset boundary (from $-0.58$ at $\alpha{=}0.45$ to $-0.28$ at $\alpha{=}0.50$); although AC1 remains negative throughout, the direction of the jump aligns with the CSD prediction that autocorrelation increases near critical transitions~\cite{scheffer2009early}.
56	Token entropy variance undergoes a $10\times$ inflation at $\alpha{=}0.25$ ($0.004 \to 0.04$), far earlier than the PermG onset at $\alpha{\approx}0.50$, suggesting that distributional instability precedes causal detectability---consistent with Layer~2 of the taxonomy above.
57	The anomalously negative AC1 at $\alpha{=}0.45$ ($-0.58$) may reflect critical speeding-up~\cite{titus2020speeding}, where indicators exhibit non-monotonic behavior immediately before a transition.
58	These patterns are suggestive but not statistically conclusive at $T{=}11$, where the 95\% confidence interval for AC1 is approximately $\pm 0.3$; longer generation protocols ($T{\geq}50$--$100$) would be needed for formal CSD testing~\cite{dakos2012methods}.
59	
60	\paragraph{Effective rank direction is model-dependent.}
61	As a distributional dimensionality indicator, effective rank tracks contraction of the distribution's effective degrees of freedom---Layer~1 in the taxonomy above.
62	However, effective rank evolves in opposite directions across architectures during iterative training.
63	In Pythia-410M, effective rank decreases (representational contraction), consistent with mode collapse concentrating the output distribution into fewer dimensions.
64	In GPT-2-medium at $\alpha{=}0.25$, effective rank \emph{increases} from 2.37 to 8.48 (+258\%).
65	The likely explanation is starting-point dependence: GPT-2-medium begins near rank-2 (a highly concentrated initial representation), and iterative training disperses activation mass across more dimensions rather than concentrating it further.
66	This finding demonstrates that effective rank cannot serve as a direction-agnostic canary and that its trajectory must be interpreted relative to architecture-specific baselines---a limitation specific to the dimensionality layer that does not affect the causal coupling layer (Granger detectability), which remains consistent across architectures.
67	
68	\paragraph{Diversity--calibration dissociation.}
69	Diversity metrics and calibration metrics respond to synthetic contamination in qualitatively opposite directions across the $\alpha$ spectrum.
70	Diversity collapse (distinct-$n$ decline) is most severe at low contamination ($\alpha{=}0.25$: distinct-3 declines by $58.9{\pm}0.9\%$) and attenuates at higher levels ($\alpha{=}1.0$: $-30.5\%$), while calibration degradation (ECE) increases monotonically with $\alpha$ ($+51.7\%$ at $\alpha{=}0.0$ to $+3780\%$ at $\alpha{=}1.0$).
71	This dissociation underscores the need for multi-method analysis: the regime in which a metric degrades most severely ($\alpha{=}0.25$ for diversity) does not coincide with the regime in which its temporal lead is most detectable ($\alpha{\geq}0.75$), and a single metric family cannot capture the full picture of iterative training degradation.
72	
73	\paragraph{Synchronous collapse at $\alpha{=}0.60$.}
74	The non-monotonic dose-response at $\alpha{=}0.60$ (PermG fwd: s42 3/8, s43 0/8, below both $\alpha{=}0.50$ and $\alpha{=}0.75$; \S\ref{sec:regime}) is consistent with the $S \times R$ prediction in \S\ref{sec:theory}: at $\alpha{=}0.60$, relaxation time matching drives temporal resolution $R \to 0$---entropy and diversity respond within the same generation---so that despite increasing signal strength $S$, the product $S \times R$ reaches a local minimum.
75	At lower contamination ($\alpha{=}0.50$), $R$ remains high---entropy leads diversity by a full generation---and $S$ has just crossed the detection threshold, yielding sufficient $S \times R$.
76	At higher contamination ($\alpha{\geq}0.75$), $S$ grows large enough to dominate: entropy collapses within generation~0$\to$1 while diversity still requires generation~1$\to$2, restoring $R$ and driving $S \times R$ well above the detection floor.
77	The synchronous dip is mechanistically distinct from the blind regime: in the blind regime ($\alpha{\leq}0.45$), canary drift is indistinguishable from the null; in the synchronous dip, both metrics drift substantially but without temporal offset.
78	This creates a four-regime structure---blind, onset, synchronous dip, detection---rather than the two-regime detect/no-detect boundary assumed by simpler models.
79	Toda--Yamamoto maintains moderate detection (3--4/8) across the $\alpha{=}0.50$--$0.75$ range including the synchronous zone where PermG drops to 0--3/8, suggesting partial inter-method complementarity: TY's augmented VAR formulation may be less sensitive to the temporal synchronization that suppresses PermG's signal at $\alpha{=}0.60$.
80	The finding also has practical implications: simple threshold-based triggers (e.g., the 15\% entropy criterion) fire at $\alpha{=}0.60$ because they respond to magnitude rather than temporal structure, suggesting that threshold triggers may outperform formal Granger tests at intermediate contamination levels.
81	
82	\paragraph{Domain-dependent directionality.}
83	The unidirectional forward causation observed consistently in WikiText experiments (PermG reverse${=}$0/8 across all contamination levels and seeds) does not hold universally.
84	On C4 at $\alpha{=}0.50$ (Pythia-410M, s42 fp32), PermG reverse reaches 7/8 (forward: 8/8), indicating near-symmetric bidirectional coupling between canary and downstream metrics (\S\ref{sec:generalization}).
85	This stands in sharp contrast to the same model at the same contamination level on WikiText, where PermG reverse${=}$0/8.
86	One possible explanation is that C4's broader distributional characteristics (Common Crawl vs.\ encyclopedic Wikipedia text) alter the temporal dynamics of collapse: the richer distributional structure may allow downstream diversity metrics to feed back into canary metrics more quickly, shortening the temporal offset that WikiText's narrower distribution preserves.
87	Alternatively, the pre-training data confound (\S\ref{sec:limitations}) may play a role, since Pythia was pre-trained on the Pile which includes C4-overlapping data.
88	The practical implication is that directional asymmetry should be verified per domain rather than assumed to transfer from WikiText-based calibration; the forward detection itself (PermG fwd${=}$8/8) remains robust across both domains.
89	
90	\paragraph{Canary metric choice as a sensitivity dimension.}
91	SmolLM3-3B reveals that canary metric selection constitutes a dimension of method sensitivity beyond the five statistical methods analyzed in Claim~3.
92	Token entropy exhibits non-monotonic oscillations across generations in SmolLM3, violating the monotonic decline assumed by Granger tests and producing 0/4 significant entropy$\to$downstream pairs.
93	ECE, by contrast, maintains monotonic growth and achieves 3/4 significant pairs (PermG fwd: 3/8 overall).
94	The two canary types activate through partially disjoint method subsets: entropy pairs reach significance via naive and differenced cross-correlation, while ECE pairs reach significance via differenced cross-correlation and permutation Granger.
95	SmolLM3-3B achieves $K{\geq}3$ = 3/8 (matching PermG fwd), confirming that consensus tracks individual-method detection even in this challenging case; however, the low overall detection (3/8) places SmolLM3 as one of three outliers ($K{\geq}3$ $<6/8$) across the 14-condition cross-architecture panel.
96	This architecture-dependent canary sensitivity complements the finding that effective rank direction is model-dependent (\S\ref{sec:case_study}): no single canary metric is universally optimal.
97	The practical implication is that monitoring dashboards should track multiple canary candidates, adapting the active metric to the architecture under evaluation.
98	
99	\paragraph{Practical utility paradox.}
100	The canary framework exhibits a paradox: it works best where it is least needed.
101	At $\alpha{\geq}0.75$, token entropy reliably Granger-precedes diversity collapse, but at these contamination levels degradation is already severe and likely detectable through simpler means.
102	At $\alpha{\leq}0.45$, where early warning would be most valuable, aggregate canary detection remains null (a faint single-pair signal appears at $\alpha{=}0.25$ but does not reach aggregate detection through $\alpha{=}0.45$).
103	A single-seed observation at $\alpha{=}0.10$ sharpens this limitation: distinct-1 already declines by 39.6\% (comparable to the multi-seed $\alpha{=}0.25$ result of $-40.3\%$), yet token entropy differs from the null by less than 1 percentage point ($-5.3\%$ vs.\ $-4.6{\pm}0.4\%$).
104	This canary blind spot means that even small amounts of synthetic contamination can trigger diversity collapse without activating any canary warning.
105	At $\alpha{=}0.50$ (fp32), detectability is reliable (PermG fwd: 6/8, both seeds consistent), with ECE outperforming token entropy as the more sensitive canary at this level.
106	This sensitivity difference reflects how each metric aggregates distributional information: ECE decomposes calibration error across multiple probability bins, making it responsive to changes in the shape of the predicted distribution rather than just its mean, while token entropy compresses the full distribution into a single scalar average.
107	At moderate contamination ($\alpha{=}0.50$), the distributional shifts are subtle enough that bin-level decomposition detects them but the global average does not.
108	This is not a framework deficiency but an inherent characteristic of collapse dynamics: at low contamination, diversity changes are too small relative to inter-generation noise for any temporal lead to emerge above the statistical detection floor~\cite{boettiger2012limits}.
109	The practical implication is that the framework is better suited to continuous monitoring dashboards that track metric trajectories across many generations than to single-point detection decisions.
110	If contamination grows over time (as in realistic web-scale data pipelines), the canary signal will strengthen as $\alpha$ increases, providing earlier detection than post-hoc quality audits.
111	
112	\paragraph{Why this matters despite the paradox.}
113	In practice, the effective contamination level $\alpha$ is unknown and typically increases over time as web-scraped training corpora accumulate more machine-generated text.
114	A continuous monitoring dashboard would automatically trigger when $\alpha$ crosses the detectability threshold ($\alpha{\approx}0.50$), converting the paradox from a static limitation into a temporal advantage: the framework detects collapse precisely when contamination first becomes severe enough to matter.
115	The methodological contribution is independent of canary utility: the consensus framework and its three-pitfall diagnostic apply to any short-time-series lead-lag analysis in iterative training, regardless of which specific metrics are monitored.
116	The regime map itself is an actionable output: practitioners who know that $\alpha{<}0.25$ is below the detection floor should invest in data provenance and source filtering rather than metric monitoring at those contamination levels.
117	
118	\paragraph{The prevention paradox under intervention.}
119	Effective intervention truncates the collapse trajectory that established Granger precedence in the first place: if an entropy-triggered intervention prevents diversity from declining, the statistical basis for the canary relationship no longer holds.
120	This is the epidemiological prevention paradox applied to training collapse: a successful canary eliminates the evidence of its own necessity.
121	Our intervention experiments (\S\ref{sec:intervention}), validated across two model scales (410M, 1.4B) and three seed-precision conditions, provide cross-scale evidence on how individual methods respond to this truncation.
122	Differenced cross-correlation retains significance under intervention (31/32 pairs significant), consistent with its sensitivity to local co-movement patterns that persist even in truncated trajectories.
123	Threshold onset detection, by contrast, fails entirely (0/8 pairs detected), because intervention prevents the sustained monotonic decline that this method requires.
124	These divergent responses reinforce the multi-method rationale of MMCT: no single method is robust across both observational and interventional settings, and the consensus framework's ability to weight methods by empirical reliability provides a natural path toward intervention-aware monitoring.
125	The practical implication is that once a canary triggers intervention, continued monitoring should rely on methods validated under truncated dynamics rather than those calibrated on unmitigated collapse.
126	
127	\paragraph{Broader implications for training pipelines.}
128	In the Confirmatory regime ($\alpha{\geq}0.75$), the consensus framework can serve as a continuous monitoring signal within iterative training pipelines: the multi-method panel would run after each generation, and sustained agreement across metric pairs would flag potential collapse onset for human review.
129	Sequential monitoring experiments (Appendix~\ref{app:csmp}) reveal that null-calibrated CUSUM and simple calibrated thresholds yield equivalent detection times at all operating points tested, extending Claim~3 (method sensitivity) to the monitoring domain: even ostensibly more sophisticated sequential methods do not outperform calibrated baselines when the initial contamination signal is large relative to the allowance parameter.
130	The contribution of the monitoring framework lies in the null-calibration procedure (setting alarm thresholds from $\alpha{=}0.0$ data to guarantee FAR${=}$0\%) rather than in any specific test statistic.
131	The cost of running these tests per generation is negligible relative to training itself, though the practical utility paradox (\S\ref{sec:limitations}) and the scope of intervention validation (three seed-precision pairs across two model scales at $\alpha{=}1.0$, threshold confirmation at $\alpha{=}0.75$) mean that broader deployment---particularly to larger models and accumulate-mode training---requires further confirmation.
132	The 15\% entropy threshold would also trigger at $\alpha{=}0.60$ (generation~1 entropy drops 31.3\%), suggesting that the detection-and-cessation mechanism may extend below the Confirmatory regime; notably, the threshold trigger fires at $\alpha{=}0.60$ even though formal Granger detection fails at this level (synchronous collapse zone; \S\ref{sec:regime}), illustrating that magnitude-based triggers can complement temporal-precedence tests.
133	However, no intervention experiment was conducted at this contamination level, so efficacy at $\alpha{=}0.60$ remains unvalidated.
134	
135	\paragraph{Token entropy versus perplexity.}
136	The finding that token entropy Granger-precedes diversity while perplexity does not ($F{\approx}0$, $p{=}0.99$ after differencing) requires clarification, since perplexity is the exponential of cross-entropy and appears mathematically related to token entropy.
137	The distinction lies in the evaluation domain: our ``token entropy'' is $H(p_\theta | \text{context})$ evaluated on \emph{held-out real data} (the model's predictive uncertainty on genuine text), while ``perplexity'' is $\exp(H_\text{cross})$ evaluated on \emph{model-generated text} (the model's self-consistency on its own outputs).
138	The identity $\text{ppl} = \exp(\text{entropy})$ holds only when the model distribution equals the data distribution, a condition that iterative collapse systematically violates.
139	In practice, both metrics trend downward during collapse (the model becomes more certain), producing high undifferenced correlation.
140	First-differencing removes this shared trend: the canary$\to$diversity channel survives because entropy \emph{leads} diversity decline by one generation (the model narrows its distribution before output diversity measurably falls), whereas the canary$\to$perplexity channel vanishes because entropy and perplexity co-move \emph{synchronously}, both driven by the same underlying distributional contraction.
141	Thus, the perplexity channel being ``spurious'' is not trivially expected from the mathematical relationship, but rather a substantive finding about collapse dynamics: the generation-evaluation divergence breaks the entropy--perplexity coupling in a temporally informative way.
142	
143	\paragraph{NLP-specific constraints on lead-lag analysis.}
144	Our application of Granger-type methods to iterative training faces constraints absent in their original econometric settings.
145	First, observation length: typical econometric applications use $T{=}100$--$1000$ time points, whereas iterative training studies are limited to $T{=}5$--$20$ generations due to computational cost.
146	This severely constrains degrees of freedom for VAR-based methods; Toda--Yamamoto's moderate detection (3--4/8) at $T{=}11$ reflects this constraint, as the augmentation order $d_{\max}$ consumes additional degrees of freedom (\S\ref{sec:ty_limitation}).
147	Second, non-stationarity is by design: each generation's training data differs from the previous generation's, making the underlying process non-stationary by construction rather than as an incidental property.
148	Standard stationarity tests (ADF, KPSS) may yield misleading results when applied to processes with deterministic degradation trajectories rather than stochastic unit roots.
149	Third, the sample-size bottleneck compounds with multiple testing: with only 8--32 pairs per regime, FDR correction operates on small multiplicity, limiting its ability to separate true from false discoveries.
150	These constraints motivate our multi-method consensus approach as a complement to, rather than replacement for, traditional significance testing.
151	
152	\paragraph{Method sensitivity extends beyond parametric tests.}
153	We additionally tested Transfer Entropy (TE), a non-parametric information-theoretic alternative to Granger causality that makes no linearity assumptions.
154	TE produced 0/192 FDR-significant results across all conditions tested (12 runs $\times$ 8 pairs $\times$ forward/reverse, BH $q{=}0.05$), with TE--Granger concordance at 52.3\% (chance level).
155	This stands in sharp contrast to the parametric permutation Granger test, which identifies 6/8 FDR-significant forward pairs at $\alpha{=}1.0$.
156	The failure of TE at $T{=}11$ is consistent with known power limitations of non-parametric entropy estimators on short time series~\cite{schreiber2000measuring}, where binning discretization collapses distributional information that parametric models can still exploit.
157	This result extends Claim~3 beyond the five methods in our consensus panel: even the parametric vs.\ non-parametric distinction in analysis method can determine whether any signal is detected at all.
158	
159	Change-point analysis under the null condition ($\alpha{=}0.00$) reveals that diversity metrics undergo structural breaks even without contamination, reflecting natural fine-tuning drift.
160	Our Granger analysis controls for this shared trend through first-differencing, which preserves canary$\to$downstream significance (24/24) while eliminating reverse-direction signal (0/8), confirming that the detected lead-lag relationship is specific to contamination-induced collapse rather than generic training dynamics (Appendix~\ref{app:change_point}).
161	
162	\paragraph{Future work.}
163	Several directions extend this work.
164	Multivariate VAR models would enable testing for confounders and multi-directional Granger relationships beyond our current bivariate framework.
165	Multi-seed replication across the six validated architecture families would further strengthen the cross-architecture claims; evaluation on larger-scale models (${>}7$B parameters) remains an open direction.
166	Longer training runs ($T{\geq}20$ generations) could unlock threshold onset detection, which requires more generation-over-generation differences for $3\sigma$ calibration to achieve adequate power; longer runs could also improve Toda--Yamamoto's moderate detection rates by providing additional degrees of freedom for the augmented VAR (\S\ref{sec:ty_limitation}).
167	The SmolLM3 finding (ECE-only detection due to non-monotonic entropy) motivates systematic study of which canary metric is most reliable per architecture family.
168	Online monitoring, where canary metrics are computed within training pipelines for real-time collapse detection, is a natural applied extension.
169	Accumulate-mode experiments~\cite{dey2024breaking} would test whether canary dynamics differ from the replace-mode setting studied here.
170	The sigmoid quantification of the onset boundary ($\alpha_c{=}0.476$; \S\ref{sec:regime}) invites connection to theoretical frameworks---the critical mixture ratio scaling law of \citet{gu2024cmr} and the universality classes of \citet{truong2025entropy}---that could explain why canary signals emerge at this contamination regime and whether the non-monotonic dip at $\alpha{=}0.60$ reflects a transition boundary; these connections remain speculative and require finer $\alpha$ resolution to validate.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "295d1c21-a000-4dbe-ac24-bb3e3b1573ce",
  "isSidechain": false,
  "promptId": "0bc1eef6-835a-4ee4-a8a1-06010792cb3b",
  "type": "user",
  "uuid": "fbcfc2ed-bcd4-4c68-bbe1-ae54e90b8536",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/discussion.tex",
      "content": "\\section{Discussion}\\label{sec:discussion}\n\n\\paragraph{Granger precedence is not causation.}\nGranger causality tests whether past values of one series improve prediction of another beyond its own history; it does not establish true causation~\\cite{granger1969investigating,shojaie2022granger}.\nBivariate Granger tests cannot exclude confounders: an unobserved process (such as a latent distributional shift in the training data) could independently drive both token entropy and diversity metrics, producing spurious lead-lag associations even when no direct relationship exists.\nOur multi-method consensus framework inherits this limitation in full.\nThroughout this paper, ``Granger precedence'' denotes predictive improvement in a time-series forecasting sense, not a causal mechanism.\nThis distinction is why we scope our central claim to ``token entropy Granger-precedes diversity collapse'' rather than asserting that token entropy \\emph{causes} diversity collapse.\n\n\\paragraph{Calibration scope and generalization.}\nAll FPR and FNR calibration results reported in this work are specific to our experimental setup: Pythia-410M~\\cite{biderman2023pythia}, a WikiText-103 subset, $T{=}10$ generation cycles, and six contamination levels ($\\alpha \\in \\{0.0, 0.10, 0.25, 0.50, 0.75, 1.0\\}$).\nGeneralization to other model architectures, datasets, or training protocols requires independent validation.\nThe consensus framework's structure (multi-method agreement combined with multi-seed replication) is intended to be applicable beyond this specific setting, but the operating thresholds are empirically calibrated and may require re-tuning under different conditions.\nFor instance, architectures with different tokenizer granularity or training dynamics could shift the balance between false positive and false negative rates.\nCross-architecture validation across 14 confirmed conditions spanning six model families confirms that the entropy-leads-diversity pattern generalizes: permutation Granger forward significance reaches ${\\geq}6/8$ in 12 of 14 architecture-seed combinations (Table~\\ref{tab:generalization}); SmolLM3-3B (3/8) diverges due to canary metric splitting (\\S\\ref{sec:generalization}).\n$K{\\geq}3$ multi-method consensus reaches ${\\geq}6/8$ in 10 of 14 conditions (11/14 pending Padding-410M audit), confirming that multi-method agreement generalizes beyond the calibration setup; Pythia-1.4B (s42: 1/8, s43: 3/8) and SmolLM3-3B (3/8) reflect scale-dependent seed sensitivity and canary metric splitting rather than framework failure.\nReverse-direction tests at $\\alpha{=}1.0$ reveal a canary-specific asymmetry: token entropy exhibits 0/28 reverse significance across all 7 validated conditions (consistent with unidirectional Granger precedence at full synthetic replacement), while ECE shows 13/28 reverse-significant pairs (5/7 conditions), all in the distinct$\\to$ECE direction. This pattern confirms bidirectional feedback between calibration and diversity.\nThe unidirectionality of token entropy is domain-dependent: at $\\alpha{=}0.50$ on C4 (s42 fp32), PermG reverse reaches 7/8, indicating near-symmetric bidirectional coupling absent from all WikiText conditions at any contamination level (see below).\nGPT-2-medium seed~43 exhibits the most pronounced bidirectional coupling: PermG reverse reaches 4/8, the highest of any condition, yet the forward signal (6/8) still exceeds the reverse, preserving net directionality.\nUnder extreme collapse ($\\alpha{=}1.0$), the mutual feedback between diversity loss and calibration drift can strengthen the reverse channel without eliminating the forward lead, consistent with a model in which diversity collapse feeds back into calibration but does so with a lag that preserves the temporal ordering established in the forward direction.\nFull-panel inter-method agreement remains low (Fleiss' $\\kappa{=}0.091$) but rises to $\\kappa{=}0.667$ among the three informative methods (\\S\\ref{sec:method_sensitivity}), confirming that the consensus framework's structure transfers across architectures even if operating thresholds require architecture-specific calibration.\nAt $\\alpha{=}0.25$, GPT-2-medium yields 0/8 pairs at PermG fwd significance, placing it in the same null regime as Pythia and confirming that the detectability boundary is consistent across architectures.\nThe full GPT-2-medium drift profile at $\\alpha{=}0.25$ is: entropy $-32.8\\%$, ECE $+422\\%$, perplexity $-44.5\\%$, distinct-1 $-23.5\\%$, distinct-2 $-31.6\\%$, distinct-3 $-30.2\\%$, MAUVE $0.0315 \\to 0.0282$ ($-10.5\\%$).\nCompared to Pythia ($-4.7{\\pm}0.5\\%$ entropy, $-40.3{\\pm}0.3\\%$ distinct-1), GPT-2-medium shows substantially stronger canary drift but milder diversity decline, likely due to its $8\\times$ larger batch size exposing more data per step.\nThe stronger canary signal approaches detectability (permutation Granger $F{=}64.09$, $p{=}0.081$ for entropy$\\to$distinct-1, compared to $p{>}0.5$ in Pythia), suggesting that the regime boundary may shift with increased effective sample size, but single-seed $T{=}10$ power remains insufficient for Confirmatory claims.\nToda--Yamamoto Granger achieves 0/8 at $\\alpha{=}0.25$ (consistent with the null regime) and moderate detection (3--4/8) only at $\\alpha{\\geq}0.50$ (\\S\\ref{sec:ty_limitation}).\n\n\\paragraph{From ad-hoc consensus to method recommendation.}\nThe primary value of the multi-method framework is not the consensus vote itself but the systematic comparison it enables.\nBy applying five methods with different inductive biases to the same data, the framework reveals \\emph{why} each method succeeds or fails: naive cross-correlation inflates FPR because it captures reverse-directional associations; differenced cross-correlation cannot distinguish forward from reverse precedence; threshold onset lacks power at $T{=}11$ under $3\\sigma$ calibration (\\S\\ref{sec:threshold_limitation}); and Toda--Yamamoto achieves moderate detection (3--4/8) but remains sensitive to the augmentation order $d_{\\max}$ (\\S\\ref{sec:ty_limitation}).\nThis process of elimination converges on permutation Granger as the recommended method: it is the only one combining zero null-control FPR, consistent detection at $\\alpha{\\geq}0.50$, and clean directional separation on WikiText (24/24 forward, 0/24 reverse at $\\alpha{=}1.0$).\nThe MMCT weighted consensus (\\S\\ref{sec:mmct}) provides formal $p$-values grounded in the empirical null distribution, maintaining FPR${=}$0\\%; however, the practical recommendation is simpler: for short iterative training series, permutation Granger alone provides reliable detection without requiring the full consensus machinery.\nMulti-method consensus ($K{\\geq}3$) remains useful as a robustness check, reaching ${\\geq}6/8$ in 10 of 14 cross-architecture conditions (\\S\\ref{sec:generalization}), but threshold onset is power-limited and Toda--Yamamoto provides moderate supplementary signal (\\S\\ref{sec:ty_limitation}), with four contributing methods supporting the $K{\\geq}3$ threshold.\n\n\\paragraph{Short time-series constraint.}\nWith $T{=}10$ generation cycles (11 data points per series), our time-series analyses operate near the lower bound of what standard methods require.\nThis series length is typical for iterative training studies, where each generation involves a complete training run, but it severely limits statistical power.\nAfter correcting a statsmodels API incompatibility (\\S\\ref{sec:ty_limitation}), Toda--Yamamoto achieves moderate detection (3--4/8 at $\\alpha{\\geq}0.50$), confirming that its lower rates reflect genuine power limitations at $T{=}11$ rather than implementation error.\nThis finding aligns with \\citet{boettiger2012limits}, who demonstrated that early-warning signals have limited detection power in short time series.\nLonger generation chains would improve power for all methods but impose substantial computational cost; this trade-off between statistical power and compute budget is inherent to iterative training research and cannot be resolved by methodological improvements alone.\nHowever, observation window sensitivity analysis provides reassurance: the $4/5$ consensus classification stabilizes at $T{\\geq}5$, well below our observation window of $T{=}10$, with identical results from $T{=}5$ through $T{=}10$ (Appendix~\\ref{app:window_sensitivity}).\nAfter implementation correction, Toda--Yamamoto's window sensitivity is consistent with its moderate detection profile: TY consensus stabilizes at $T{\\geq}6$, slightly later than the primary methods ($T{\\geq}5$), reflecting the additional degrees of freedom consumed by the augmentation order $d_{\\max}$ (\\S\\ref{sec:ty_limitation}).\n\n\\paragraph{Four-layer detection taxonomy.}\nOur results suggest a layered taxonomy for detecting iterative training degradation, ordered by onset threshold:\n(1)~\\emph{Distributional dimensionality} (effective rank): detects contraction of the distribution's effective degrees of freedom, with onset at $\\alpha{\\approx}0.10$ (established);\n(2)~\\emph{Distributional instability} (entropy variance): detects inflated fluctuations in canary metrics across generations, with suggestive onset at $\\alpha{\\approx}0.25$ (a $10\\times$ variance inflation from $0.004$ to $0.04$), well before causal coupling emerges;\n(3)~\\emph{Causal coupling} (Granger-type tests): detects temporal precedence between canary and downstream metrics, with onset at $\\alpha_c{\\approx}0.50$ (the detection phase transition established in \\S\\ref{sec:regime}); and\n(4)~\\emph{Dynamical stability} (AC1): suggestive evidence of autocorrelation shifts near the onset boundary (see below), but not statistically conclusive at $T{=}11$.\nLayers~1 and~3 are established; Layers~2 and~4 are suggestive and require longer generation protocols for confirmation ($T{\\geq}50$; \\citealt{dakos2012methods}).\nThese four layers are complementary rather than redundant: dimensionality collapse and distributional instability precede causal detectability by a wide margin, and the layers can diverge across architectures.\n\n\\paragraph{Suggestive CSD signatures at the onset boundary.}\nExploratory analysis of classical critical slowing down indicators reveals patterns consistent with---but not confirmatory of---CSD predictions at the detection phase transition.\nToken entropy AC1 exhibits a $+0.30$ jump at the onset boundary (from $-0.58$ at $\\alpha{=}0.45$ to $-0.28$ at $\\alpha{=}0.50$); although AC1 remains negative throughout, the direction of the jump aligns with the CSD prediction that autocorrelation increases near critical transitions~\\cite{scheffer2009early}.\nToken entropy variance undergoes a $10\\times$ inflation at $\\alpha{=}0.25$ ($0.004 \\to 0.04$), far earlier than the PermG onset at $\\alpha{\\approx}0.50$, suggesting that distributional instability precedes causal detectability---consistent with Layer~2 of the taxonomy above.\nThe anomalously negative AC1 at $\\alpha{=}0.45$ ($-0.58$) may reflect critical speeding-up~\\cite{titus2020speeding}, where indicators exhibit non-monotonic behavior immediately before a transition.\nThese patterns are suggestive but not statistically conclusive at $T{=}11$, where the 95\\% confidence interval for AC1 is approximately $\\pm 0.3$; longer generation protocols ($T{\\geq}50$--$100$) would be needed for formal CSD testing~\\cite{dakos2012methods}.\n\n\\paragraph{Effective rank direction is model-dependent.}\nAs a distributional dimensionality indicator, effective rank tracks contraction of the distribution's effective degrees of freedom---Layer~1 in the taxonomy above.\nHowever, effective rank evolves in opposite directions across architectures during iterative training.\nIn Pythia-410M, effective rank decreases (representational contraction), consistent with mode collapse concentrating the output distribution into fewer dimensions.\nIn GPT-2-medium at $\\alpha{=}0.25$, effective rank \\emph{increases} from 2.37 to 8.48 (+258\\%).\nThe likely explanation is starting-point dependence: GPT-2-medium begins near rank-2 (a highly concentrated initial representation), and iterative training disperses activation mass across more dimensions rather than concentrating it further.\nThis finding demonstrates that effective rank cannot serve as a direction-agnostic canary and that its trajectory must be interpreted relative to architecture-specific baselines---a limitation specific to the dimensionality layer that does not affect the causal coupling layer (Granger detectability), which remains consistent across architectures.\n\n\\paragraph{Diversity--calibration dissociation.}\nDiversity metrics and calibration metrics respond to synthetic contamination in qualitatively opposite directions across the $\\alpha$ spectrum.\nDiversity collapse (distinct-$n$ decline) is most severe at low contamination ($\\alpha{=}0.25$: distinct-3 declines by $58.9{\\pm}0.9\\%$) and attenuates at higher levels ($\\alpha{=}1.0$: $-30.5\\%$), while calibration degradation (ECE) increases monotonically with $\\alpha$ ($+51.7\\%$ at $\\alpha{=}0.0$ to $+3780\\%$ at $\\alpha{=}1.0$).\nThis dissociation underscores the need for multi-method analysis: the regime in which a metric degrades most severely ($\\alpha{=}0.25$ for diversity) does not coincide with the regime in which its temporal lead is most detectable ($\\alpha{\\geq}0.75$), and a single metric family cannot capture the full picture of iterative training degradation.\n\n\\paragraph{Synchronous collapse at $\\alpha{=}0.60$.}\nThe non-monotonic dose-response at $\\alpha{=}0.60$ (PermG fwd: s42 3/8, s43 0/8, below both $\\alpha{=}0.50$ and $\\alpha{=}0.75$; \\S\\ref{sec:regime}) is consistent with the $S \\times R$ prediction in \\S\\ref{sec:theory}: at $\\alpha{=}0.60$, relaxation time matching drives temporal resolution $R \\to 0$---entropy and diversity respond within the same generation---so that despite increasing signal strength $S$, the product $S \\times R$ reaches a local minimum.\nAt lower contamination ($\\alpha{=}0.50$), $R$ remains high---entropy leads diversity by a full generation---and $S$ has just crossed the detection threshold, yielding sufficient $S \\times R$.\nAt higher contamination ($\\alpha{\\geq}0.75$), $S$ grows large enough to dominate: entropy collapses within generation~0$\\to$1 while diversity still requires generation~1$\\to$2, restoring $R$ and driving $S \\times R$ well above the detection floor.\nThe synchronous dip is mechanistically distinct from the blind regime: in the blind regime ($\\alpha{\\leq}0.45$), canary drift is indistinguishable from the null; in the synchronous dip, both metrics drift substantially but without temporal offset.\nThis creates a four-regime structure---blind, onset, synchronous dip, detection---rather than the two-regime detect/no-detect boundary assumed by simpler models.\nToda--Yamamoto maintains moderate detection (3--4/8) across the $\\alpha{=}0.50$--$0.75$ range including the synchronous zone where PermG drops to 0--3/8, suggesting partial inter-method complementarity: TY's augmented VAR formulation may be less sensitive to the temporal synchronization that suppresses PermG's signal at $\\alpha{=}0.60$.\nThe finding also has practical implications: simple threshold-based triggers (e.g., the 15\\% entropy criterion) fire at $\\alpha{=}0.60$ because they respond to magnitude rather than temporal structure, suggesting that threshold triggers may outperform formal Granger tests at intermediate contamination levels.\n\n\\paragraph{Domain-dependent directionality.}\nThe unidirectional forward causation observed consistently in WikiText experiments (PermG reverse${=}$0/8 across all contamination levels and seeds) does not hold universally.\nOn C4 at $\\alpha{=}0.50$ (Pythia-410M, s42 fp32), PermG reverse reaches 7/8 (forward: 8/8), indicating near-symmetric bidirectional coupling between canary and downstream metrics (\\S\\ref{sec:generalization}).\nThis stands in sharp contrast to the same model at the same contamination level on WikiText, where PermG reverse${=}$0/8.\nOne possible explanation is that C4's broader distributional characteristics (Common Crawl vs.\\ encyclopedic Wikipedia text) alter the temporal dynamics of collapse: the richer distributional structure may allow downstream diversity metrics to feed back into canary metrics more quickly, shortening the temporal offset that WikiText's narrower distribution preserves.\nAlternatively, the pre-training data confound (\\S\\ref{sec:limitations}) may play a role, since Pythia was pre-trained on the Pile which includes C4-overlapping data.\nThe practical implication is that directional asymmetry should be verified per domain rather than assumed to transfer from WikiText-based calibration; the forward detection itself (PermG fwd${=}$8/8) remains robust across both domains.\n\n\\paragraph{Canary metric choice as a sensitivity dimension.}\nSmolLM3-3B reveals that canary metric selection constitutes a dimension of method sensitivity beyond the five statistical methods analyzed in Claim~3.\nToken entropy exhibits non-monotonic oscillations across generations in SmolLM3, violating the monotonic decline assumed by Granger tests and producing 0/4 significant entropy$\\to$downstream pairs.\nECE, by contrast, maintains monotonic growth and achieves 3/4 significant pairs (PermG fwd: 3/8 overall).\nThe two canary types activate through partially disjoint method subsets: entropy pairs reach significance via naive and differenced cross-correlation, while ECE pairs reach significance via differenced cross-correlation and permutation Granger.\nSmolLM3-3B achieves $K{\\geq}3$ = 3/8 (matching PermG fwd), confirming that consensus tracks individual-method detection even in this challenging case; however, the low overall detection (3/8) places SmolLM3 as one of three outliers ($K{\\geq}3$ $<6/8$) across the 14-condition cross-architecture panel.\nThis architecture-dependent canary sensitivity complements the finding that effective rank direction is model-dependent (\\S\\ref{sec:case_study}): no single canary metric is universally optimal.\nThe practical implication is that monitoring dashboards should track multiple canary candidates, adapting the active metric to the architecture under evaluation.\n\n\\paragraph{Practical utility paradox.}\nThe canary framework exhibits a paradox: it works best where it is least needed.\nAt $\\alpha{\\geq}0.75$, token entropy reliably Granger-precedes diversity collapse, but at these contamination levels degradation is already severe and likely detectable through simpler means.\nAt $\\alpha{\\leq}0.45$, where early warning would be most valuable, aggregate canary detection remains null (a faint single-pair signal appears at $\\alpha{=}0.25$ but does not reach aggregate detection through $\\alpha{=}0.45$).\nA single-seed observation at $\\alpha{=}0.10$ sharpens this limitation: distinct-1 already declines by 39.6\\% (comparable to the multi-seed $\\alpha{=}0.25$ result of $-40.3\\%$), yet token entropy differs from the null by less than 1 percentage point ($-5.3\\%$ vs.\\ $-4.6{\\pm}0.4\\%$).\nThis canary blind spot means that even small amounts of synthetic contamination can trigger diversity collapse without activating any canary warning.\nAt $\\alpha{=}0.50$ (fp32), detectability is reliable (PermG fwd: 6/8, both seeds consistent), with ECE outperforming token entropy as the more sensitive canary at this level.\nThis sensitivity difference reflects how each metric aggregates distributional information: ECE decomposes calibration error across multiple probability bins, making it responsive to changes in the shape of the predicted distribution rather than just its mean, while token entropy compresses the full distribution into a single scalar average.\nAt moderate contamination ($\\alpha{=}0.50$), the distributional shifts are subtle enough that bin-level decomposition detects them but the global average does not.\nThis is not a framework deficiency but an inherent characteristic of collapse dynamics: at low contamination, diversity changes are too small relative to inter-generation noise for any temporal lead to emerge above the statistical detection floor~\\cite{boettiger2012limits}.\nThe practical implication is that the framework is better suited to continuous monitoring dashboards that track metric trajectories across many generations than to single-point detection decisions.\nIf contamination grows over time (as in realistic web-scale data pipelines), the canary signal will strengthen as $\\alpha$ increases, providing earlier detection than post-hoc quality audits.\n\n\\paragraph{Why this matters despite the paradox.}\nIn practice, the effective contamination level $\\alpha$ is unknown and typically increases over time as web-scraped training corpora accumulate more machine-generated text.\nA continuous monitoring dashboard would automatically trigger when $\\alpha$ crosses the detectability threshold ($\\alpha{\\approx}0.50$), converting the paradox from a static limitation into a temporal advantage: the framework detects collapse precisely when contamination first becomes severe enough to matter.\nThe methodological contribution is independent of canary utility: the consensus framework and its three-pitfall diagnostic apply to any short-time-series lead-lag analysis in iterative training, regardless of which specific metrics are monitored.\nThe regime map itself is an actionable output: practitioners who know that $\\alpha{<}0.25$ is below the detection floor should invest in data provenance and source filtering rather than metric monitoring at those contamination levels.\n\n\\paragraph{The prevention paradox under intervention.}\nEffective intervention truncates the collapse trajectory that established Granger precedence in the first place: if an entropy-triggered intervention prevents diversity from declining, the statistical basis for the canary relationship no longer holds.\nThis is the epidemiological prevention paradox applied to training collapse: a successful canary eliminates the evidence of its own necessity.\nOur intervention experiments (\\S\\ref{sec:intervention}), validated across two model scales (410M, 1.4B) and three seed-precision conditions, provide cross-scale evidence on how individual methods respond to this truncation.\nDifferenced cross-correlation retains significance under intervention (31/32 pairs significant), consistent with its sensitivity to local co-movement patterns that persist even in truncated trajectories.\nThreshold onset detection, by contrast, fails entirely (0/8 pairs detected), because intervention prevents the sustained monotonic decline that this method requires.\nThese divergent responses reinforce the multi-method rationale of MMCT: no single method is robust across both observational and interventional settings, and the consensus framework's ability to weight methods by empirical reliability provides a natural path toward intervention-aware monitoring.\nThe practical implication is that once a canary triggers intervention, continued monitoring should rely on methods validated under truncated dynamics rather than those calibrated on unmitigated collapse.\n\n\\paragraph{Broader implications for training pipelines.}\nIn the Confirmatory regime ($\\alpha{\\geq}0.75$), the consensus framework can serve as a continuous monitoring signal within iterative training pipelines: the multi-method panel would run after each generation, and sustained agreement across metric pairs would flag potential collapse onset for human review.\nSequential monitoring experiments (Appendix~\\ref{app:csmp}) reveal that null-calibrated CUSUM and simple calibrated thresholds yield equivalent detection times at all operating points tested, extending Claim~3 (method sensitivity) to the monitoring domain: even ostensibly more sophisticated sequential methods do not outperform calibrated baselines when the initial contamination signal is large relative to the allowance parameter.\nThe contribution of the monitoring framework lies in the null-calibration procedure (setting alarm thresholds from $\\alpha{=}0.0$ data to guarantee FAR${=}$0\\%) rather than in any specific test statistic.\nThe cost of running these tests per generation is negligible relative to training itself, though the practical utility paradox (\\S\\ref{sec:limitations}) and the scope of intervention validation (three seed-precision pairs across two model scales at $\\alpha{=}1.0$, threshold confirmation at $\\alpha{=}0.75$) mean that broader deployment---particularly to larger models and accumulate-mode training---requires further confirmation.\nThe 15\\% entropy threshold would also trigger at $\\alpha{=}0.60$ (generation~1 entropy drops 31.3\\%), suggesting that the detection-and-cessation mechanism may extend below the Confirmatory regime; notably, the threshold trigger fires at $\\alpha{=}0.60$ even though formal Granger detection fails at this level (synchronous collapse zone; \\S\\ref{sec:regime}), illustrating that magnitude-based triggers can complement temporal-precedence tests.\nHowever, no intervention experiment was conducted at this contamination level, so efficacy at $\\alpha{=}0.60$ remains unvalidated.\n\n\\paragraph{Token entropy versus perplexity.}\nThe finding that token entropy Granger-precedes diversity while perplexity does not ($F{\\approx}0$, $p{=}0.99$ after differencing) requires clarification, since perplexity is the exponential of cross-entropy and appears mathematically related to token entropy.\nThe distinction lies in the evaluation domain: our ``token entropy'' is $H(p_\\theta | \\text{context})$ evaluated on \\emph{held-out real data} (the model's predictive uncertainty on genuine text), while ``perplexity'' is $\\exp(H_\\text{cross})$ evaluated on \\emph{model-generated text} (the model's self-consistency on its own outputs).\nThe identity $\\text{ppl} = \\exp(\\text{entropy})$ holds only when the model distribution equals the data distribution, a condition that iterative collapse systematically violates.\nIn practice, both metrics trend downward during collapse (the model becomes more certain), producing high undifferenced correlation.\nFirst-differencing removes this shared trend: the canary$\\to$diversity channel survives because entropy \\emph{leads} diversity decline by one generation (the model narrows its distribution before output diversity measurably falls), whereas the canary$\\to$perplexity channel vanishes because entropy and perplexity co-move \\emph{synchronously}, both driven by the same underlying distributional contraction.\nThus, the perplexity channel being ``spurious'' is not trivially expected from the mathematical relationship, but rather a substantive finding about collapse dynamics: the generation-evaluation divergence breaks the entropy--perplexity coupling in a temporally informative way.\n\n\\paragraph{NLP-specific constraints on lead-lag analysis.}\nOur application of Granger-type methods to iterative training faces constraints absent in their original econometric settings.\nFirst, observation length: typical econometric applications use $T{=}100$--$1000$ time points, whereas iterative training studies are limited to $T{=}5$--$20$ generations due to computational cost.\nThis severely constrains degrees of freedom for VAR-based methods; Toda--Yamamoto's moderate detection (3--4/8) at $T{=}11$ reflects this constraint, as the augmentation order $d_{\\max}$ consumes additional degrees of freedom (\\S\\ref{sec:ty_limitation}).\nSecond, non-stationarity is by design: each generation's training data differs from the previous generation's, making the underlying process non-stationary by construction rather than as an incidental property.\nStandard stationarity tests (ADF, KPSS) may yield misleading results when applied to processes with deterministic degradation trajectories rather than stochastic unit roots.\nThird, the sample-size bottleneck compounds with multiple testing: with only 8--32 pairs per regime, FDR correction operates on small multiplicity, limiting its ability to separate true from false discoveries.\nThese constraints motivate our multi-method consensus approach as a complement to, rather than replacement for, traditional significance testing.\n\n\\paragraph{Method sensitivity extends beyond parametric tests.}\nWe additionally tested Transfer Entropy (TE), a non-parametric information-theoretic alternative to Granger causality that makes no linearity assumptions.\nTE produced 0/192 FDR-significant results across all conditions tested (12 runs $\\times$ 8 pairs $\\times$ forward/reverse, BH $q{=}0.05$), with TE--Granger concordance at 52.3\\% (chance level).\nThis stands in sharp contrast to the parametric permutation Granger test, which identifies 6/8 FDR-significant forward pairs at $\\alpha{=}1.0$.\nThe failure of TE at $T{=}11$ is consistent with known power limitations of non-parametric entropy estimators on short time series~\\cite{schreiber2000measuring}, where binning discretization collapses distributional information that parametric models can still exploit.\nThis result extends Claim~3 beyond the five methods in our consensus panel: even the parametric vs.\\ non-parametric distinction in analysis method can determine whether any signal is detected at all.\n\nChange-point analysis under the null condition ($\\alpha{=}0.00$) reveals that diversity metrics undergo structural breaks even without contamination, reflecting natural fine-tuning drift.\nOur Granger analysis controls for this shared trend through first-differencing, which preserves canary$\\to$downstream significance (24/24) while eliminating reverse-direction signal (0/8), confirming that the detected lead-lag relationship is specific to contamination-induced collapse rather than generic training dynamics (Appendix~\\ref{app:change_point}).\n\n\\paragraph{Future work.}\nSeveral directions extend this work.\nMultivariate VAR models would enable testing for confounders and multi-directional Granger relationships beyond our current bivariate framework.\nMulti-seed replication across the six validated architecture families would further strengthen the cross-architecture claims; evaluation on larger-scale models (${>}7$B parameters) remains an open direction.\nLonger training runs ($T{\\geq}20$ generations) could unlock threshold onset detection, which requires more generation-over-generation differences for $3\\sigma$ calibration to achieve adequate power; longer runs could also improve Toda--Yamamoto's moderate detection rates by providing additional degrees of freedom for the augmented VAR (\\S\\ref{sec:ty_limitation}).\nThe SmolLM3 finding (ECE-only detection due to non-monotonic entropy) motivates systematic study of which canary metric is most reliable per architecture family.\nOnline monitoring, where canary metrics are computed within training pipelines for real-time collapse detection, is a natural applied extension.\nAccumulate-mode experiments~\\cite{dey2024breaking} would test whether canary dynamics differ from the replace-mode setting studied here.\nThe sigmoid quantification of the onset boundary ($\\alpha_c{=}0.476$; \\S\\ref{sec:regime}) invites connection to theoretical frameworks---the critical mixture ratio scaling law of \\citet{gu2024cmr} and the universality classes of \\citet{truong2025entropy}---that could explain why canary signals emerge at this contamination regime and whether the non-monotonic dip at $\\alpha{=}0.60$ reflects a transition boundary; these connections remain speculative and require finer $\\alpha$ resolution to validate.",
      "numLines": 170,
      "startLine": 1,
      "totalLines": 170
    }
  },
  "sourceToolAssistantUUID": "295d1c21-a000-4dbe-ac24-bb3e3b1573ce",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Tool call

_source line 769 · 2026-05-20T10:04:50.061Z_

<details open><summary>🔧 Tool call — Read · `toolu_01MMMKQVDvbuuHrAxHg6cxzQ`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "fbcfc2ed-bcd4-4c68-bbe1-ae54e90b8536",
  "isSidechain": false,
  "requestId": "req_011CbDdc6rvs2h3eQocptdzN",
  "type": "assistant",
  "uuid": "35efed85-a976-4aa8-8fef-89e3b71c6e7f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FQ92ZR5eZQWbG8x9P7E4V3",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 33355,
      "cache_read_input_tokens": 46573,
      "output_tokens": 307,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 33355,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 307,
          "cache_read_input_tokens": 46573,
          "cache_creation_input_tokens": 33355,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 33355
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

_source line 770 · 2026-05-20T10:04:50.858Z_

<details><summary>↩ Tool result · `toolu_0158nVjAdxS3J5eoh4PdaFpE`</summary>

```text
1	\section{Related Work}
2	\label{sec:related_work}
3	
4	\paragraph{Model collapse in iterative training.}
5	
6	The phenomenon of iterative training collapse was formalized by \citet{shumailov2024curse}, who showed that recursively replacing real data with model-generated text causes progressive tail erosion across VAEs, GMMs, and language models, and by \citet{alemohammad2024mad}, who demonstrated quality--diversity tradeoffs in self-consuming generative loops for image models.
7	Theoretical analyses have since sharpened these results: \citet{dohmatob2024tale} recast collapse as a change in scaling-law exponents, showing that even small fractions of synthetic data alter effective scaling behavior, while \citet{dohmatob2025strong} proved that collapse can occur even when synthetic data constitutes a vanishingly small fraction of the training set.
8	\citet{hataya2023will} provided early empirical evidence that large-scale generative models degrade future datasets through web-scale contamination, showing that even state-of-the-art models produce training-data artifacts detectable in downstream models, a finding that motivates our focus on contamination-level-dependent analysis.
9	\citet{seddik2024bad} formalized the statistical analysis of training on synthetic data, deriving excess risk bounds that quantify how synthetic fraction and model misspecification jointly govern degradation; their framework predicts regime-dependent behavior consistent with the onset boundary we observe empirically at $\alpha{\approx}0.45$--$0.50$.
10	The role of data accumulation has been a central theme.
11	\citet{dey2024breaking} proved that accumulating data across generations (rather than replacing it) prevents divergence of population risk in GMMs, HMMs, and language models.
12	\citet{kazdan2025collapse} systematically compared replace and accumulate regimes, finding that synthetic data value depends on the absolute quantity of co-present real data.
13	\citet{fu2025selfconsuming} provided generalization bounds for self-consuming loops, establishing that a constant fraction of real data suffices for convergence under accumulation.
14	On the calibration side, \citet{he2025golden} showed that optimal real-data weighting converges to the golden-ratio inverse ($1/\varphi \approx 0.618$) in Gaussian and GLM settings, and that the risk landscape is non-monotone in mixing ratio, a theoretical prediction with implications for regime-dependent canary behavior.
15	Beyond distributional statistics, \citet{guo2024linguistic} documented progressive decline in lexical, syntactic, and semantic diversity across iterative fine-tuning generations, providing the multi-level diversity metrics that serve as downstream targets in our lead-lag analysis.
16	\citet{schaeffer2025position} catalogued eight distinct and sometimes contradictory definitions of ``model collapse'' in the literature, underscoring the importance of explicit operational definitions, a concern our framework addresses by scoping canary prediction to diversity metrics specifically.
17	
18	\paragraph{Canary metrics and collapse monitoring.}
19	
20	Several recent works have proposed monitoring metrics that precede or accompany distributional degradation during iterative training.
21	\citet{du2026geometric} observe that calibration error rises before accuracy degrades in iteratively trained language models, interpreting this through a geometric-regulation lens.
22	\citet{du2025scales} report a similar pattern across model scales and mixing ratios, noting that ECE increases of 75\% appear at 30\% synthetic contamination before accuracy drops become visible.
23	Beyond calibration, SIGMA~\cite{sigma2026spectral} introduces a dual-track spectral framework based on embedding Gram matrices, where divergence between deterministic and stochastic spectral bounds serves as an early collapse diagnostic.
24	\citet{kalinowski2026topology} proposes a topological monitoring approach using persistent homology features to detect multi-scale structural loss in representation space.
25	DCES~\cite{dces2026counter} uses center-edge sampling dynamics as a collapse signal and reports improvements in ECE and entropy preservation.
26	\citet{gambetta2024surplexity} introduces surplexity, a surprise-based metric that simultaneously detects collapse and filters training data, demonstrating that high-surplexity selection matches human-data baselines in maintaining distributional balance.
27	
28	These works collectively demonstrate growing interest in collapse monitoring, yet they share methodological limitations that weaken their lead-lag claims.
29	None apply differencing tests to distinguish genuine temporal precedence from spurious co-trending; none cross-validate findings across multiple statistical methods; and none apply false discovery rate correction when testing multiple metric pairs.
30	Our work differs from the closest predecessor, \citet{du2026geometric}, in four respects:
31	(i)~we compare an entire family of canary metrics rather than a single metric pair;
32	(ii)~we cross-validate each lead-lag relationship across five independent statistical methods, quantifying inter-method sensitivity via Cohen's $\kappa$ and intra-method sensitivity via augmentation order $d_{\max}$;
33	(iii)~we map detectability as a function of contamination regime rather than reporting a single aggregate result; and
34	(iv)~we treat method-selection sensitivity itself as a primary finding, showing that it is the dominant source of variation in existing lead-lag conclusions.
35	
36	\paragraph{Training dynamics monitoring.}
37	
38	A broader literature tracks within-training diagnostics such as loss of plasticity~\cite{dohare2024plasticity,lyle2023plasticity}, effective representation rank, and gradient norm statistics as indicators of learning health.
39	These approaches monitor a single training run and detect pathologies (saturated units, rank collapse, unstable gradients) that emerge over optimization steps.
40	Our work differs in a key structural way: we analyze \emph{cross-generation} temporal relationships between aggregate statistics computed after each full training cycle, applying time-series causal methods to a sequence of $T{=}10$ generation-level observations rather than tracking step-level dynamics within a single run.
41	This distinction is methodologically consequential because the short, non-stationary series that arise from generational measurement require entirely different statistical tools (Granger causality, permutation tests, differencing diagnostics) than the long, dense traces available from step-level monitoring.
42	
43	\paragraph{Early-warning signals and critical transitions.}
44	
45	The theoretical foundation for canary-based prediction of system failure originates in ecology and climate science.
46	\citet{scheffer2009early} established that complex systems approaching tipping points exhibit generic early-warning signals (rising autocorrelation and variance due to critical slowing down), independent of system-specific mechanisms.
47	\citet{scheffer2012anticipating} extended this framework by combining empirical warning indicators with network-architecture analysis, arguing that structural and statistical signals together improve anticipatory power.
48	Crucially, \citet{boettiger2012limits} quantified the statistical detection limits of these signals, showing that early-warning power is often negligible in short time series, a constraint directly relevant to iterative training, where the number of generations (typically 5--20) is far smaller than typical ecological datasets.
49	\citet{truong2025entropy} connects entropy collapse to critical transitions, characterizing it as a first-order phase transition with universality classes that determine whether classical early-warning signals retain predictive power.
50	\citet{gu2024cmr} establish a scaling law for predicting critical mixture ratios in continual pre-training, demonstrating that the boundary between beneficial and harmful data mixing follows a power-law relationship with training scale, suggesting that onset boundaries in collapse monitoring may have principled theoretical explanations.
51	The model collapse literature has not yet imported these methodological tools: existing canary studies neither frame their claims in terms of detection power under finite samples nor test whether observed lead-lag patterns survive the short-series constraints that \citet{boettiger2012limits} identified as fundamental.
52	
53	\paragraph{Lead-lag methodology.}
54	
55	Granger causality~\cite{granger1969investigating} provides the standard econometric framework for testing whether one time series improves prediction of another beyond its own history.
56	\citet{shojaie2022granger} review classical and modern extensions, including VAR-based tests, kernel methods, and neural approaches for nonlinear dependencies \cite{marcinkevics2022neural}.
57	A key practical issue is non-stationarity: standard Granger tests applied to integrated (unit-root) series produce inflated rejection rates, the spurious regression problem formalized by \citet{granger1974spurious}, who demonstrated that regressions between independent random walks yield spuriously significant $t$-statistics, a hazard directly applicable to co-trending metrics in iterative training.
58	The Toda--Yamamoto procedure~\cite{toda1995statistical} addresses this by augmenting the VAR lag order by the integration order $d_{\max}$ and testing only the original lags, yielding valid asymptotic inference regardless of cointegration structure; however, this robustness comes at the cost of reduced degrees of freedom, a trade-off that becomes severe in the short series ($T{\leq}20$) typical of iterative training studies.
59	Despite wide use in economics and neuroscience, these methods are largely absent from the machine learning literature on iterative training.
60	Existing canary studies rely on visual inspection or naive cross-correlation, which cannot distinguish genuine temporal precedence from shared non-stationary trends.
61	Our framework applies five complementary methods (naive cross-correlation, differenced cross-correlation, threshold onset detection, permutation Granger causality, and Toda--Yamamoto Granger causality) and requires multi-method consensus before classifying a lead-lag relationship as robust, directly addressing the method-sensitivity problem that arises when any single test is taken in isolation.
62	Recent work on causal method reliability reinforces this multi-method rationale.
63	\citet{ruiz2026causalaudit} propose Causal-Audit, a pre-screening framework that validates causal assumptions before method selection and achieves 62\% false positive reduction; whereas their approach filters methods \emph{ex ante}, our consensus framework validates conclusions \emph{ex post} across methods already applied.
64	\citet{yi2026causalcompass} benchmark causal discovery robustness under eight misspecification scenarios and confirm that no single method dominates universally, directly supporting the multi-method rationale of our consensus framework.
65	Independently, \citet{sahoo2026calibration} show that calibration metrics are sensitive to training-distribution perturbation beyond the iterative collapse setting, suggesting that ECE-based canary signals may be confounded by non-collapse sources of calibration drift.
66	\citet{falahati2026curated} prove that pluralistic curation of synthetic data can prevent iterative collapse entirely, implying that canary detection is most relevant in uncontrolled data pipelines where such curation is absent.
67	
68	\paragraph{Analytical robustness in ML research.}
69	
70	The broader issue of researcher degrees of freedom in ML has received increasing attention.
71	\citet{bell2022modeling} introduced multiverse analysis to machine learning, where pipeline choices create a combinatorial space of possible results; \citet{coretta2023multidimensional} provided direct evidence through a many-analysts design in which 46 independent teams analyzed identical data and reached substantially different conclusions; and \citet{kapoor2024reforms} synthesized these concerns into REFORMS, a 32-item consensus checklist for ML-based science.
72	Our work applies this multiverse perspective to model collapse: five statistical methods across six contamination regimes produce conclusions that range from universal significance to complete null on the same dataset.
73	
74	Table~\ref{tab:method-comparison} summarizes the methodological coverage of existing canary and monitoring analyses across the diagnostic dimensions identified in \S\ref{sec:pitfalls}.
75	No prior work combines all six dimensions.
76	
77	\begin{table}[t]
78	\centering
79	\small
80	\caption{Methodological comparison of canary and monitoring analyses in the model collapse literature. \checkmark\ = present, $\times$ = absent, $\circ$ = partial (${\leq}2$ levels or limited replication). Diff.\ = differencing or stationarity controls for spurious regression. Multi-M.\ = cross-validation across ${\geq}2$ independent statistical methods. MTC = multiple testing correction (e.g., Bonferroni, BH-FDR). Regime = systematic variation of contamination level~$\alpha$. Seeds = ${\geq}3$ independent random seeds. Arch.\ = validation on ${\geq}2$ architecturally distinct model families.}
81	\label{tab:method-comparison}
82	\resizebox{\columnwidth}{!}{%
83	\begin{tabular}{lccccccl}
84	\toprule
85	Work & Diff. & Multi-M. & MTC & Regime & Seeds & Arch. & Metrics \\
86	\midrule
87	\citet{shumailov2024curse}     & $\times$   & $\times$   & $\times$   & $\circ$    & \checkmark & \checkmark & PPL \\
88	\citet{du2025scales}           & $\times$   & $\times$   & \checkmark & \checkmark & \checkmark & $\times$   & ECE, Acc, Dist-$n$ \\
89	\citet{gambetta2024surplexity} & $\times$   & $\times$   & $\times$   & \checkmark & \checkmark & \checkmark & Surplexity, Ent \\
90	SIGMA~\cite{sigma2026spectral} & $\times$   & $\times$   & $\times$   & $\times$   & $\times$   & $\times$   & Spectral \\
91	DCES~\cite{dces2026counter}    & $\times$   & $\times$   & $\times$   & $\times$   & $\times$   & \checkmark & ECE, Ent, PPL \\
92	\midrule
93	\textbf{Ours}                  & \checkmark & \checkmark & \checkmark & \checkmark & \checkmark & \checkmark & Ent, ECE, PPL, Dist-$n$ \\
94	\bottomrule
95	\end{tabular}%
96	}
97	\end{table}
98	
99	In summary, the model collapse literature has established the phenomenon and proposed monitoring metrics, while the econometric literature provides the statistical tools for temporal precedence testing.
100	However, no prior work bridges these two bodies of literature with the methodological rigor that short, non-stationary time series demand: systematic multi-method cross-validation, differencing diagnostics, false discovery correction, and regime-dependent calibration.
101	Our consensus framework fills this gap.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "11fa0f4c-062b-4303-9fd5-12632623b2d1",
  "isSidechain": false,
  "promptId": "0bc1eef6-835a-4ee4-a8a1-06010792cb3b",
  "type": "user",
  "uuid": "e1c127ce-2fda-4d26-ad7f-4e5c513d5746",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/related_work.tex",
      "content": "\\section{Related Work}\n\\label{sec:related_work}\n\n\\paragraph{Model collapse in iterative training.}\n\nThe phenomenon of iterative training collapse was formalized by \\citet{shumailov2024curse}, who showed that recursively replacing real data with model-generated text causes progressive tail erosion across VAEs, GMMs, and language models, and by \\citet{alemohammad2024mad}, who demonstrated quality--diversity tradeoffs in self-consuming generative loops for image models.\nTheoretical analyses have since sharpened these results: \\citet{dohmatob2024tale} recast collapse as a change in scaling-law exponents, showing that even small fractions of synthetic data alter effective scaling behavior, while \\citet{dohmatob2025strong} proved that collapse can occur even when synthetic data constitutes a vanishingly small fraction of the training set.\n\\citet{hataya2023will} provided early empirical evidence that large-scale generative models degrade future datasets through web-scale contamination, showing that even state-of-the-art models produce training-data artifacts detectable in downstream models, a finding that motivates our focus on contamination-level-dependent analysis.\n\\citet{seddik2024bad} formalized the statistical analysis of training on synthetic data, deriving excess risk bounds that quantify how synthetic fraction and model misspecification jointly govern degradation; their framework predicts regime-dependent behavior consistent with the onset boundary we observe empirically at $\\alpha{\\approx}0.45$--$0.50$.\nThe role of data accumulation has been a central theme.\n\\citet{dey2024breaking} proved that accumulating data across generations (rather than replacing it) prevents divergence of population risk in GMMs, HMMs, and language models.\n\\citet{kazdan2025collapse} systematically compared replace and accumulate regimes, finding that synthetic data value depends on the absolute quantity of co-present real data.\n\\citet{fu2025selfconsuming} provided generalization bounds for self-consuming loops, establishing that a constant fraction of real data suffices for convergence under accumulation.\nOn the calibration side, \\citet{he2025golden} showed that optimal real-data weighting converges to the golden-ratio inverse ($1/\\varphi \\approx 0.618$) in Gaussian and GLM settings, and that the risk landscape is non-monotone in mixing ratio, a theoretical prediction with implications for regime-dependent canary behavior.\nBeyond distributional statistics, \\citet{guo2024linguistic} documented progressive decline in lexical, syntactic, and semantic diversity across iterative fine-tuning generations, providing the multi-level diversity metrics that serve as downstream targets in our lead-lag analysis.\n\\citet{schaeffer2025position} catalogued eight distinct and sometimes contradictory definitions of ``model collapse'' in the literature, underscoring the importance of explicit operational definitions, a concern our framework addresses by scoping canary prediction to diversity metrics specifically.\n\n\\paragraph{Canary metrics and collapse monitoring.}\n\nSeveral recent works have proposed monitoring metrics that precede or accompany distributional degradation during iterative training.\n\\citet{du2026geometric} observe that calibration error rises before accuracy degrades in iteratively trained language models, interpreting this through a geometric-regulation lens.\n\\citet{du2025scales} report a similar pattern across model scales and mixing ratios, noting that ECE increases of 75\\% appear at 30\\% synthetic contamination before accuracy drops become visible.\nBeyond calibration, SIGMA~\\cite{sigma2026spectral} introduces a dual-track spectral framework based on embedding Gram matrices, where divergence between deterministic and stochastic spectral bounds serves as an early collapse diagnostic.\n\\citet{kalinowski2026topology} proposes a topological monitoring approach using persistent homology features to detect multi-scale structural loss in representation space.\nDCES~\\cite{dces2026counter} uses center-edge sampling dynamics as a collapse signal and reports improvements in ECE and entropy preservation.\n\\citet{gambetta2024surplexity} introduces surplexity, a surprise-based metric that simultaneously detects collapse and filters training data, demonstrating that high-surplexity selection matches human-data baselines in maintaining distributional balance.\n\nThese works collectively demonstrate growing interest in collapse monitoring, yet they share methodological limitations that weaken their lead-lag claims.\nNone apply differencing tests to distinguish genuine temporal precedence from spurious co-trending; none cross-validate findings across multiple statistical methods; and none apply false discovery rate correction when testing multiple metric pairs.\nOur work differs from the closest predecessor, \\citet{du2026geometric}, in four respects:\n(i)~we compare an entire family of canary metrics rather than a single metric pair;\n(ii)~we cross-validate each lead-lag relationship across five independent statistical methods, quantifying inter-method sensitivity via Cohen's $\\kappa$ and intra-method sensitivity via augmentation order $d_{\\max}$;\n(iii)~we map detectability as a function of contamination regime rather than reporting a single aggregate result; and\n(iv)~we treat method-selection sensitivity itself as a primary finding, showing that it is the dominant source of variation in existing lead-lag conclusions.\n\n\\paragraph{Training dynamics monitoring.}\n\nA broader literature tracks within-training diagnostics such as loss of plasticity~\\cite{dohare2024plasticity,lyle2023plasticity}, effective representation rank, and gradient norm statistics as indicators of learning health.\nThese approaches monitor a single training run and detect pathologies (saturated units, rank collapse, unstable gradients) that emerge over optimization steps.\nOur work differs in a key structural way: we analyze \\emph{cross-generation} temporal relationships between aggregate statistics computed after each full training cycle, applying time-series causal methods to a sequence of $T{=}10$ generation-level observations rather than tracking step-level dynamics within a single run.\nThis distinction is methodologically consequential because the short, non-stationary series that arise from generational measurement require entirely different statistical tools (Granger causality, permutation tests, differencing diagnostics) than the long, dense traces available from step-level monitoring.\n\n\\paragraph{Early-warning signals and critical transitions.}\n\nThe theoretical foundation for canary-based prediction of system failure originates in ecology and climate science.\n\\citet{scheffer2009early} established that complex systems approaching tipping points exhibit generic early-warning signals (rising autocorrelation and variance due to critical slowing down), independent of system-specific mechanisms.\n\\citet{scheffer2012anticipating} extended this framework by combining empirical warning indicators with network-architecture analysis, arguing that structural and statistical signals together improve anticipatory power.\nCrucially, \\citet{boettiger2012limits} quantified the statistical detection limits of these signals, showing that early-warning power is often negligible in short time series, a constraint directly relevant to iterative training, where the number of generations (typically 5--20) is far smaller than typical ecological datasets.\n\\citet{truong2025entropy} connects entropy collapse to critical transitions, characterizing it as a first-order phase transition with universality classes that determine whether classical early-warning signals retain predictive power.\n\\citet{gu2024cmr} establish a scaling law for predicting critical mixture ratios in continual pre-training, demonstrating that the boundary between beneficial and harmful data mixing follows a power-law relationship with training scale, suggesting that onset boundaries in collapse monitoring may have principled theoretical explanations.\nThe model collapse literature has not yet imported these methodological tools: existing canary studies neither frame their claims in terms of detection power under finite samples nor test whether observed lead-lag patterns survive the short-series constraints that \\citet{boettiger2012limits} identified as fundamental.\n\n\\paragraph{Lead-lag methodology.}\n\nGranger causality~\\cite{granger1969investigating} provides the standard econometric framework for testing whether one time series improves prediction of another beyond its own history.\n\\citet{shojaie2022granger} review classical and modern extensions, including VAR-based tests, kernel methods, and neural approaches for nonlinear dependencies \\cite{marcinkevics2022neural}.\nA key practical issue is non-stationarity: standard Granger tests applied to integrated (unit-root) series produce inflated rejection rates, the spurious regression problem formalized by \\citet{granger1974spurious}, who demonstrated that regressions between independent random walks yield spuriously significant $t$-statistics, a hazard directly applicable to co-trending metrics in iterative training.\nThe Toda--Yamamoto procedure~\\cite{toda1995statistical} addresses this by augmenting the VAR lag order by the integration order $d_{\\max}$ and testing only the original lags, yielding valid asymptotic inference regardless of cointegration structure; however, this robustness comes at the cost of reduced degrees of freedom, a trade-off that becomes severe in the short series ($T{\\leq}20$) typical of iterative training studies.\nDespite wide use in economics and neuroscience, these methods are largely absent from the machine learning literature on iterative training.\nExisting canary studies rely on visual inspection or naive cross-correlation, which cannot distinguish genuine temporal precedence from shared non-stationary trends.\nOur framework applies five complementary methods (naive cross-correlation, differenced cross-correlation, threshold onset detection, permutation Granger causality, and Toda--Yamamoto Granger causality) and requires multi-method consensus before classifying a lead-lag relationship as robust, directly addressing the method-sensitivity problem that arises when any single test is taken in isolation.\nRecent work on causal method reliability reinforces this multi-method rationale.\n\\citet{ruiz2026causalaudit} propose Causal-Audit, a pre-screening framework that validates causal assumptions before method selection and achieves 62\\% false positive reduction; whereas their approach filters methods \\emph{ex ante}, our consensus framework validates conclusions \\emph{ex post} across methods already applied.\n\\citet{yi2026causalcompass} benchmark causal discovery robustness under eight misspecification scenarios and confirm that no single method dominates universally, directly supporting the multi-method rationale of our consensus framework.\nIndependently, \\citet{sahoo2026calibration} show that calibration metrics are sensitive to training-distribution perturbation beyond the iterative collapse setting, suggesting that ECE-based canary signals may be confounded by non-collapse sources of calibration drift.\n\\citet{falahati2026curated} prove that pluralistic curation of synthetic data can prevent iterative collapse entirely, implying that canary detection is most relevant in uncontrolled data pipelines where such curation is absent.\n\n\\paragraph{Analytical robustness in ML research.}\n\nThe broader issue of researcher degrees of freedom in ML has received increasing attention.\n\\citet{bell2022modeling} introduced multiverse analysis to machine learning, where pipeline choices create a combinatorial space of possible results; \\citet{coretta2023multidimensional} provided direct evidence through a many-analysts design in which 46 independent teams analyzed identical data and reached substantially different conclusions; and \\citet{kapoor2024reforms} synthesized these concerns into REFORMS, a 32-item consensus checklist for ML-based science.\nOur work applies this multiverse perspective to model collapse: five statistical methods across six contamination regimes produce conclusions that range from universal significance to complete null on the same dataset.\n\nTable~\\ref{tab:method-comparison} summarizes the methodological coverage of existing canary and monitoring analyses across the diagnostic dimensions identified in \\S\\ref{sec:pitfalls}.\nNo prior work combines all six dimensions.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Methodological comparison of canary and monitoring analyses in the model collapse literature. \\checkmark\\ = present, $\\times$ = absent, $\\circ$ = partial (${\\leq}2$ levels or limited replication). Diff.\\ = differencing or stationarity controls for spurious regression. Multi-M.\\ = cross-validation across ${\\geq}2$ independent statistical methods. MTC = multiple testing correction (e.g., Bonferroni, BH-FDR). Regime = systematic variation of contamination level~$\\alpha$. Seeds = ${\\geq}3$ independent random seeds. Arch.\\ = validation on ${\\geq}2$ architecturally distinct model families.}\n\\label{tab:method-comparison}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccccccl}\n\\toprule\nWork & Diff. & Multi-M. & MTC & Regime & Seeds & Arch. & Metrics \\\\\n\\midrule\n\\citet{shumailov2024curse}     & $\\times$   & $\\times$   & $\\times$   & $\\circ$    & \\checkmark & \\checkmark & PPL \\\\\n\\citet{du2025scales}           & $\\times$   & $\\times$   & \\checkmark & \\checkmark & \\checkmark & $\\times$   & ECE, Acc, Dist-$n$ \\\\\n\\citet{gambetta2024surplexity} & $\\times$   & $\\times$   & $\\times$   & \\checkmark & \\checkmark & \\checkmark & Surplexity, Ent \\\\\nSIGMA~\\cite{sigma2026spectral} & $\\times$   & $\\times$   & $\\times$   & $\\times$   & $\\times$   & $\\times$   & Spectral \\\\\nDCES~\\cite{dces2026counter}    & $\\times$   & $\\times$   & $\\times$   & $\\times$   & $\\times$   & \\checkmark & ECE, Ent, PPL \\\\\n\\midrule\n\\textbf{Ours}                  & \\checkmark & \\checkmark & \\checkmark & \\checkmark & \\checkmark & \\checkmark & Ent, ECE, PPL, Dist-$n$ \\\\\n\\bottomrule\n\\end{tabular}%\n}\n\\end{table}\n\nIn summary, the model collapse literature has established the phenomenon and proposed monitoring metrics, while the econometric literature provides the statistical tools for temporal precedence testing.\nHowever, no prior work bridges these two bodies of literature with the methodological rigor that short, non-stationary time series demand: systematic multi-method cross-validation, differencing diagnostics, false discovery correction, and regime-dependent calibration.\nOur consensus framework fills this gap.",
      "numLines": 101,
      "startLine": 1,
      "totalLines": 101
    }
  },
  "sourceToolAssistantUUID": "11fa0f4c-062b-4303-9fd5-12632623b2d1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Tool result

_source line 771 · 2026-05-20T10:04:50.078Z_

<details><summary>↩ Tool result · `toolu_01MMMKQVDvbuuHrAxHg6cxzQ`</summary>

```text
1	\section{Conclusion}
2	\label{sec:conclusion}
3	
4	Lead-lag analysis in iterative training collapse is far more fragile than the current literature assumes.
5	Method choice alone inflates spurious-signal rates to at least 62.5\%, first-differencing exposes canary$\to$perplexity associations as entirely spurious, and regime dependence causes the same Granger test to shift from 24/24 to 0/8 significant pairs across contamination levels.
6	These pitfalls establish that single-method, single-regime analyses (the current default) cannot reliably distinguish genuine temporal precedence from statistical artifacts.
7	
8	Our systematic five-method comparison through the Multi-Method Consensus Test (MMCT) identifies permutation Granger causality as the recommended detection method: it is the only one combining zero null-control FPR with high sensitivity, exhibiting a clean step-function dose-response from 0/8 (blind spot, $\alpha{\leq}0.45$) to 6/8 (onset, $\alpha{=}0.50$) with reliable detection at $\alpha{\geq}0.75$.
9	The other four methods each fail in characteristic ways: naive cross-correlation inflates FPR to 75\%, differenced cross-correlation cannot separate forward from reverse precedence, threshold onset is power-limited at $T{=}10$ under $3\sigma$ calibration, and Toda--Yamamoto Granger achieves moderate detection (3--4/8 at $\alpha{\geq}0.50$) as a supplementary method.
10	
11	Applying permutation Granger, token entropy exhibits robust one-generation-ahead precedence over diversity collapse at $\alpha{=}1.0$ on WikiText-103 (24/24 forward, 0/24 reverse across 4~seeds, replicated on GPT-2-medium and OPT-1.3B), with cross-architecture validation confirming detection (${\geq}6/8$) in 12 of 14 model-seed combinations spanning six families (345M--6.9B).
12	Directional asymmetry is domain-dependent: consistent unidirectionality holds on WikiText across all regimes, while C4 exhibits near-symmetric bidirectional coupling at $\alpha{=}0.50$ (PermG reverse 7/8), though forward detection remains robust in both domains.
13	This finding is deliberately scoped to lexical diversity, not model collapse broadly, since the perplexity channel proved entirely spurious under differencing.
14	
15	The methodological pitfalls we expose arise from generic properties of short, non-stationary time series.
16	Cross-architecture (six families, 345M--6.9B), cross-scale ($3.4\times$ within Pythia), and cross-domain (C4) validation confirms that both the pitfalls and the method recommendation are not specific to a single experimental configuration; evaluation on models at ${>}$7B parameters remains an open direction.
17	Limitations are detailed in \S\ref{sec:limitations}; future directions are discussed in \S\ref{sec:discussion}.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "35efed85-a976-4aa8-8fef-89e3b71c6e7f",
  "isSidechain": false,
  "promptId": "0bc1eef6-835a-4ee4-a8a1-06010792cb3b",
  "type": "user",
  "uuid": "b5c08a99-bb33-4318-9b4e-ec826c842815",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/conclusion.tex",
      "content": "\\section{Conclusion}\n\\label{sec:conclusion}\n\nLead-lag analysis in iterative training collapse is far more fragile than the current literature assumes.\nMethod choice alone inflates spurious-signal rates to at least 62.5\\%, first-differencing exposes canary$\\to$perplexity associations as entirely spurious, and regime dependence causes the same Granger test to shift from 24/24 to 0/8 significant pairs across contamination levels.\nThese pitfalls establish that single-method, single-regime analyses (the current default) cannot reliably distinguish genuine temporal precedence from statistical artifacts.\n\nOur systematic five-method comparison through the Multi-Method Consensus Test (MMCT) identifies permutation Granger causality as the recommended detection method: it is the only one combining zero null-control FPR with high sensitivity, exhibiting a clean step-function dose-response from 0/8 (blind spot, $\\alpha{\\leq}0.45$) to 6/8 (onset, $\\alpha{=}0.50$) with reliable detection at $\\alpha{\\geq}0.75$.\nThe other four methods each fail in characteristic ways: naive cross-correlation inflates FPR to 75\\%, differenced cross-correlation cannot separate forward from reverse precedence, threshold onset is power-limited at $T{=}10$ under $3\\sigma$ calibration, and Toda--Yamamoto Granger achieves moderate detection (3--4/8 at $\\alpha{\\geq}0.50$) as a supplementary method.\n\nApplying permutation Granger, token entropy exhibits robust one-generation-ahead precedence over diversity collapse at $\\alpha{=}1.0$ on WikiText-103 (24/24 forward, 0/24 reverse across 4~seeds, replicated on GPT-2-medium and OPT-1.3B), with cross-architecture validation confirming detection (${\\geq}6/8$) in 12 of 14 model-seed combinations spanning six families (345M--6.9B).\nDirectional asymmetry is domain-dependent: consistent unidirectionality holds on WikiText across all regimes, while C4 exhibits near-symmetric bidirectional coupling at $\\alpha{=}0.50$ (PermG reverse 7/8), though forward detection remains robust in both domains.\nThis finding is deliberately scoped to lexical diversity, not model collapse broadly, since the perplexity channel proved entirely spurious under differencing.\n\nThe methodological pitfalls we expose arise from generic properties of short, non-stationary time series.\nCross-architecture (six families, 345M--6.9B), cross-scale ($3.4\\times$ within Pythia), and cross-domain (C4) validation confirms that both the pitfalls and the method recommendation are not specific to a single experimental configuration; evaluation on models at ${>}$7B parameters remains an open direction.\nLimitations are detailed in \\S\\ref{sec:limitations}; future directions are discussed in \\S\\ref{sec:discussion}.",
      "numLines": 17,
      "startLine": 1,
      "totalLines": 17
    }
  },
  "sourceToolAssistantUUID": "35efed85-a976-4aa8-8fef-89e3b71c6e7f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Tool call

_source line 772 · 2026-05-20T10:04:50.535Z_

<details open><summary>🔧 Tool call — Read · `toolu_014FDPNZ5evVQrs8RMYre2D6`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/background.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b5c08a99-bb33-4318-9b4e-ec826c842815",
  "isSidechain": false,
  "requestId": "req_011CbDdc6rvs2h3eQocptdzN",
  "type": "assistant",
  "uuid": "bc723af5-28d6-4035-95b8-9f2f87d3ab88",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FQ92ZR5eZQWbG8x9P7E4V3",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 33355,
      "cache_read_input_tokens": 46573,
      "output_tokens": 307,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 33355,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 307,
          "cache_read_input_tokens": 46573,
          "cache_creation_input_tokens": 33355,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 33355
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

_source line 773 · 2026-05-20T10:04:50.541Z_

<details><summary>↩ Tool result · `toolu_014FDPNZ5evVQrs8RMYre2D6`</summary>

```text
1	\section{Background}
2	\label{sec:background}
3	
4	This section establishes the formal setup and notation used throughout the paper.
5	
6	\paragraph{Iterative training loop.}
7	Let $M_0$ denote a pretrained language model and $\mathcal{D}_\text{real}$ a fixed corpus of human-written text.
8	At each generation $t \geq 1$, the model $M_{t-1}$ generates a synthetic corpus $\mathcal{D}_\text{synth}^{(t-1)}$, and the next-generation model $M_t$ is fine-tuned on a mixture of $\alpha$ fraction synthetic data and $(1{-}\alpha)$ fraction real data:
9	\begin{equation}
10	    \mathcal{D}_\text{train}^{(t)} = \alpha \cdot \mathcal{D}_\text{synth}^{(t-1)} \;+\; (1{-}\alpha) \cdot \mathcal{D}_\text{real}, \quad \alpha \in [0, 1].
11	    \label{eq:mixing}
12	\end{equation}
13	The contamination level $\alpha$ controls the fraction of machine-generated text in each training round.
14	At $\alpha{=}1.0$, this reduces to the full-replacement paradigm of \citet{shumailov2024curse}, where each generation trains exclusively on the previous generation's output.
15	Iterating this process for $T$ generations yields a trajectory $M_0 \to M_1 \to \cdots \to M_T$.
16	
17	\paragraph{Metric families.}
18	We distinguish two families of metrics evaluated at each generation~$t$.
19	\emph{Canary metrics} are cheap-to-compute statistics on the model's output distribution, hypothesized to change before downstream quality degrades, analogous to early-warning indicators studied in the context of critical transitions in dynamical systems \cite{scheffer2009early}.
20	We consider two canary metrics: \emph{token entropy}, the average next-token prediction entropy over held-out samples, and \emph{expected calibration error} (ECE), which measures the discrepancy between predicted token probabilities and empirical correctness frequencies.
21	\emph{Downstream metrics} capture generation quality directly.
22	We use \emph{distinct-$n$} ($n \in \{1, 2, 3\}$), the ratio of unique $n$-grams to total $n$-grams in generated text \cite{li2016diversity}, as a measure of lexical diversity, and \emph{perplexity} on a held-out set as a measure of language modeling quality.
23	Each metric produces a time series of $T{+}1$ observations (generations $0$ through $T$).
24	
25	\paragraph{The lead-lag testing problem.}
26	Given two such time series $X = (x_0, \ldots, x_T)$ and $Y = (y_0, \ldots, y_T)$ (for instance, a canary metric and a downstream metric), the central question is whether changes in $X$ temporally precede changes in $Y$.
27	This requires more than measuring correlation: the test must establish \emph{directionality} ($X \to Y$ rather than $Y \to X$) and account for confounders such as shared non-stationary trends that can produce spurious associations.
28	The classical framework for testing temporal predictive precedence is Granger causality \cite{granger1969investigating}, which asks whether past values of $X$ improve prediction of $Y$ beyond $Y$'s own history.
29	We note that Granger precedence tests predictive improvement, not true causality \cite{shojaie2022granger}; this distinction is discussed further in \S\ref{sec:method}.
30	
31	\paragraph{Five detection methods.}
32	We employ five lead-lag detection methods spanning a spectrum from permissive to conservative:
33	(1)~\emph{naive cross-correlation}, which computes Pearson correlation on undifferenced series at lags up to~5;
34	(2)~\emph{differenced cross-correlation}, which applies the same procedure to first-differenced series, removing shared linear trends;
35	(3)~\emph{threshold onset detection}, which compares the generation at which each metric first exceeds a predefined deviation threshold;
36	(4)~\emph{permutation Granger causality}, a non-parametric Granger test using 5{,}000 permutations on first-differenced series \cite{shojaie2022granger}; and
37	(5)~\emph{Toda--Yamamoto Granger causality}, an augmented VAR approach that tests Granger precedence without requiring prior differencing \cite{toda1995statistical}.
38	These methods differ in their assumptions about stationarity, their sensitivity to shared trends, and their statistical power at short time-series lengths.
39	Their joint application forms the basis of the multi-method consensus framework developed in \S\ref{sec:method}.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "bc723af5-28d6-4035-95b8-9f2f87d3ab88",
  "isSidechain": false,
  "promptId": "0bc1eef6-835a-4ee4-a8a1-06010792cb3b",
  "type": "user",
  "uuid": "0046797d-986c-451e-96fe-399be5b1112e",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/background.tex",
      "content": "\\section{Background}\n\\label{sec:background}\n\nThis section establishes the formal setup and notation used throughout the paper.\n\n\\paragraph{Iterative training loop.}\nLet $M_0$ denote a pretrained language model and $\\mathcal{D}_\\text{real}$ a fixed corpus of human-written text.\nAt each generation $t \\geq 1$, the model $M_{t-1}$ generates a synthetic corpus $\\mathcal{D}_\\text{synth}^{(t-1)}$, and the next-generation model $M_t$ is fine-tuned on a mixture of $\\alpha$ fraction synthetic data and $(1{-}\\alpha)$ fraction real data:\n\\begin{equation}\n    \\mathcal{D}_\\text{train}^{(t)} = \\alpha \\cdot \\mathcal{D}_\\text{synth}^{(t-1)} \\;+\\; (1{-}\\alpha) \\cdot \\mathcal{D}_\\text{real}, \\quad \\alpha \\in [0, 1].\n    \\label{eq:mixing}\n\\end{equation}\nThe contamination level $\\alpha$ controls the fraction of machine-generated text in each training round.\nAt $\\alpha{=}1.0$, this reduces to the full-replacement paradigm of \\citet{shumailov2024curse}, where each generation trains exclusively on the previous generation's output.\nIterating this process for $T$ generations yields a trajectory $M_0 \\to M_1 \\to \\cdots \\to M_T$.\n\n\\paragraph{Metric families.}\nWe distinguish two families of metrics evaluated at each generation~$t$.\n\\emph{Canary metrics} are cheap-to-compute statistics on the model's output distribution, hypothesized to change before downstream quality degrades, analogous to early-warning indicators studied in the context of critical transitions in dynamical systems \\cite{scheffer2009early}.\nWe consider two canary metrics: \\emph{token entropy}, the average next-token prediction entropy over held-out samples, and \\emph{expected calibration error} (ECE), which measures the discrepancy between predicted token probabilities and empirical correctness frequencies.\n\\emph{Downstream metrics} capture generation quality directly.\nWe use \\emph{distinct-$n$} ($n \\in \\{1, 2, 3\\}$), the ratio of unique $n$-grams to total $n$-grams in generated text \\cite{li2016diversity}, as a measure of lexical diversity, and \\emph{perplexity} on a held-out set as a measure of language modeling quality.\nEach metric produces a time series of $T{+}1$ observations (generations $0$ through $T$).\n\n\\paragraph{The lead-lag testing problem.}\nGiven two such time series $X = (x_0, \\ldots, x_T)$ and $Y = (y_0, \\ldots, y_T)$ (for instance, a canary metric and a downstream metric), the central question is whether changes in $X$ temporally precede changes in $Y$.\nThis requires more than measuring correlation: the test must establish \\emph{directionality} ($X \\to Y$ rather than $Y \\to X$) and account for confounders such as shared non-stationary trends that can produce spurious associations.\nThe classical framework for testing temporal predictive precedence is Granger causality \\cite{granger1969investigating}, which asks whether past values of $X$ improve prediction of $Y$ beyond $Y$'s own history.\nWe note that Granger precedence tests predictive improvement, not true causality \\cite{shojaie2022granger}; this distinction is discussed further in \\S\\ref{sec:method}.\n\n\\paragraph{Five detection methods.}\nWe employ five lead-lag detection methods spanning a spectrum from permissive to conservative:\n(1)~\\emph{naive cross-correlation}, which computes Pearson correlation on undifferenced series at lags up to~5;\n(2)~\\emph{differenced cross-correlation}, which applies the same procedure to first-differenced series, removing shared linear trends;\n(3)~\\emph{threshold onset detection}, which compares the generation at which each metric first exceeds a predefined deviation threshold;\n(4)~\\emph{permutation Granger causality}, a non-parametric Granger test using 5{,}000 permutations on first-differenced series \\cite{shojaie2022granger}; and\n(5)~\\emph{Toda--Yamamoto Granger causality}, an augmented VAR approach that tests Granger precedence without requiring prior differencing \\cite{toda1995statistical}.\nThese methods differ in their assumptions about stationarity, their sensitivity to shared trends, and their statistical power at short time-series lengths.\nTheir joint application forms the basis of the multi-method consensus framework developed in \\S\\ref{sec:method}.",
      "numLines": 39,
      "startLine": 1,
      "totalLines": 39
    }
  },
  "sourceToolAssistantUUID": "bc723af5-28d6-4035-95b8-9f2f87d3ab88",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Tool call

_source line 774 · 2026-05-20T10:04:50.835Z_

<details open><summary>🔧 Tool call — Read · `toolu_0158nVjAdxS3J5eoh4PdaFpE`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0046797d-986c-451e-96fe-399be5b1112e",
  "isSidechain": false,
  "requestId": "req_011CbDdc6rvs2h3eQocptdzN",
  "type": "assistant",
  "uuid": "11fa0f4c-062b-4303-9fd5-12632623b2d1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FQ92ZR5eZQWbG8x9P7E4V3",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 33355,
      "cache_read_input_tokens": 46573,
      "output_tokens": 307,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 33355,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 307,
          "cache_read_input_tokens": 46573,
          "cache_creation_input_tokens": 33355,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 33355
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

_source line 775 · 2026-05-20T10:04:50.877Z_

```json
{
  "parentUuid": "e1c127ce-2fda-4d26-ad7f-4e5c513d5746",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "44593d22-5949-4fc8-85da-48b49297875d",
  "timestamp": "2026-05-20T10:04:50.877Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

---


### Runtime record

_source line 776_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Director 指令] [Reframe — D130] 论文从 Methodology Paper 转型为 Detection Phase Transition Discovery Paper  投稿目标：EMNLP 2026 ARR June cycle，8 页 main text + unlimited references + appendix。当前 37 页需大幅压缩。  ## 核心…",
  "leafUuid": "44593d22-5949-4fc8-85da-48b49297875d",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


### Runtime record

_source line 777_

```json
{
  "type": "ai-title",
  "aiTitle": "Correct effective_rank framework and add phase transition citations",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


### Assistant

_source line 778 · 2026-05-20T10:04:55.015Z_

<details><summary>Logged reasoning block</summary>

```text
Now I have a comprehensive view of the current paper. Let me also read the registry and paper_framing to understand the data landscape, and check the paper-plan skill.

Actually, the paper-plan skill file wasn't found at the expected path. Let me search for it.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "44593d22-5949-4fc8-85da-48b49297875d",
  "isSidechain": false,
  "requestId": "req_011CbDdcbEV9hxos9J9uDZfW",
  "type": "assistant",
  "uuid": "c6f1eb90-579d-447d-85e6-6f087d892228",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019FPkWiN4EYAf9Gxxquhnnz",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14267,
      "cache_read_input_tokens": 79928,
      "output_tokens": 242,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 14267,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 242,
          "cache_read_input_tokens": 79928,
          "cache_creation_input_tokens": 14267,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 14267
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

_source line 779 · 2026-05-20T10:04:55.624Z_

Now let me read the registry and the paper-plan skill.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c6f1eb90-579d-447d-85e6-6f087d892228",
  "isSidechain": false,
  "requestId": "req_011CbDdcbEV9hxos9J9uDZfW",
  "type": "assistant",
  "uuid": "aab44033-fafd-482c-a2ec-9bd5a70d0b9f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019FPkWiN4EYAf9Gxxquhnnz",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14267,
      "cache_read_input_tokens": 79928,
      "output_tokens": 242,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 14267,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 242,
          "cache_read_input_tokens": 79928,
          "cache_creation_input_tokens": 14267,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 14267
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

_source line 780 · 2026-05-20T10:04:57.037Z_

<details open><summary>🔧 Tool call — Glob · `toolu_0128NXXtUM4FdsRwmneEBzxw`</summary>

```json
{
  "pattern": "**/paper-plan.skill.md",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "aab44033-fafd-482c-a2ec-9bd5a70d0b9f",
  "isSidechain": false,
  "requestId": "req_011CbDdcbEV9hxos9J9uDZfW",
  "type": "assistant",
  "uuid": "f5a02110-3667-4528-9797-154a49b17bef",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019FPkWiN4EYAf9Gxxquhnnz",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14267,
      "cache_read_input_tokens": 79928,
      "output_tokens": 242,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 14267,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 242,
          "cache_read_input_tokens": 79928,
          "cache_creation_input_tokens": 14267,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 14267
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

_source line 781 · 2026-05-20T10:04:57.278Z_

<details><summary>↩ Tool result · `toolu_01XJyPvZBfvWz3MDZrUmDuuX`</summary>

```text
No matching deferred tools found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "48ffb9a3-9dfd-45fd-ab7c-4c42f7f14745",
  "isSidechain": false,
  "promptId": "0bc1eef6-835a-4ee4-a8a1-06010792cb3b",
  "type": "user",
  "uuid": "695f5b1a-d0af-43dc-884c-66d71e7b9823",
  "toolUseResult": {
    "matches": [],
    "query": "select:read_registry",
    "total_deferred_tools": 51
  },
  "sourceToolAssistantUUID": "48ffb9a3-9dfd-45fd-ab7c-4c42f7f14745",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Tool result

_source line 782 · 2026-05-20T10:04:57.077Z_

<details><summary>↩ Tool result · `toolu_0128NXXtUM4FdsRwmneEBzxw`</summary>

```text
No files found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f5a02110-3667-4528-9797-154a49b17bef",
  "isSidechain": false,
  "promptId": "0bc1eef6-835a-4ee4-a8a1-06010792cb3b",
  "type": "user",
  "uuid": "b5ba2272-fe8d-4351-a66c-a69443df5b43",
  "toolUseResult": {
    "filenames": [],
    "durationMs": 32,
    "numFiles": 0,
    "truncated": false
  },
  "sourceToolAssistantUUID": "f5a02110-3667-4528-9797-154a49b17bef",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Tool call

_source line 783 · 2026-05-20T10:04:57.273Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01XJyPvZBfvWz3MDZrUmDuuX`</summary>

```json
{
  "query": "select:read_registry",
  "max_results": 1
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b5ba2272-fe8d-4351-a66c-a69443df5b43",
  "isSidechain": false,
  "requestId": "req_011CbDdcbEV9hxos9J9uDZfW",
  "type": "assistant",
  "uuid": "48ffb9a3-9dfd-45fd-ab7c-4c42f7f14745",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019FPkWiN4EYAf9Gxxquhnnz",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14267,
      "cache_read_input_tokens": 79928,
      "output_tokens": 242,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 14267,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 242,
          "cache_read_input_tokens": 79928,
          "cache_creation_input_tokens": 14267,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 14267
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

_source line 784 · 2026-05-20T10:05:00.688Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01R7c7HGaqrDNhHrya96RGqK`</summary>

```json
{
  "pattern": "**/paper-plan*.md",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "695f5b1a-d0af-43dc-884c-66d71e7b9823",
  "isSidechain": false,
  "requestId": "req_011CbDdd4s9kSa52sLjsK3Qp",
  "type": "assistant",
  "uuid": "4c6b73a2-116a-42ed-b16a-4fe744123e11",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HoekGCQUExV6rPs8TaQ2Xq",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 313,
      "cache_read_input_tokens": 94195,
      "output_tokens": 150,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 313,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 150,
          "cache_read_input_tokens": 94195,
          "cache_creation_input_tokens": 313,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 313
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

_source line 785 · 2026-05-20T10:05:00.723Z_

<details><summary>↩ Tool result · `toolu_01R7c7HGaqrDNhHrya96RGqK`</summary>

```text
No files found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "4c6b73a2-116a-42ed-b16a-4fe744123e11",
  "isSidechain": false,
  "promptId": "0bc1eef6-835a-4ee4-a8a1-06010792cb3b",
  "type": "user",
  "uuid": "564f295a-849b-4d81-8b48-0c0782332eb6",
  "toolUseResult": {
    "filenames": [],
    "durationMs": 31,
    "numFiles": 0,
    "truncated": false
  },
  "sourceToolAssistantUUID": "4c6b73a2-116a-42ed-b16a-4fe744123e11",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Tool call

_source line 786 · 2026-05-20T10:05:00.963Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_011H7tEDuUjEQjCKXvHMu11A`</summary>

```json
{
  "query": "read_registry",
  "max_results": 1
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "564f295a-849b-4d81-8b48-0c0782332eb6",
  "isSidechain": false,
  "requestId": "req_011CbDdd4s9kSa52sLjsK3Qp",
  "type": "assistant",
  "uuid": "7d6beb0a-5028-4234-b2af-50b71d6160a4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HoekGCQUExV6rPs8TaQ2Xq",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 313,
      "cache_read_input_tokens": 94195,
      "output_tokens": 150,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 313,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 150,
          "cache_read_input_tokens": 94195,
          "cache_creation_input_tokens": 313,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 313
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

_source line 787 · 2026-05-20T10:05:00.970Z_

<details><summary>↩ Tool result · `toolu_011H7tEDuUjEQjCKXvHMu11A`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__read_registry"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "7d6beb0a-5028-4234-b2af-50b71d6160a4",
  "isSidechain": false,
  "promptId": "0bc1eef6-835a-4ee4-a8a1-06010792cb3b",
  "type": "user",
  "uuid": "11b41c98-4dcf-4ab1-af8c-abbeae7082dc",
  "toolUseResult": {
    "matches": [
      "mcp__agent-ml-research__read_registry"
    ],
    "query": "read_registry",
    "total_deferred_tools": 51
  },
  "sourceToolAssistantUUID": "7d6beb0a-5028-4234-b2af-50b71d6160a4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Assistant

_source line 788 · 2026-05-20T10:05:04.087Z_

<details><summary>Logged reasoning block</summary>

```text
Let me now read the paper-plan skill from the global skills directory, and also get the registry data to understand what experiments we have.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "11b41c98-4dcf-4ab1-af8c-abbeae7082dc",
  "isSidechain": false,
  "requestId": "req_011CbDddLy2LkGGPN77wP76X",
  "type": "assistant",
  "uuid": "b1cdf85d-3920-4eb6-8523-eeb85b11046a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017qBqnquh2TCBdGgbvnrZuK",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 556,
      "cache_read_input_tokens": 94508,
      "output_tokens": 192,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 556,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 192,
          "cache_read_input_tokens": 94508,
          "cache_creation_input_tokens": 556,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 556
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

_source line 789 · 2026-05-20T10:05:05.081Z_

<details open><summary>🔧 Tool call — Glob · `toolu_011TV94RdYoqFSsKWbMfsDP1`</summary>

```json
{
  "pattern": "**/skills/**/paper-plan*",
  "path": "/home/ubuntu"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b1cdf85d-3920-4eb6-8523-eeb85b11046a",
  "isSidechain": false,
  "requestId": "req_011CbDddLy2LkGGPN77wP76X",
  "type": "assistant",
  "uuid": "7d4ac698-d6ba-4a14-abca-9ac151715f50",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017qBqnquh2TCBdGgbvnrZuK",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 556,
      "cache_read_input_tokens": 94508,
      "output_tokens": 192,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 556,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 192,
          "cache_read_input_tokens": 94508,
          "cache_creation_input_tokens": 556,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 556
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

_source line 790 · 2026-05-20T10:05:05.452Z_

<details><summary>↩ Tool result · `toolu_011TV94RdYoqFSsKWbMfsDP1`</summary>

```text
/home/ubuntu/agent-ml-research/skills/global/paper-plan.skill.md
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "7d4ac698-d6ba-4a14-abca-9ac151715f50",
  "isSidechain": false,
  "promptId": "0bc1eef6-835a-4ee4-a8a1-06010792cb3b",
  "type": "user",
  "uuid": "d97082ec-d79e-42e3-b12a-9745c6b02a26",
  "toolUseResult": {
    "filenames": [
      "/home/ubuntu/agent-ml-research/skills/global/paper-plan.skill.md"
    ],
    "durationMs": 366,
    "numFiles": 1,
    "truncated": false
  },
  "sourceToolAssistantUUID": "7d4ac698-d6ba-4a14-abca-9ac151715f50",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Tool call

_source line 791 · 2026-05-20T10:05:05.456Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_016gD1itUWFXZ3yfHMTNFtgU`</summary>

```json
{
  "project": "distrib_canary_collapse",
  "limit": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d97082ec-d79e-42e3-b12a-9745c6b02a26",
  "isSidechain": false,
  "requestId": "req_011CbDddLy2LkGGPN77wP76X",
  "type": "assistant",
  "uuid": "4620d78e-4233-4efc-9e7c-4d1b358f752b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017qBqnquh2TCBdGgbvnrZuK",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 556,
      "cache_read_input_tokens": 94508,
      "output_tokens": 192,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 556,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 192,
          "cache_read_input_tokens": 94508,
          "cache_creation_input_tokens": 556,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 556
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

_source line 792 · 2026-05-20T10:05:06.319Z_

<details><summary>↩ Tool result · `toolu_016gD1itUWFXZ3yfHMTNFtgU`</summary>

```text
Error: result (94,504 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-4-projects-distrib-canary-collapse--claude-sessions-paper-agent-73c709c0/71c5797e-c964-4419-a009-2e487a4de1fc/tool-results/mcp-agent-ml-research-read_registry-1779271506315.txt.
Format: JSON with schema: {result: string}
Use offset and limit parameters to read specific portions of the file, search within it for specific content, and jq to make structured queries.
REQUIREMENTS FOR SUMMARIZATION/ANALYSIS/REVIEW:
- You MUST read the content from the file at /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-4-projects-distrib-canary-collapse--claude-sessions-paper-agent-73c709c0/71c5797e-c964-4419-a009-2e487a4de1fc/tool-results/mcp-agent-ml-research-read_registry-1779271506315.txt in sequential chunks until 100% of the content has been read.
- If you receive truncation warnings when reading the file, reduce the chunk size until you have read 100% of the content without truncation.
- Before producing ANY summary or analysis, you MUST explicitly describe what portion of the content you have read. ***If you did not read the entire content, you MUST explicitly state this.***

```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "4620d78e-4233-4efc-9e7c-4d1b358f752b",
  "isSidechain": false,
  "promptId": "0bc1eef6-835a-4ee4-a8a1-06010792cb3b",
  "type": "user",
  "uuid": "7383800d-9a92-4720-b4d2-3601d06517c8",
  "toolUseResult": "Error: result (94,504 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-4-projects-distrib-canary-collapse--claude-sessions-paper-agent-73c709c0/71c5797e-c964-4419-a009-2e487a4de1fc/tool-results/mcp-agent-ml-research-read_registry-1779271506315.txt.\nFormat: JSON with schema: {result: string}\nUse offset and limit parameters to read specific portions of the file, search within it for specific content, and jq to make structured queries.\nREQUIREMENTS FOR SUMMARIZATION/ANALYSIS/REVIEW:\n- You MUST read the content from the file at /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-4-projects-distrib-canary-collapse--claude-sessions-paper-agent-73c709c0/71c5797e-c964-4419-a009-2e487a4de1fc/tool-results/mcp-agent-ml-research-read_registry-1779271506315.txt in sequential chunks until 100% of the content has been read.\n- If you receive truncation warnings when reading the file, reduce the chunk size until you have read 100% of the content without truncation.\n- Before producing ANY summary or analysis, you MUST explicitly describe what portion of the content you have read. ***If you did not read the entire content, you MUST explicitly state this.***\n",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"alpha_sweep_a045_s43_fp32\": {\"status\": \"ANALYZING\", \"created_at\": \"2026-05-20T05:49:23.885Z\", \"updated_at\": \"2026-05-20T09:59:10.878Z\", \"hypothesis\": \"Onset boundary cross-seed at α=0.45: s42 shows PermG=0/8 (blind zone, K3=3/8). If s43 also PermG=0/8 → onset > 0.45 is seed-robust, strengthening the [0.45, 0.50] onset claim. If s43 PermG>0 → onset is seed-sensitive at the boundary.\"}, \"alpha_sweep_a065_s42_fp32\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-20T09:34:26.984Z\", \"updated_at\": \"2026-05-20T09:34:27.743Z\", \"hypothesis\": \"D126 Track 3 dip recovery mapping: α=0.65 s42 fp32 填补 sync collapse dip(0.60)→detection recovery(0.75) 的过渡区。α=0.60 存在非单调 PermG dip，α=0.75 恢复到 6/8。α=0.65 确定恢复是渐进还是突变——如果 PermG 已恢复则 dip 仅限 [0.55,0.60]；如果仍被压制则 sync collapse 区扩展至 [0.55,0.65]。\", \"parent\": \"alpha_sweep_a060_s42_fp32_v4\"}, \"t20_a075_s42_fp32\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-20T09:34:23.102Z\", \"updated_at\": \"2026-05-20T09:34:24.160Z\", \"hypothesis\": \"D126 Track 1: T=20 extended generation at α=0.75 detection regime。T=11 下 PermG=6/8，T=20 提供 2× 数据点提升 Granger 统计功效。predict→verify 关键数据：理论预测 α≥0.75 在 detection regime 应展示最强最稳定的 PermG 信号，T=20 验证这一预测。当前 T=20 覆盖 α=0.50/0.60/1.00，α=0.75 是缺失的 detection boundary 数据点。\", \"parent\": \"alpha_sweep_a075_s42_fp32\"}, \"alpha_sweep_a055_s42_fp32\": {\"status\": \"RUNNING\", \"created_at\": \"2026-05-20T09:30:15.566Z\", \"updated_at\": \"2026-05-20T09:32:10.642Z\", \"hypothesis\": \"D126 Track 3 dip precision mapping: α=0.55 s42 fp32 填补 onset(0.50)→sync(0.60) 过渡区的关键缺失点。α=0.50 PermG=6/8，α=0.60 存在非单调 dip（T=11），α=0.55 确定 dip 起始位置——如果 PermG 仍为 6/8 则 dip 在 [0.55,0.60]；如果已下降则 onset→sync 过渡在 [0.50,0.55]。dose-response 精细刻画必需。\", \"parent\": \"alpha_sweep_a050_s42_fp32\"}, \"data_strategy_ablation_s43\": {\"status\": \"ANALYZING\", \"created_at\": \"2026-05-20T04:45:33.830Z\", \"updated_at\": \"2026-05-20T09:27:05.395Z\", \"hypothesis\": \"数据累积策略 ablation cross-seed：accumulate 模式 α=0.50 seed=43。验证 s42 结果（data_strategy_ablation_s42）的 seed robustness。如果 s42/s43 PermG 一致 → accumulate 效果 seed-robust；如果不同 → 策略效果 seed-sensitive。Baseline: alpha_sweep_a050_s43_fp32 (replace, PermG=6/8)。\", \"parent\": \"data_strategy_ablation_s42\", \"metrics\": {\"data_strategy\": \"accumulate\", \"baseline_exp\": \"alpha_sweep_a050_s43_fp32\"}}, \"gen_gpt2m_a100_s43_bf16\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T17:25:55.336Z\", \"updated_at\": \"2026-05-20T09:26:18.357Z\", \"hypothesis\": \"GPT-2-medium multi-seed s43: GPT-2-medium × WikiText-103 × α=1.0 × seed=43. Validates s42 cross-architecture results (K≥4=6/8) are reproducible.\", \"conclusion\": \"success\", \"metrics\": {\"token_entropy_gen0\": 3.6021, \"token_entropy_gen10\": 3.0035, \"token_entropy_delta_pct\": -16.6, \"distinct_1_gen0\": 0.1092, \"distinct_1_gen10\": 0.0724, \"distinct_1_delta_pct\": -33.7, \"distinct_2_delta_pct\": -39.6, \"distinct_3_delta_pct\": -33.5, \"ece_delta_pct\": 547.9, \"lead_lag\": {\"perm_granger_fdr_fwd\": \"0/8\", \"TY_granger_fwd\": \"3/8\", \"K_gte3\": \"0/8\", \"threshold_onset_3sigma\": \"0/8\", \"diff_xcorr_fdr_fwd\": \"N/A\"}, \"d120_canonical\": true, \"note\": \"M046 D120 canonical analysis on 17855. bf16 precision: PermG=0/8 vs fp32=6/8 (same config gen_gpt2m_a100_s43_fp32). bf16 stochastic rounding destroys causal signal completely.\"}}, \"generalize_pythia1b_c4_a100_s43_v2\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-20T09:19:05.335Z\", \"updated_at\": \"2026-05-20T09:19:05.335Z\", \"metrics\": {\"lead_lag\": {\"perm_granger_fdr_fwd\": \"8/8\", \"ty_granger_fwd\": \"4/8\", \"K_gte3\": \"6/8\", \"threshold_onset_3sigma\": \"2/8\", \"diff_xcorr_fdr_fwd\": \"8/8\"}, \"note\": \"M046 D120 canonical reanalysis: TY 2→4, K≥3 5→6\"}}, \"generalize_pythia14b_wiki_a100_s43\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T02:44:10.708Z\", \"updated_at\": \"2026-05-20T09:19:03.606Z\", \"hypothesis\": \"Pythia-1.4B s43 validates whether Scale row K>=4=5/8 is a systematic scale effect: if s43 also weak then scale is a real challenge, if s43 strong then s42 is seed noise\", \"parent\": \"generalize_pythia14b_wiki_a100_s42\", \"conclusion\": \"success\", \"metrics\": {\"lead_lag\": {\"perm_granger_fdr_fwd\": \"6/8\", \"ty_granger_fwd\": \"3/8\", \"K_gte3\": \"3/8\", \"threshold_onset_3sigma\": \"0/8\", \"diff_xcorr_fdr_fwd\": \"8/8\"}, \"note\": \"M046 D120 canonical reanalysis: TY 4→3, K≥3 7→3, Threshold 8→0\"}, \"notes\": \"D102 unified 8-pair. PermG fwd 6/8 stable. D102决策: Table 7 列出两seed, s42=2/8 vs s43=6/8 标注seed sensitivity.\"}, \"generalize_pythia14b_wiki_a100_s42\": {\"status\": \"DONE\", \"created_at\": \"2026-05-17T13:25:15.889Z\", \"updated_at\": \"2026-05-20T09:19:01.719Z\", \"hypothesis\": \"方法论陷阱跨 scale 泛化——Pythia-1.4B (同家族 410M→1.4B) 在 α=1.0 WikiText 上保持 consensus ≥4/5 的 canary→downstream 因果信号，证明框架不依赖特定模型规模\", \"metrics\": {\"lead_lag\": {\"perm_granger_fdr_fwd\": \"2/8\", \"ty_granger_fwd\": \"3/8\", \"K_gte3\": \"3/8\", \"threshold_onset_3sigma\": \"0/8\", \"diff_xcorr_fdr_fwd\": \"7/8\"}, \"note\": \"M046 D120 canonical reanalysis: TY 0→3, K≥3 1→3\"}, \"conclusion\": \"success\", \"notes\": \"D102 unified 8-pair. PermG fwd 2/8 (weakest Wiki model). D102决策: Table 7 主指标=PermG fwd, 辅助=K≥3. 报告cross-seed range: s42=2/8, s43=6/8, 标注seed sensitivity. Threshold σ统一=3σ(低优先级, 等训练完后统一重算).\"}, \"t20_a060_s42_fp32\": {\"status\": \"RUNNING\", \"created_at\": \"2026-05-20T09:16:22.779Z\", \"updated_at\": \"2026-05-20T09:16:59.815Z\", \"hypothesis\": \"T=20 extended generation at α=0.60: Tests whether the non-monotonic PermG dip at α=0.60 (observed in T=11) persists with longer time series. T=20 provides 2× more data points for Granger causality, potentially resolving whether the dip is real signal attenuation or statistical power issue.\", \"parent\": \"alpha_sweep_a060_s42_fp32_v4\"}, \"data_strategy_ablation_s42\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T04:27:03.682Z\", \"updated_at\": \"2026-05-20T09:16:06.145Z\", \"hypothesis\": \"数据累积策略（accumulate：每代叠加所有前几代生成文本）会通过缓冲训练数据多样性，减弱 canary→downstream 的 lead-lag 时序耦合，相比 replace 模式（每代只用上一代输出）降低 5-method 检测率。\", \"parent\": \"alpha_sweep_a050_s42_fp32\", \"metrics\": {\"accumulate_permg_fwd\": \"0/8\", \"replace_permg_fwd\": \"6/8\", \"accumulate_K_gte3\": \"0/8\", \"replace_K_gte3\": \"6/8\", \"accumulate_TY\": \"4/8\", \"replace_TY\": \"4/8\", \"accumulate_entropy_drift\": \"-2.4%\", \"replace_entropy_drift\": \"-16.3%\", \"accumulate_ece_drift\": \"+89%\", \"replace_ece_drift\": \"+703%\", \"accumulate_distinct1_drift\": \"-27%\", \"replace_distinct1_drift\": \"-29%\"}, \"conclusion\": \"success\"}, \"alpha_sweep_a060_s42_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T21:56:18.971Z\", \"updated_at\": \"2026-05-20T09:15:13.634Z\", \"hypothesis\": \"fp32 α=0.60 dose-response 主轴数据点: D079 要求 fp32 数据填补 dose-response map。与 alpha_sweep_a060_s42_bf16 完全相同配置，唯一区别 fp32 精度。bf16 的 stochastic rounding 系统性抑制 collapse 5-730x，fp32 数据是 Table 7 主轴必需。\", \"conclusion\": \"failed\", \"notes\": \"D080: torch_dtype=None bug → fp16 without GradScaler → NaN. Already failed.\"}, \"alpha_sweep_a005_s42\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T20:52:49.138Z\", \"updated_at\": \"2026-05-20T09:15:11.610Z\", \"hypothesis\": \"α=0.05 定位 diversity 悬崖精确位置: α=0.00 d1=-14% 到 α=0.10 d1=-40% 之间存在非线性断崖，α=0.05 确定断崖在 0-5% 还是 5-10% 区间。\", \"parent\": \"alpha_sweep_a010_s42_v2\", \"notes\": \"D080: torch_dtype=None bug → fp16 without GradScaler → NaN. Killed and resubmitting as v3\", \"conclusion\": \"failed\"}, \"interv_pred_a075_s42_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T21:57:16.554Z\", \"updated_at\": \"2026-05-20T09:15:09.775Z\", \"hypothesis\": \"fp32 predictive intervention at α=0.75 boundary: Canary-based intervention (entropy >15% drop triggers α=0.0 switch) in the transitional regime where Granger causality becomes FDR-significant. D079 requires fp32 for Table 7 comparability. Tests if predictive intervention can prevent collapse at moderate contamination.\", \"conclusion\": \"failed\", \"notes\": \"D080: torch_dtype=None bug → fp16 without GradScaler → NaN. Already failed.\"}, \"interv_pred_14b_s42_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T20:44:38.477Z\", \"updated_at\": \"2026-05-20T09:15:07.751Z\", \"hypothesis\": \"Cross-scale intervention validation: Tests if canary-based predictive intervention (token_entropy >15% drop → α=0.0) is effective at 1.4B scale. At 410M, intervention triggers Gen 1 and recovers by Gen 2. If 1.4B shows same pattern, validates scale-independence of canary utility (Claim 4).\", \"parent\": \"intervention_predictive_s42\", \"conclusion\": \"success\"}, \"t20_a050_s42_fp32\": {\"status\": \"RUNNING\", \"created_at\": \"2026-05-20T08:23:30.831Z\", \"updated_at\": \"2026-05-20T08:25:22.687Z\", \"hypothesis\": \"D126 战线1: T=20 extended generation 在 onset boundary α=0.50。T=10 下 PermG=6/8, K≥3=6/8。T=20 提供更多数据点：(1) PermG 统计功效提升 (2) 观察 onset 后 canary-downstream lag 是否随时间拉大或收敛。boundary regime 行为对 dose-response 精细刻画至关重要。\"}, \"t20_a100_s42_fp32\": {\"status\": \"RUNNING\", \"created_at\": \"2026-05-20T08:23:28.680Z\", \"updated_at\": \"2026-05-20T08:25:19.428Z\", \"hypothesis\": \"D126 战线1: T=20 extended generation 验证 canary lead-lag 在长序列下的演化。α=1.0 是最强信号点，T=20 下 PermG 应保持或增强（更多数据点提升统计功效）。如果 K≥3 在 gen 11-20 下降 → collapse 饱和后 canary 失效；如果保持 → 长期监控可行。\"}, \"qwen35_08b_wiki_a100_s43_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T17:12:33.701Z\", \"updated_at\": \"2026-05-20T08:02:50.957Z\", \"hypothesis\": \"Qwen3.5-0.8B s43 cross-seed 验证：s42 PermG=8/8, K≥3=8/8，验证这一极强信号的跨 seed 可复现性。唯一非 Pythia/GPT/OPT 家族，审稿人重点关注。\", \"parent\": \"qwen35_08b_wiki_a100_s42_v2\", \"notes\": \"EXIT_CODE=124 timeout. Parent s42 took 12.8h. Diagnosing: fix_worker_id: worker_diagnose_qwen35_08b_wiki_a100_s43_fp32_20260520T061050\", \"conclusion\": \"success\", \"metrics\": {\"PermG_fwd\": \"6/8\", \"PermG_rev\": \"0/8\", \"diff_xcorr_fdr\": \"6/8\", \"naive_xcorr\": \"6/8\", \"threshold_onset\": \"8/8\", \"TY_granger\": \"6/8\", \"K_ge3\": \"6/8\", \"K_ge4\": \"6/8\", \"d120_canonical\": true, \"note\": \"6 distinct_* pairs all K=5/5 (perfect). mauve pairs K=1/5 (peak_lag=+1, direction filter excluded). threshold_onset=8/8 strongest of any experiment.\"}}, \"scale_69b_a100_s43\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T18:03:25.659Z\", \"updated_at\": \"2026-05-20T08:01:04.011Z\", \"hypothesis\": \"Pythia-6.9B s43 cross-seed 验证：s42 PermG=7/8, K≥3=8/8（bf16+gradient_checkpointing），当前最强 Wiki 模型仅单 seed，审稿人可攻击可复现性。s43 bf16 匹配 s42 精度，验证跨 seed 稳健性。plan_028。\", \"parent\": \"scale_69b_a100_s42\", \"metrics\": {\"PermG_fwd\": \"6/8\", \"PermG_rev\": \"0/8\", \"diff_xcorr_fdr\": \"6/8\", \"naive_xcorr\": \"6/8\", \"threshold_onset\": \"0/8\", \"TY_granger\": \"0/8\", \"K_ge3\": \"6/8\", \"K_ge4\": \"0/8\", \"d120_canonical\": true, \"checkpoint_path\": \"/root/autodl-tmp/distrib_canary_collapse/results/scale_check/pythia69b_wiki_a100_s43/gen_10/checkpoint/\"}, \"conclusion\": \"success\", \"notes\": \"Cross-seed validation Pythia-6.9B bf16: s43 PermG=6/8 (vs s42 7/8), K≥3=6/8 (matches s42). PermG_rev=0/8 confirms directionality. D120 canonical. Both seeds confirm canary detection at 6.9B scale.\"}, \"qwen35_08b_wiki_a100_s42_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T00:28:45.037Z\", \"updated_at\": \"2026-05-20T07:33:37.960Z\", \"hypothesis\": \"D080 fix: Qwen3.5-0.8B fp32 cross-architecture validation. Resubmit with explicit .to(dtype=float32) cast after from_pretrained, because transformers 5.8.1 ignores dtype param for Qwen3.5 (loads bfloat16 from safetensors regardless).\", \"parent\": \"qwen35_08b_wiki_a100_s42\", \"conclusion\": \"success\", \"metrics\": {\"PermG_fwd\": \"8/8\", \"PermG_rev\": \"0/8\", \"diff_xcorr_fdr\": \"8/8\", \"naive_xcorr\": \"4/8\", \"threshold_onset\": \"0/8\", \"TY_granger\": \"6/8\", \"K_ge3\": \"6/8\", \"K_ge4\": \"3/8\", \"d120_canonical\": true, \"previous_K_ge3\": \"8/8\", \"note\": \"D120 canonical: K≥3 dropped 8/8→6/8. mauve pairs lost consensus. TY=6/8 strong contributor.\"}}, \"scale_69b_a100_s42\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T18:03:54.429Z\", \"updated_at\": \"2026-05-20T07:33:35.724Z\", \"hypothesis\": \"Pythia-6.9B α=1.0 s42: 17× scale-up verification of canary lead-lag phenomenon. Tests if entropy-leads-diversity pattern persists at 6.9B scale with gradient_checkpointing + bf16.\", \"conclusion\": \"success\", \"metrics\": {\"PermG_fwd\": \"7/8\", \"PermG_rev\": \"0/8\", \"diff_xcorr_fdr\": \"6/8\", \"naive_xcorr\": \"5/8\", \"threshold_onset\": \"2/8\", \"TY_granger\": \"1/8\", \"K_ge3\": \"5/8\", \"K_ge4\": \"0/8\", \"d120_canonical\": true, \"previous_K_ge3\": \"8/8\", \"note\": \"D120 canonical: K≥3 dropped 8/8→5/8. mauve pairs lost consensus. Core distinct_1/2/3 retained.\"}}, \"alpha_sweep_a060_s42_fp32_v4\": {\"status\": \"RUNNING\", \"created_at\": \"2026-05-20T07:24:33.768Z\", \"updated_at\": \"2026-05-20T07:25:48.938Z\", \"hypothesis\": \"D108 sync collapse 关键数据点: α=0.60 s42 fp32 标准版重跑（替代 v3_d080 变体，D125 决策排除不可溯源的 v3_d080）。α=0.60 位于 onset [0.45,0.50] 和 detection ≥0.75 之间的 sync collapse 过渡带，dose-response 精细刻画必需。使用与 a050_s42_fp32 完全相同的脚本和参数，仅改 α。\", \"parent\": \"alpha_sweep_a060_s42_fp32_v3\"}, \"scale_14b_c4_s42_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T22:26:29.074Z\", \"updated_at\": \"2026-05-20T07:21:16.204Z\", \"hypothesis\": \"D112 scale×domain cross: Pythia-1.4B × C4 × α=1.0 分离域效应 vs 规模效应。C4 在 410M 下 collapse 机制与 WikiText 不同（ppl-dominated, d1 仅 -4%）。1.4B 下如果 C4 仍 ppl-dominated → 域效应；如果转为 diversity-dominated → 规模效应。Claim 1 cross-domain scale validation.\", \"parent\": \"generalize_pythia1b_c4_a100_s42_v2\", \"conclusion\": \"success\", \"metrics\": {\"PermG_fwd\": \"8/8\", \"PermG_rev\": \"0/8\", \"diff_xcorr_fdr\": \"8/8\", \"naive_xcorr\": \"8/8\", \"threshold_onset\": \"0/8\", \"TY_granger\": \"0/8\", \"K_ge3\": \"8/8\", \"K_ge4\": \"0/8\", \"note\": \"D120 TY-fixed analysis. TY=0 due to T=11 low power (dmax=1, df_resid insufficient). Threshold=0 (signal too strong, all gens exceed threshold, no onset detectable).\"}}, \"padding_robustness_a100_s42_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T09:54:17.535Z\", \"updated_at\": \"2026-05-20T06:09:34.410Z\", \"hypothesis\": \"D093 padding_side='left' 修复后重跑 α=1.0 s42 fp32，对比修复前 mvp_v4_rep42 结果，验证 right-padding bug 对 collapse 轨迹和 lead-lag 信号的影响程度。预期：相对趋势不变，绝对数值可能有小幅差异\", \"metrics\": {\"PermG_fwd\": \"6/8\", \"PermG_rev\": \"0/8\", \"K_ge_3_3sigma\": \"6/8\", \"K_ge_4_3sigma\": \"0/8\", \"threshold_onset_3sigma\": \"0/8\", \"naive_xcorr\": \"6/8\", \"diff_xcorr\": \"6/8\", \"TY_granger\": \"N/A (signonly API error on 17855)\", \"D105_3sigma\": \"true 3sigma (std of full series)\", \"D111_direction\": \"peak_lag < 0 (C009 corrected)\", \"analysis_script\": \"run_5method_analysis_d102.py\", \"n_perm\": 5000, \"D120_recomputed\": \"2026-05-20\", \"D102_8pair\": \"canary=[token_entropy,ece] x downstream=[d1,d2,d3,mauve]\", \"failing_pairs\": \"token_entropy&lt;mauve (0/5), ece&lt;mauve (0/5)\", \"vs_wiki_baseline\": \"K3=6/8 matches generalize_pythia410m_wiki_a100_s42 (6/8). Both fail mauve pairs. Padding side has no detectable effect on lead-lag.\"}, \"conclusion\": \"success\"}, \"c4_a075_s42_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T14:37:54.299Z\", \"updated_at\": \"2026-05-20T06:09:30.290Z\", \"hypothesis\": \"Claim 2 cross-domain validation: canary lead-lag generalizes from WikiText to C4 at α=0.75 regime boundary, expecting PermG_fwd signal comparable to WikiText parent (6/8)\", \"parent\": \"alpha_sweep_a075_s42_fp32\", \"metrics\": {\"PermG_fwd\": \"8/8\", \"PermG_rev\": \"0/8\", \"K_ge_3_3sigma\": \"8/8\", \"K_ge_4_3sigma\": \"0/8\", \"threshold_onset_3sigma\": \"0/8\", \"naive_xcorr\": \"8/8\", \"diff_xcorr\": \"8/8\", \"TY_granger\": \"N/A (signonly API error on 17855)\", \"drift_token_entropy\": -35.32, \"drift_ece\": 2809.23, \"drift_perplexity\": 2152.6, \"drift_distinct_1\": -12.4, \"drift_distinct_2\": -15.41, \"drift_distinct_3\": -14.59, \"drift_mauve\": -42.26, \"drift_effective_rank\": 110.31, \"gen0_token_entropy\": 3.1094, \"D105_3sigma\": \"true 3sigma (std of full series)\", \"D111_direction\": \"peak_lag < 0 (C009 corrected)\", \"analysis_script\": \"run_5method_analysis_d102.py\", \"n_perm\": 5000, \"D120_recomputed\": \"2026-05-20\", \"D102_8pair\": \"canary=[token_entropy,ece] x downstream=[d1,d2,d3,mauve]\"}, \"conclusion\": \"success\"}, \"c4_a050_s42_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T14:37:57.965Z\", \"updated_at\": \"2026-05-20T06:09:25.116Z\", \"hypothesis\": \"bf16 precision destroys PermG causal signal at C4 α=0.50; fp32 rerun should recover non-zero PermG fwd if the 0/8 was a precision artifact rather than a true blind zone\", \"parent\": \"alpha_sweep_c4_a050_s42\", \"metrics\": {\"PermG_fwd\": \"8/8\", \"PermG_rev\": \"7/8\", \"K_ge_3_3sigma\": \"4/8\", \"K_ge_4_3sigma\": \"0/8\", \"threshold_onset_3sigma\": \"0/8\", \"naive_xcorr\": \"4/8\", \"diff_xcorr\": \"8/8\", \"TY_granger\": \"N/A (signonly API error on 17855)\", \"drift_token_entropy_pct\": -47.99, \"drift_ece_pct\": 3103.74, \"drift_perplexity_pct\": 2931.59, \"drift_d1_pct\": -9.78, \"drift_d2_pct\": -15.72, \"drift_d3_pct\": -17.75, \"drift_mauve_pct\": -54.25, \"gen0_token_entropy\": 3.109, \"D105_3sigma\": \"true 3sigma (std of full series)\", \"D111_direction\": \"peak_lag < 0 (C009 corrected)\", \"analysis_script\": \"run_5method_analysis_d102.py\", \"n_perm\": 5000, \"D120_recomputed\": \"2026-05-20\", \"D102_8pair\": \"canary=[token_entropy,ece] x downstream=[d1,d2,d3,mauve]\", \"note\": \"PermG bidirectional (fwd=8/8 rev=7/8) — unique to C4 cross-domain at α=0.50\"}, \"conclusion\": \"success\"}, \"c4_a025_s42_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T18:30:39.613Z\", \"updated_at\": \"2026-05-20T06:09:19.816Z\", \"hypothesis\": \"C4 跨域 onset 比较：WikiText onset ∈ (0.40, 0.50) 全部 PermG=0/8。C4 在 α=0.50 已是 8/8（fp32）。如果 C4 α=0.25 PermG>0 → C4 onset 显著低于 WikiText，跨域灵敏度差异是论文级发现。Claim 2 cross-domain。\", \"parent\": \"c4_a050_s42_fp32\", \"metrics\": {\"PermG_fwd\": \"0/8\", \"PermG_rev\": \"0/8\", \"K_ge_3_3sigma\": \"0/8\", \"K_ge_4_3sigma\": \"0/8\", \"threshold_onset_3sigma\": \"2/8\", \"naive_xcorr\": \"4/8\", \"diff_xcorr\": \"8/8\", \"TY_granger\": \"N/A (signonly API error on 17855)\", \"drift_token_entropy\": \"-53.01%\", \"drift_ece\": \"+3242.80%\", \"drift_perplexity\": \"+3617.05%\", \"drift_d1\": \"-4.10%\", \"drift_d2\": \"-8.78%\", \"drift_d3\": \"-11.95%\", \"drift_mauve\": \"-52.08%\", \"drift_effective_rank\": \"+111.90%\", \"D105_3sigma\": \"true 3sigma (std of full series)\", \"D111_direction\": \"peak_lag < 0 (C009 corrected)\", \"analysis_script\": \"run_5method_analysis_d102.py\", \"n_perm\": 5000, \"D120_recomputed\": \"2026-05-20\", \"D102_8pair\": \"canary=[token_entropy,ece] x downstream=[d1,d2,d3,mauve]\"}, \"conclusion\": \"success\"}, \"interv_pred_a075_s42\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T21:01:51.433Z\", \"updated_at\": \"2026-05-20T05:52:25.482Z\", \"hypothesis\": \"Predictive intervention at α=0.75 boundary regime: Tests if canary-based intervention (switch to α=0.0 when token_entropy drops >15%) can prevent collapse in the transitional regime. At α=0.75, Granger causality becomes FDR-significant (3/8 pairs). If predictive intervention triggers and recovers quality, it validates canary as actionable early warning even in moderate contamination.\", \"conclusion\": \"killed\"}, \"scale_14b_a050_s42_fp32\": {\"status\": \"RUNNING\", \"created_at\": \"2026-05-20T05:49:21.885Z\", \"updated_at\": \"2026-05-20T05:50:02.248Z\", \"hypothesis\": \"Pythia-1.4B at onset boundary α=0.50: tests if canary lead-lag persists at 1.4B scale in the boundary regime. 410M shows PermG=6/8 at α=0.50. If 1.4B also detects → onset boundary is scale-independent; if not → onset shifts with model size. Claim 1 cross-scale dose-response.\"}, \"pythia410m_wiki_a100_s43_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T19:07:43.365Z\", \"updated_at\": \"2026-05-20T04:28:18.111Z\", \"hypothesis\": \"Pythia-410M s43 cross-seed 验证：410M 是 dose-response 全部实验的 base model，但 Table 7 α=1.0 仅有 s42 单 seed（PermG=6/8, K≥3=6/8）。5/8 架构单 seed 是审稿攻击面。s43 验证 core model 的跨 seed 稳健性。Claim 1/3。\", \"parent\": \"generalize_pythia410m_wiki_a100_s42\", \"metrics\": {\"threshold_onset_3sigma_m037\": \"unknown→true_3sigma\", \"K3_3sigma_m037\": \"6/8\", \"K3_3sigma_d111_detail\": \"naive=6/8 diff=6/8 thr3s=0/8 pg=6/8 ty=6/8\", \"caveat\": \"xcorr recomputed from raw metrics without FDR\"}, \"conclusion\": \"success\"}, \"alpha_sweep_a050_postd093_s42_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T22:57:33.388Z\", \"updated_at\": \"2026-05-20T04:28:16.487Z\", \"hypothesis\": \"验证 α=0.50 PermG≥6/8 是否独立于 D093 padding 变更。如果 post-D093 仍 PermG≥6/8 → onset [0.45, 0.50] 稳健；如果 PermG=0/8 → onset 依赖 padding side，需要全面重审\", \"parent\": \"alpha_sweep_a050_s42_fp32\", \"conclusion\": \"success\", \"metrics\": {\"threshold_onset_3sigma_m037\": \"unknown→true_3sigma\", \"K3_3sigma_m037\": \"3/8\", \"K3_3sigma_d111_detail\": \"naive=3/8 diff=2/8 thr3s=0/8 pg=6/8 ty=4/8\"}}, \"generalize_pythia1b_c4_a100_s43\": {\"status\": \"DONE\", \"created_at\": \"2026-05-17T19:15:09.476Z\", \"updated_at\": \"2026-05-20T04:28:13.996Z\", \"hypothesis\": \"C4 域 multi-seed 验证——seed=43 下 Pythia-1B C4 α=1.0 是否复现 8/8 consensus 和 token_entropy 单向性 (rev=0/4)，确认 domain robustness 非单种子偶然\", \"parent\": \"generalize_pythia1b_c4_a100_s42_v2\", \"metrics\": {\"threshold_onset_3sigma_m037\": \"3x_sigma_drift→true_3sigma\", \"K3_3sigma_m037\": \"6/8\", \"K3_3sigma_d111_detail\": \"naive=4/8 diff=8/8 thr3s=2/8 pg=8/8 ty=4/8\"}, \"conclusion\": \"success\", \"notes\": \"D102 unified 8-pair. PermG fwd 8/8, rev 0/8 (perfect asymmetry). D102决策: Table 7 主指标=PermG fwd. Cross-seed confirms C4 robustness.\"}, \"opt13b_wiki_a100_s43_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T15:10:53.215Z\", \"updated_at\": \"2026-05-20T04:28:12.012Z\", \"hypothesis\": \"OPT-1.3B × WikiText-103 × α=1.0 × seed=43 × fp32 跨架构 multi-seed 验证。s42 已完成 K≥4=6/8，s43 验证跨 seed 稳健性。plan_030。\", \"parent\": \"gen_opt13b_a100_s43_bf16\", \"notes\": \"D103: s42 统一 pair K≥4=0/8。s43 验证 OPT 在统一配置下的 PermG/MMCT 表现。\", \"metrics\": {\"threshold_onset_3sigma_m037\": \"already_3sigma_d105\", \"K3_3sigma_m037\": \"6/8\", \"K3_3sigma_d111_detail\": \"naive=8/8 diff=6/8 thr3s=0/8 pg=6/8 ty=5/8\"}, \"conclusion\": \"success\"}, \"generalize_opt1b_wiki_a100_s42\": {\"status\": \"DONE\", \"created_at\": \"2026-05-17T07:08:23.938Z\", \"updated_at\": \"2026-05-20T04:28:10.446Z\", \"hypothesis\": \"Methodological pitfalls (FPR inflation from single-method reliance) generalize to OPT-1.3B architecture — different model family at α=1.0 should show same canary→downstream causal pattern as Pythia\", \"metrics\": {\"threshold_onset_3sigma_m037\": \"3x_sigma_drift→true_3sigma\", \"K3_3sigma_m037\": \"6/8\", \"K3_3sigma_d111_detail\": \"naive=7/8 diff=6/8 thr3s=2/8 pg=6/8 ty=0/8\"}, \"conclusion\": \"success\", \"notes\": \"D102 reanalysis: K≥4 dropped from 6/8 to 0/8 with unified pairs. →ppl inflation confirmed. PermG fwd 6/8 stable. pair_config: unified_8pair (ent/ece→d1/d2/d3/mauve).\"}, \"gen_gpt2m_a100_s43_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T23:45:29.110Z\", \"updated_at\": \"2026-05-20T04:28:09.194Z\", \"hypothesis\": \"GPT-2-medium multi-seed s43 fp32: Table 7 gap fill. GPT-2-medium × WikiText-103 × α=1.0 × seed=43 × fp32. Validates s42 cross-architecture canary lead-lag. D079 requires fp32 for main axis comparability.\", \"parent\": \"gen_wiki_gpt2m_a100_s42_v4\", \"metrics\": {\"threshold_onset_3sigma_m037\": \"3x_sigma_drift→true_3sigma\", \"K3_3sigma_m037\": \"6/8\", \"K3_3sigma_d111_detail\": \"naive=7/8 diff=6/8 thr3s=0/8 pg=6/8 ty=4/8\"}, \"conclusion\": \"success\", \"notes\": \"D102 qualified success: PermG fwd=6/8 (unified pairs), K≥4 不适用 (extreme collapse + mauve SNR不足), PermG rev=4/8 存在双向耦合但 fwd>rev. MMCT wpair=75%. Cross-seed consistent with s42.\"}, \"generalize_pythia410m_wiki_a100_s42\": {\"status\": \"DONE\", \"created_at\": \"2026-05-17T07:08:22.930Z\", \"updated_at\": \"2026-05-20T04:28:06.803Z\", \"hypothesis\": \"Methodological pitfalls (FPR inflation from single-method reliance) generalize across model architectures and data domains — Pythia-410M on WikiText α=1.0 should reproduce canary→downstream Granger signal with perfect directionality\", \"metrics\": {\"threshold_onset_3sigma_m037\": \"3x_sigma_drift→true_3sigma\", \"K3_3sigma_m037\": \"6/8\", \"K3_3sigma_d111_detail\": \"naive=7/8 diff=6/8 thr3s=2/8 pg=6/8 ty=1/8\"}, \"conclusion\": \"success\", \"notes\": \"D102 reanalysis: K≥4 0/8 (was 0/8, unchanged). PermG fwd 6/8 stable. DiffXCorr 8/8→6/8 (mauve pairs weak). pair_config: unified_8pair.\"}, \"c4_a050_s43_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T00:11:58.679Z\", \"updated_at\": \"2026-05-20T04:25:18.624Z\", \"hypothesis\": \"C4 α=0.50 cross-seed validation: s42 showed PermG=8/8, K≥3=6/8 (fp32). s43 tests seed robustness of C4 onset detection. If PermG≥6/8 → C4 onset at α=0.50 is seed-robust; if PermG drops significantly → C4 onset is seed-sensitive, weakening cross-domain claim.\", \"parent\": \"\", \"metrics\": {\"PermG_fwd\": \"8/8\", \"PermG_rev\": \"1/8\", \"K_ge_3_3sigma\": \"3/8\", \"K_ge_4_3sigma\": \"0/8\", \"threshold_onset_3sigma\": \"0/8\", \"naive_xcorr\": \"4/8\", \"diff_xcorr\": \"6/8\", \"TY_granger\": \"0/8\", \"drift_token_entropy\": -47.98, \"drift_ece\": 3102.5, \"drift_perplexity\": 2957.1, \"drift_distinct_1\": -9.9, \"drift_distinct_2\": -16, \"drift_distinct_3\": -17.5, \"drift_mauve\": -47.5, \"drift_effective_rank\": 113.4, \"gen0_token_entropy\": 3.1094, \"D111_direction_check\": \"applied: naive_xcorr peak_lag<0, diff_xcorr peak_lag<0\", \"D102_8pair\": \"canary=[token_entropy,ece] x downstream=[d1,d2,d3,mauve]\", \"D105_3sigma\": \"true 3sigma (std of full series)\", \"analysis_script\": \"run_5method_analysis_d102.py + D105 inline recompute\", \"n_perm\": 5000}, \"conclusion\": \"success\"}, \"c4_a075_s43_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-20T00:14:59.039Z\", \"updated_at\": \"2026-05-20T04:25:16.959Z\", \"hypothesis\": \"C4 α=0.75 cross-seed validation: s42 showed PermG=8/8, K≥3=6/8 (fp32, detection regime). s43 tests seed robustness. If PermG≥6/8 → C4 detection regime is seed-robust at α=0.75; combined with c4_a050_s43 → C4 dose-response has multi-seed coverage at both onset and detection α.\", \"parent\": \"c4_a075_s42_fp32\", \"metrics\": {\"PermG_fwd\": \"8/8\", \"PermG_rev\": \"0/8\", \"K_ge_3_3sigma\": \"8/8\", \"K_ge_4_3sigma\": \"1/8\", \"threshold_onset_3sigma\": \"0/8\", \"naive_xcorr\": \"8/8\", \"diff_xcorr\": \"8/8\", \"TY_granger\": \"1/8\", \"drift_token_entropy\": -34.12, \"drift_ece\": 2781.6, \"drift_perplexity\": 2149.2, \"drift_distinct_1\": -12.6, \"drift_distinct_2\": -16.2, \"drift_distinct_3\": -15.7, \"drift_mauve\": -52.8, \"drift_effective_rank\": 111, \"gen0_token_entropy\": 3.1094, \"D111_direction_check\": \"applied: naive_xcorr peak_lag<0, diff_xcorr peak_lag<0\", \"D102_8pair\": \"canary=[token_entropy,ece] x downstream=[d1,d2,d3,mauve]\", \"D105_3sigma\": \"true 3sigma (std of full series)\", \"analysis_script\": \"run_5method_analysis_d102.py + D105 inline recompute\", \"n_perm\": 5000}, \"conclusion\": \"success\"}, \"alpha_sweep_a075_s43\": {\"status\": \"DONE\", \"created_at\": \"2026-05-16T06:16:27.880Z\", \"updated_at\": \"2026-05-20T04:21:53.270Z\", \"notes\": \"第三次重启 (17:57 UTC)：第二次运行 (09:56-~17:00, Gen 0-7) 被另一 Agent 会话 kill+rm-rf+重启，~7h GPU 浪费。原因：并发 Agent 会话判断需重跑。当前为第三次运行，从 Gen 0 开始，预计 ~10-12h 完成。\", \"conclusion\": \"success\", \"metrics\": {\"gen0\": {\"token_entropy\": 3.234, \"ece\": 0.0108, \"perplexity\": 26.95, \"distinct_1\": 0.0983, \"distinct_2\": 0.5132, \"distinct_3\": 0.8057, \"effective_rank\": 46.61, \"mauve\": 0.0335}, \"gen10\": {\"token_entropy\": 2.349, \"ece\": 0.204, \"perplexity\": 76.08, \"distinct_1\": 0.0666, \"distinct_2\": 0.2984, \"distinct_3\": 0.4838, \"effective_rank\": 79.4, \"mauve\": 0.0289}, \"drift_pct\": {\"token_entropy\": -27.38, \"ece\": 1791.96, \"perplexity\": 182.3, \"distinct_1\": -32.3, \"distinct_2\": -41.86, \"distinct_3\": -39.96, \"effective_rank\": 70.36, \"mauve\": -13.63}, \"PermG_fwd\": \"5/8\", \"PermG_rev\": \"0/8\", \"naive_xcorr_fwd_D111\": \"2/8\", \"diff_xcorr_fwd_D111\": \"6/8\", \"threshold_onset_3sigma\": \"8/8\", \"TY_granger\": \"6/8\", \"K3_3sigma\": \"7/8\", \"K4_3sigma\": \"5/8\", \"perm_granger_fdr_forward_sig\": \"5/8\", \"D105_D111_compliant\": true, \"M035_direction\": \"peak_lag < 0\", \"precision\": \"fp32\", \"n_perm\": 5000, \"pair_config\": \"canary=[token_entropy,ece] x downstream=[distinct_1,distinct_2,distinct_3,mauve]\"}, \"hypothesis\": \"α=0.75 multi-seed 复现: Permutation Granger 因果信号（≥4/8 FDR sig forward, 0/8 reverse）在不同随机种子下稳定存在，确认 transitional regime 非单种子偶然\", \"parent\": \"alpha_sweep_a075_s42\"}, \"alpha_sweep_a050_s43_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T05:31:00.885Z\", \"updated_at\": \"2026-05-20T04:21:47.996Z\", \"hypothesis\": \"D091: α=0.50 fp32 s43 boundary regime. Pre-D080 data was fp16. fp32 rerun confirms PermG step function lower bound at boundary regime. 3-seed parallel with s42/s44.\", \"metrics\": {\"token_entropy_gen0\": 3.2342, \"token_entropy_gen10\": 2.7227, \"token_entropy_drift_pct\": -15.81, \"ece_gen0\": 0.0108, \"ece_gen10\": 0.0842, \"ece_drift_pct\": 679.56, \"distinct_1_gen0\": 0.0929, \"distinct_1_gen10\": 0.066, \"distinct_1_drift_pct\": -29, \"perplexity_gen0\": 26.95, \"perplexity_gen10\": 31.58, \"perplexity_drift_pct\": 17.17, \"mauve_drift_pct\": -23.54, \"PermG_fwd\": \"6/8\", \"PermG_rev\": \"0/8\", \"naive_xcorr_fwd_D111\": \"2/8\", \"diff_xcorr_fwd_D111\": \"6/8\", \"threshold_onset_3sigma\": \"8/8\", \"TY_granger\": \"5/8\", \"K3_3sigma\": \"6/8\", \"K4_3sigma\": \"5/8\", \"perm_granger_fdr_forward_sig\": \"6/8\", \"D105_D111_compliant\": true, \"M035_direction\": \"peak_lag < 0\", \"precision\": \"fp32\", \"n_perm\": 5000, \"pair_config\": \"canary=[token_entropy,ece] x downstream=[distinct_1,distinct_2,distinct_3,mauve]\"}, \"conclusion\": \"success\"}, \"alpha_sweep_a060_s43_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T12:20:24.931Z\", \"updated_at\": \"2026-05-20T04:20:56.820Z\", \"hypothesis\": \"α=0.60 同步坍缩区 cross-seed 验证：s42 PermG=3/8 (D108 non-monotonic dip)，s43 确认同步坍缩区 PermG 下降是否 seed-robust。如果 s43 也 PermG≤3/8 → 4-regime 结构中 α=0.60 dip 是机制性的；如果 s43 PermG≥6/8 → dip 是 seed-sensitive，需调整 regime boundary。\", \"parent\": \"alpha_sweep_a060_s42_fp32_v3\", \"conclusion\": \"success\", \"metrics\": {\"perm_granger_fwd_fdr\": \"0/8\", \"perm_granger_rev_fdr\": \"0/8\", \"consensus_k4_3sigma\": \"3/8\", \"consensus_k3_3sigma\": \"7/8\", \"threshold_onset_3sigma\": \"8/8\", \"naive_xcorr\": \"7/8\", \"diff_xcorr_fdr\": \"6/8\", \"ty_granger\": \"4/8\", \"drift_pct\": {\"token_entropy\": -28.61, \"distinct_1\": -31.02, \"distinct_2\": -39.02, \"distinct_3\": -37.3, \"ece\": 1530.81, \"perplexity\": 85.11, \"mauve\": -10.96, \"effective_rank\": 61}, \"gen0\": {\"token_entropy\": 3.234, \"perplexity\": 26.949, \"distinct_1\": 0.098}, \"gen9\": {\"token_entropy\": 2.309, \"perplexity\": 49.885, \"distinct_1\": 0.068}, \"note\": \"T=10 (gen_0-9, gen_10 timeout EXIT_CODE=124), D108 non-monotonicity confirmed\"}}, \"generalize_pythia1b_c4_a100_s42\": {\"status\": \"DONE\", \"created_at\": \"2026-05-17T07:08:24.826Z\", \"updated_at\": \"2026-05-20T02:32:36.379Z\", \"hypothesis\": \"Methodological pitfalls generalize across data domains — Pythia-1B on C4 (vs WikiText) at α=1.0 should reproduce canary→downstream causal pattern, proving domain-independence of the framework\", \"conclusion\": \"failed\", \"notes\": \"失败原因: hf-mirror.com 下载 Pythia-1B 权重时连接中断 (ChunkedEncodingError)，仅下载 7%。训练未开始，无可用数据。修复: 清理 .incomplete 缓存 → 预下载模型 → 重新提交。\", \"metrics\": {\"D102_reanalysis\": \"→mauve (replacing →ppl)\", \"pair_config\": \"canary=[token_entropy,ece] × downstream=[distinct_1,distinct_2,distinct_3,mauve]\", \"n_perm\": 5000, \"perm_granger_fdr_forward_sig\": \"8/8\", \"diff_xcorr_fdr_forward_sig\": \"8/8\", \"threshold_forward_sig\": \"8/8\", \"ty_forward_sig\": \"4/8\", \"robust_pairs_K3\": \"8/8\", \"robust_pairs_K4\": \"8/8\", \"D102_note\": \"ppl→mauve统一后: robust 2→8, perm_fdr 6→8, diff_fdr 6→8, ty 1→4.\", \"K_ge3_D116\": \"~1/8\", \"K_ge4_D116\": \"0/8\", \"D116_note\": \"D105+D111 joint: threshold JSON 3x_sigma_drift=8/8 but registry threshold_onset_3sigma=0/8 (M034). D111 kills diff_fwd. Reviewer estimate ~1/8.\"}}, \"alpha_sweep_a000_s42\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T19:01:37.470Z\", \"updated_at\": \"2026-05-20T00:12:04.092Z\", \"conclusion\": \"success\", \"metrics\": {\"gen0_token_entropy\": 3.2342, \"gen10_token_entropy\": 3.0693, \"gen0_ece\": 0.0108, \"gen10_ece\": 0.0164, \"gen0_perplexity\": 26.95, \"gen10_perplexity\": 21.11, \"gen0_distinct_1\": 0.0982, \"gen10_distinct_1\": 0.0847, \"token_entropy_drift_pct\": -5.1, \"ece_drift_pct\": 51.7, \"perplexity_drift_pct\": -21.7, \"distinct_1_drift_pct\": -13.8, \"distinct_2_drift_pct\": -9.8, \"distinct_3_drift_pct\": -4.5, \"gen1_10_perplexity_drift_pct\": 9.4, \"gen1_10_distinct_1_drift_pct\": -13.1, \"gen1_10_entropy_drift_pct\": 2.6}, \"notes\": \"D111 direction-checked. AUTHORITATIVE analysis dir: analysis/ (5method_leadlag.json). analysis_mauve/ is DEPRECATED — uses different threshold logic (canary_onset vs onset_canary field names), TY p-values diverge, results inconsistent with analysis/. All CSV artifacts and paper figures must source from analysis/ only. FPR: naive=6/8(0.750), diff=0/8, threshold=3/8(0.375), PermG=0/8, TY=1/8(0.125), K≥3=1/8(0.125).\"}, \"smollm3_3b_wiki_a100_s43_fp32\": {\"status\": \"RUNNING\", \"created_at\": \"2026-05-19T19:10:05.988Z\", \"updated_at\": \"2026-05-19T23:53:16.641Z\", \"hypothesis\": \"SmolLM3-3B 在 iterative self-distillation 下会表现出与 SmolLM2 类似的 distributional collapse 模式（熵递减、diversity 下降），验证 collapse 现象的模型规模泛化性。\", \"parent\": \"smollm3_3b_wiki_a100_s42_v3\"}, \"alpha_sweep_a075_s42_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T06:18:30.958Z\", \"updated_at\": \"2026-05-19T23:36:45.069Z\", \"hypothesis\": \"α=0.75 pre-D080 was fp16; fp32 rerun provides D079-compliant authoritative data. PermG expected ~83% (high regime), drift magnitude may change with fp32 precision.\", \"metrics\": {\"n_generations\": 11, \"gen0\": {\"token_entropy\": 3.2342, \"ece\": 0.0108, \"perplexity\": 26.949, \"distinct_1\": 0.098, \"distinct_2\": 0.5141, \"distinct_3\": 0.8127, \"effective_rank\": 46.613, \"mauve\": 0.0311}, \"gen10\": {\"token_entropy\": 2.283, \"ece\": 0.2145, \"perplexity\": 77.697, \"distinct_1\": 0.0731, \"distinct_2\": 0.357, \"distinct_3\": 0.5957, \"effective_rank\": 78.06, \"mauve\": 0.0299}, \"drift_pct\": {\"token_entropy\": -29.41, \"ece\": 1885.41, \"perplexity\": 188.31, \"distinct_1\": -25.38, \"distinct_2\": -30.55, \"distinct_3\": -26.7, \"effective_rank\": 67.47, \"mauve\": -3.73}, \"lead_lag\": {\"PermG_fwd\": \"6/8\", \"PermG_rev\": \"0/8\", \"K_ge_4\": \"6/8\", \"MMCT_detection\": 0.75, \"TY_granger\": \"8/8\", \"naive_xcorr\": \"7/8\", \"diff_xcorr\": \"6/8\", \"threshold_onset\": \"8/8\"}, \"asymmetry\": \"strong (fwd=6, rev=0)\"}, \"conclusion\": \"success\"}, \"alpha_sweep_a060_s42_fp32_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T00:22:51.958Z\", \"updated_at\": \"2026-05-19T23:36:42.935Z\", \"hypothesis\": \"D080 fix: fp32 α=0.60 dose-response (torch_dtype=float32). Resubmit with dtype bug fixed.\", \"parent\": \"alpha_sweep_a060_s42_fp32\", \"conclusion\": \"success\", \"metrics\": {\"final_ppl\": 45.41, \"final_entropy\": 2.48, \"final_eff_rank\": 69.3, \"final_mauve\": 0.023, \"precision\": \"fp32\", \"token_entropy_drift\": -23.36, \"ece_drift\": 1260.23, \"perplexity_drift\": 68.52, \"distinct_1_drift\": -28.17, \"distinct_2_drift\": -37.22, \"distinct_3_drift\": -35.35, \"perm_granger_fwd\": \"3/8\", \"perm_granger_rev\": \"0/8\", \"ty_granger_fwd\": \"8/8\", \"threshold_onset_fwd\": \"8/8\", \"consensus_k4\": \"7/8\", \"mmct_wpair_fwd\": 0.875}}, \"alpha_sweep_a050_s42_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T05:30:58.574Z\", \"updated_at\": \"2026-05-19T23:36:41.575Z\", \"hypothesis\": \"D091: α=0.50 fp32 s42 boundary regime. Pre-D080 data was fp16. fp32 rerun confirms PermG step function lower bound at boundary regime. 3-seed parallel with s43/s44.\", \"metrics\": {\"token_entropy_gen0\": 3.2342, \"token_entropy_gen10\": 2.7075, \"token_entropy_drift_pct\": -16.3, \"distinct_1_gen0\": 0.0916, \"distinct_1_gen10\": 0.0649, \"distinct_1_drift_pct\": -29.2, \"perplexity_gen0\": 26.95, \"perplexity_gen10\": 31.46, \"perplexity_drift_pct\": 16.8, \"ece_gen0\": 0.0108, \"ece_gen10\": 0.0868, \"ece_drift_pct\": 703.4, \"perm_granger_fwd\": \"6/8\", \"perm_granger_rev\": \"0/8\", \"ty_granger_fwd\": \"4/8\", \"consensus_k4\": \"6/8\", \"mmct_wpair_fwd\": \"6/8\", \"precision\": \"fp32\", \"n_perm\": 5000, \"padding_side\": \"right (D093 fix NOT applied)\"}, \"conclusion\": \"success\"}, \"alpha_sweep_a035_s42_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T14:37:56.167Z\", \"updated_at\": \"2026-05-19T23:36:39.700Z\", \"hypothesis\": \"D098 onset boundary 精化：α=0.35 预期仍在 blind zone。如果 PermG=0/8 → onset ≥ 0.35；如果 PermG>0 → onset 在 [0.30, 0.35]\", \"parent\": \"alpha_sweep_a030_s42_fp32\", \"conclusion\": \"success\", \"metrics\": {\"PermG_fwd\": \"0/8\", \"PermG_rev\": \"0/8\", \"K_ge3_3sigma\": \"6/8\", \"K_ge4_3sigma\": \"2/8\", \"threshold_onset\": \"8/8\", \"TY_granger\": \"4/8\", \"naive_xcorr_fwd\": \"8/8\", \"diff_xcorr_fwd\": \"4/8\", \"detection_rate_k4\": 0.25, \"drift_pct\": {\"token_entropy\": -18.53, \"ece\": 651.26, \"perplexity\": -1.27, \"distinct_1\": -36.38, \"distinct_2\": -49.45, \"distinct_3\": -50.04, \"effective_rank\": 22.21, \"mauve\": -17.78}, \"gen0\": {\"token_entropy\": 3.234, \"ece\": 0.0108, \"perplexity\": 26.95, \"distinct_1\": 0.098, \"distinct_2\": 0.514, \"distinct_3\": 0.813, \"effective_rank\": 46.61, \"mauve\": 0.0311}, \"gen10\": {\"token_entropy\": 2.635, \"ece\": 0.0812, \"perplexity\": 26.61, \"distinct_1\": 0.0623, \"distinct_2\": 0.26, \"distinct_3\": 0.406, \"effective_rank\": 56.96, \"mauve\": 0.0256}, \"consensus_detail\": {\"K4_pairs\": [\"token_entropy->distinct_1\", \"ece->distinct_1\"], \"K3_pairs\": [\"token_entropy->distinct_2\", \"token_entropy->mauve\", \"ece->distinct_2\", \"ece->mauve\"], \"K2_pairs\": [\"token_entropy->distinct_3\", \"ece->distinct_3\"]}, \"n_generations\": 11, \"precision\": \"fp32\", \"onset_conclusion\": \"PermG=0/8 confirms onset >= 0.35; combined with a040(0/8) and a050(6/8), onset in [0.40, 0.50]\"}}, \"alpha_sweep_a025_s42_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T06:18:27.981Z\", \"updated_at\": \"2026-05-19T23:36:37.721Z\", \"hypothesis\": \"At α=0.25 (boundary regime between 0.10 and 0.50), fp32 training will show PermG=0/8 because the synthetic data ratio is below the phase transition threshold for statistically detectable Granger-causal lead-lag structure\", \"metrics\": {\"PermG_fwd\": \"0/8\", \"PermG_rev\": \"0/8\", \"K_ge_4\": \"0/8\", \"MMCT\": \"0/8\", \"MMCT_detection_rate\": 0, \"d1_drift_pct\": -39.15, \"d2_drift_pct\": -54.75, \"d3_drift_pct\": -56.98, \"mauve_drift_pct\": -41.86, \"entropy_drift_pct\": -4.79, \"ece_drift_pct\": 79.17, \"ppl_drift_pct\": -18.09, \"eff_rank_drift_pct\": -3.78, \"ppl_by_gen\": [26.95, 19.39, 20.37, 20.75, 21.14, 21.3, 21.48, 21.88, 21.9, 22.25, 22.07], \"entropy_by_gen\": [3.234, 2.983, 3.015, 3.039, 3.051, 3.034, 3.049, 3.067, 3.063, 3.104, 3.079], \"d1_by_gen\": [0.098, 0.0976, 0.0815, 0.0737, 0.0688, 0.0657, 0.0635, 0.0614, 0.061, 0.0601, 0.0596], \"mauve_by_gen\": [0.0311, 0.0314, 0.0326, 0.0318, 0.0314, 0.0272, 0.0242, 0.0221, 0.0207, 0.0207, 0.0181], \"naive_xcorr_fwd\": \"8/8\", \"diff_xcorr_fwd\": \"3/8\", \"threshold_onset_fwd\": \"5/8\", \"ty_granger_sig\": \"3/8\", \"consensus_detail_max_votes\": 3, \"hypothesis_validated\": true, \"note\": \"PermG=0/8 confirms α=0.25 is below phase transition. d1_drift=-39.15% is surprisingly large (> α=0.50's -28.7%), suggesting diversity collapse proceeds without Granger-detectable lead-lag at this α. token_entropy→distinct_1 had raw PermG p=0.007 but FDR-corrected p=0.053 (borderline).\"}, \"conclusion\": \"success\"}, \"alpha_sweep_a010_s42_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T05:20:18.646Z\", \"updated_at\": \"2026-05-19T23:36:36.495Z\", \"hypothesis\": \"D083/D084 blind zone fp32 s42: α=0.10 canary blind zone dual-seed fp32 validation. a010_s43_fp32 confirmed PermG=0/8 (blind zone precision-invariant). s42 fp32 completes cross-seed stability check for D075 claim.\", \"parent\": \"alpha_sweep_a010_s42_v2\", \"conclusion\": \"success\", \"metrics\": {\"token_entropy_drift_pct\": -4.59, \"distinct_1_drift_pct\": -23.8, \"distinct_2_drift_pct\": -27.15, \"distinct_3_drift_pct\": -19.36, \"perplexity_drift_pct\": -18.94, \"perm_granger_fwd\": \"0/8\", \"perm_granger_rev\": \"0/8\", \"ty_granger_fwd\": \"3/8\", \"threshold_onset_fwd\": \"5/8\", \"consensus_k4\": \"2/8\", \"mmct_wpair_fwd\": \"2/8\", \"mmct_detection_rate\": 0.25, \"precision\": \"fp32\", \"padding_side_fix\": \"D093 applied\", \"blind_zone_confirmed\": true, \"cross_seed_permg_stable\": true}}, \"alpha_sweep_a005_s42_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T00:22:50.997Z\", \"updated_at\": \"2026-05-19T23:36:35.408Z\", \"hypothesis\": \"D080 fix: α=0.05 diversity cliff position (fp32, torch_dtype=float32). Resubmit of a005_s42 with dtype bug fixed.\", \"parent\": \"alpha_sweep_a005_s42\", \"conclusion\": \"success\", \"metrics\": {\"final_ppl\": 20.81, \"final_entropy\": 3.04, \"final_eff_rank\": 45.3, \"final_mauve\": 0.023, \"precision\": \"fp32\", \"token_entropy_drift\": -5.96, \"ece_drift\": 55.41, \"perplexity_drift\": -22.78, \"distinct_1_drift\": -24.86, \"distinct_2_drift\": -28.42, \"distinct_3_drift\": -19.54, \"perm_granger_fwd\": \"0/8\", \"perm_granger_rev\": \"0/8\", \"ty_granger_fwd\": \"3/8\", \"threshold_onset_fwd\": \"5/8\", \"consensus_k4\": \"0/8\", \"mmct_wpair_fwd\": 0}}, \"alpha_sweep_a010_s42_bf16\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-18T17:26:31.462Z\", \"updated_at\": \"2026-05-19T23:28:51.948Z\", \"hypothesis\": \"α=0.10 regime map gap fill with bf16: Pythia-410M WikiText s42 at synthetic_ratio=0.10. Tests whether near-zero contamination shows detectable canary signal.\", \"conclusion\": \"killed\"}, \"scale_14b_a050_s42_bf16\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-18T17:24:05.784Z\", \"updated_at\": \"2026-05-19T23:28:50.974Z\", \"hypothesis\": \"Pythia-1.4B α=0.50 s42 with bf16: Verifies whether canary lead-lag persists at 1.4B scale in the boundary regime (α=0.50). Tests if method sensitivity findings from 410M transfer to larger models.\", \"conclusion\": \"killed\"}, \"interv_react_s43\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-18T16:57:59.843Z\", \"updated_at\": \"2026-05-19T23:28:50.049Z\", \"hypothesis\": \"Intervention reactive multi-seed s43: Pythia-410M WikiText α=1.0, distinct_1 >10% drop trigger, switch to α=0.0. Validates s42 result (trigger Gen 2, recovery Gen 4) is reproducible across seeds.\", \"conclusion\": \"killed\"}, \"alpha_sweep_a040_s42_fp32_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T14:10:58.868Z\", \"updated_at\": \"2026-05-19T23:15:31.875Z\", \"hypothesis\": \"At α=0.40 synthetic ratio, Pythia-410M on WikiText should show onset of distributional canary collapse signal detectable before downstream quality degradation, helping narrow the onset boundary from [0.25, 0.50].\", \"parent\": \"alpha_sweep_a025_s42_fp32\", \"conclusion\": \"success\", \"metrics\": {\"PermG_fwd\": \"0/8\", \"PermG_rev\": \"0/8\", \"K4_3sigma\": \"0/8\", \"K3_3sigma\": \"1/8\", \"threshold_onset_3sigma\": \"8/8\", \"naive_xcorr\": \"4/8\", \"diff_xcorr\": \"0/8\", \"TY_granger\": \"4/8\", \"drift_token_entropy\": \"-19.13%\", \"drift_ece\": \"+736.90%\", \"drift_distinct1\": \"-35.48%\", \"drift_distinct2\": \"-48.01%\", \"drift_distinct3\": \"-48.42%\", \"drift_mauve\": \"-23.04%\", \"drift_perplexity\": \"+5.36%\", \"D111_direction_check\": \"applied: naive 8/8→4/8, diff 3/8→0/8, K3 6/8→1/8, K4 1/8→0/8\"}}, \"alpha_sweep_a030_s42_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T14:16:27.139Z\", \"updated_at\": \"2026-05-19T23:15:29.157Z\", \"hypothesis\": \"D098 onset boundary 精化：α=0.25 PermG=0/8, α=0.50 PermG=6/8。α=0.30 测试是否仍在 blind zone（预期 PermG=0/8），将 onset 下界从 0.25 收紧到 0.30。如果 PermG>0 则 onset 在 [0.25, 0.30]。\", \"parent\": \"alpha_sweep_a025_s42_fp32\", \"metrics\": {\"permg_fwd\": \"0/8\", \"permg_rev\": \"0/8\", \"k_ge3\": \"3/8\", \"k_ge4\": \"3/8\", \"naive_xcorr\": \"5/8\", \"diff_xcorr\": \"3/8\", \"threshold_onset\": \"8/8\", \"ty_granger\": \"5/8\", \"drift_entropy_pct\": -17.32, \"drift_ece_pct\": 549.38, \"drift_d1_pct\": -36.72, \"drift_d2_pct\": -49.75, \"drift_d3_pct\": -50.09, \"drift_mauve_pct\": -26.09, \"n_generations\": 11, \"n_perm\": 5000, \"D111_direction_check\": \"applied: naive 8/8→5/8, diff 4/8→3/8, K3 6/8→3/8, K4 unchanged 3/8\"}, \"conclusion\": \"success\"}, \"alpha_sweep_a045_s42_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T18:30:38.128Z\", \"updated_at\": \"2026-05-19T22:52:32.386Z\", \"hypothesis\": \"At α=0.45 (between blind α=0.40 and detected α=0.50), PermG fwd will be 0/8 if onset threshold is above 0.45, narrowing the onset boundary to [0.45, 0.50].\", \"parent\": \"alpha_sweep_a040_s42_fp32_v2\", \"metrics\": {\"permg_fwd\": 0, \"permg_rev\": 0, \"k_ge3\": 3, \"k_ge4\": 0, \"naive_xcorr\": 7, \"diff_xcorr\": 3, \"threshold_onset\": 8, \"ty_granger\": 1, \"total_pairs\": 8, \"drift_entropy_pct\": -18.73, \"drift_ece_pct\": 770.37, \"drift_d1_pct\": -35.39, \"drift_d2_pct\": -47.87, \"drift_d3_pct\": -47.79, \"drift_perplexity_pct\": 12.19, \"drift_mauve_pct\": -24.89, \"drift_effrank_pct\": 23.41, \"gen0_token_entropy\": 3.2342, \"gen10_token_entropy\": 2.6283, \"gen0_ece\": 0.0108, \"gen10_ece\": 0.094, \"gen0_distinct_1\": 0.098, \"gen10_distinct_1\": 0.0633, \"gen0_perplexity\": 26.949, \"gen10_perplexity\": 30.234, \"gen0_mauve\": 0.0311, \"gen10_mauve\": 0.0234, \"onset_boundary\": \"[0.45, 0.50]\"}, \"conclusion\": \"success\"}, \"method_ablation_phase3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T23:10:03.625Z\", \"updated_at\": \"2026-05-19T19:52:08.341Z\", \"hypothesis\": \"Phase 3 method ablation: 扩展 7 个 α 点（0.00-1.00）的 5 种检测方法 significance rate 矩阵，验证 permG/TY 在不同 contamination regime 下的灵敏度。\", \"conclusion\": \"success\", \"metrics\": {\"n_alpha_points\": 10, \"alphas\": [0, 0.05, 0.1, 0.25, 0.35, 0.4, 0.5, 0.6, 0.75, 1], \"naive_sig_rates\": [1, 0.875, 0.875, 1, 1, 1, 1, 0.875, 0.875, 1], \"diff_sig_rates\": [0.5, 0.375, 0.75, 0.375, 0.5, 0.375, 0.875, 1, 0.75, 0.75], \"thresh_3sigma_rates\": [0.5, 0.625, 0.625, 0.625, 1, 1, 1, 1, 1, 1], \"permG_fwd_rates\": [0, 0, 0, 0, 0, 0, 0.75, 0.375, 0.75, 0.75], \"permG_rev_rates\": [0, 0, 0, 0, 0, 0, 0, 0, 0, 0], \"TY_rates\": [0.25, 0.375, 0.375, 0.375, 0.5, 0.5, 0.5, 1, 1, 0.375], \"K_ge3_rates\": [0.375, 0.375, 0.5, 0.5, 0.75, 0.75, 0.875, 1, 0.875, 0.75], \"K_ge4_rates\": [0, 0, 0.25, 0, 0.25, 0.125, 0.75, 0.875, 0.75, 0.75], \"regime_structure\": {\"null\": \"alpha<=0.40: PermG=0%, naive=87-100% FPR. 11 data points all PermG=0/8\", \"onset\": \"alpha=[0.40,0.50]: PermG jumps 0→75%, K≥4 jumps 0→75%\", \"sync_collapse\": \"alpha=0.60: PermG drops to 37.5% (non-monotonic, D108). BUT K≥4 peaks at 87.5% — TY complements PermG (TY=100% here vs 50% at α=0.50). MMCT multi-method consensus strongest at this α\", \"detection\": \"alpha>=0.75: PermG=75%, TY non-monotonic drop to 37.5-100%\"}, \"claim3_support\": \"strong: 4-regime dose-response with non-monotonic PermG at α=0.60 (sync collapse) and TY complementarity. Method choice directly determines conclusion validity. PermG 0% FPR in null regime = cleanest discriminator.\", \"D105_standard\": \"3sigma + FDR BH + n_perm=5000 + unified 8-pair\"}}, \"smollm3_3b_wiki_a100_s42_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T00:24:12.263Z\", \"updated_at\": \"2026-05-19T19:46:57.358Z\", \"hypothesis\": \"D080 fix: SmolLM3-3B fp32 cross-architecture validation. Resubmit with torch_dtype=float32 to satisfy D079 fp32 requirement.\", \"parent\": \"smollm3_3b_wiki_a100_s42_v2\", \"conclusion\": \"negative\", \"metrics\": {\"PermG_fwd\": \"3/8\", \"PermG_rev\": \"0/8\", \"robust_pairs_K4_3sigma\": \"0/8\", \"robust_pairs_K3_3sigma\": \"0/8\", \"robust_pairs_K3_2sigma\": \"6/8\", \"robust_pairs_K4_2sigma\": \"3/8\", \"threshold_onset_3sigma\": \"0/8\", \"threshold_onset_2sigma\": \"8/8\", \"naive_xcorr\": \"4/8\", \"diff_xcorr\": \"6/8\", \"ty_granger\": \"0/8\", \"note\": \"D105+D111: FDR per-method, 3sigma, direction-checked. K≥3 corrected 3/8→0/8: 3sigma_recompute_v2 had naive_xcorr direction-blind bug (ECE pairs peak_lag<0 wrongly counted). Authoritative source: 5method_leadlag.json with peak_lag>0 check. PermG_fwd=3/8 (ECE→d1/d2/d3 via diff_xcorr+permG). naive_xcorr corrected 8/8→4/8 (entropy pairs only, ECE pairs all lag<0).\"}}, \"gen_gpt2m_a100_s43\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-18T16:58:48.288Z\", \"updated_at\": \"2026-05-19T19:07:04.842Z\", \"hypothesis\": \"GPT-2-medium multi-seed s43: GPT-2-medium × WikiText-103 × α=1.0 × seed=43. Validates s42 cross-architecture results (K≥4=6/8) are reproducible, confirming architecture-independent canary lead-lag.\", \"conclusion\": \"killed\"}, \"qwen35_dryrun_launch\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-18T21:31:44.039Z\", \"updated_at\": \"2026-05-19T19:07:02.672Z\", \"conclusion\": \"killed\"}, \"scale_69b_a100_s43_fp32\": {\"status\": \"PREPARING\", \"created_at\": \"2026-05-19T17:44:02.526Z\", \"updated_at\": \"2026-05-19T19:06:55.237Z\", \"hypothesis\": \"Pythia-6.9B s43 cross-seed 验证：s42 PermG=7/8, K≥3=8/8，当前最强 Wiki 模型仅单 seed，审稿人可攻击可复现性。s43 验证这一结果的跨 seed 稳健性。plan_028。\", \"parent\": \"scale_69b_a100_s42\", \"conclusion\": \"killed\"}, \"interv_react_s43_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T13:41:42.984Z\", \"updated_at\": \"2026-05-19T18:59:55.044Z\", \"hypothesis\": \"Reactive intervention multi-seed fp32: Pythia-410M α=1.0 s43, distinct_1 drop >10% trigger → switch α=0.0. Validates s42 reactive result (trigger Gen 2, recovery Gen 4) is reproducible. fp32 for D079 compliance.\", \"parent\": \"intervention_reactive_s42\", \"conclusion\": \"success\", \"metrics\": {\"trigger_gen\": 2, \"trigger_distinct1_drop_pct\": -15.83, \"gen2_ppl\": 158.22, \"recovery_ppl\": 21.98, \"recovery_complete_by_gen\": 3, \"intervention_metric\": \"distinct_1\", \"intervention_threshold\": 0.1, \"intervention_alpha\": 0, \"gen0\": {\"token_entropy\": 3.234, \"perplexity\": 26.949, \"distinct_1\": 0.098}, \"gen9\": {\"token_entropy\": 3.079, \"perplexity\": 21.357, \"distinct_1\": 0.089}, \"gen10\": {\"token_entropy\": 3.088, \"perplexity\": 21.387, \"distinct_1\": 0.083}, \"note\": \"reactive intervention triggered at gen2 (d1=0.083 < threshold=0.1), alpha 1.0→0.0; ppl spike 26.9→158.2 recovered by gen3 to 22.0; d1 partial recovery 0.098→0.083→0.089\"}}, \"generalize_pythia1b_c4_a100_s42_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-17T13:06:55.402Z\", \"updated_at\": \"2026-05-19T16:53:26.694Z\", \"hypothesis\": \"Methodological pitfalls generalize across data domains — Pythia-1B on C4 (vs WikiText) at α=1.0 should reproduce canary→downstream causal pattern, proving domain-independence of the framework (retry after download fix)\", \"parent\": \"generalize_pythia1b_c4_a100_s42\", \"conclusion\": \"success\", \"metrics\": {\"robust_pairs_K4_3sigma\": \"4/8\", \"robust_pairs_K3_3sigma\": \"8/8\", \"threshold_onset_3sigma\": \"0/8\", \"D105_3sigma_note\": \"D105 backfill: true 3sigma, fdr_permethod, unified 8-pair (canary={token_entropy,ece} x downstream={d1,d2,d3,mauve})\"}, \"notes\": \"D102 unified 8-pair. PermG fwd 8/8 (C4 mauve strong). D102决策: Table 7 主指标=PermG fwd. C4域最强信号.\"}, \"gen_wiki_gpt2m_a100_s42_v4\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T01:20:50.055Z\", \"updated_at\": \"2026-05-19T16:40:02.123Z\", \"hypothesis\": \"GPT-2-medium 重跑以产出可审计 artifact：用统一参数 (n_perm=5000, xcorr_lag=5) 验证跨架构泛化，填充 Table 7 GPT-2m 行\", \"parent\": \"\", \"metrics\": {\"robust_pairs_K4_3sigma\": \"2/8\", \"robust_pairs_K3_3sigma\": \"6/8\", \"threshold_onset_3sigma\": \"0/8\", \"D105_3sigma_note\": \"True 3sigma recompute. threshold_onset dropped 6/8->0/8. K4 dropped 6/8->2/8. PermG/TY unchanged.\"}, \"conclusion\": \"success\", \"notes\": \"D102: metrics updated to unified pair config (D101). K≥4 6/8→0/8 (old was inflated by →ppl). PermG fwd 6/8 unchanged. MMCT wpair 75%.\"}, \"alpha_sweep_a025_s43_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T06:18:28.979Z\", \"updated_at\": \"2026-05-19T15:02:43.632Z\", \"hypothesis\": \"D098 3-seed onset 确認：α=0.25 fp32 multi-seed 验证 s42 结果的 seed stability，确认 fp32 下 drift magnitude 和 PermG=0/8 跨 seed 稳定\", \"metrics\": {\"drift_pct\": {\"d1\": -38.95, \"d2\": -53.35, \"d3\": -54.8, \"entropy\": -4.94, \"ece\": 64.77, \"ppl\": -18.38, \"mauve\": -35.59, \"eff_rank\": -1.99}, \"gen0_abs\": {\"token_entropy\": 3.234, \"distinct_1\": 0.0983, \"perplexity\": 26.95, \"ece\": 0.0108}, \"gen10_abs\": {\"token_entropy\": 3.069, \"distinct_1\": 0.0595, \"perplexity\": 21.95, \"ece\": 0.0218}, \"lead_lag\": {\"perm_granger_fwd\": \"0/8\", \"perm_granger_rev\": \"0/8\", \"consensus_k4\": \"0/8\", \"mmct_detection_rate\": 0, \"ty_granger\": \"6/8\", \"naive_xcorr\": \"8/8\", \"threshold_onset\": \"4/8\"}, \"max_consensus_votes\": 3, \"precision\": \"fp32\", \"padding_side_fix\": \"D093 applied\"}, \"conclusion\": \"success\"}, \"alpha_sweep_a040_s42_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T14:07:24.253Z\", \"updated_at\": \"2026-05-19T14:34:26.016Z\", \"hypothesis\": \"D098 onset boundary 精化：与 α=0.30 配合将 phase transition onset 定位到 ±0.05 精度。α=0.40 预期仍在 blind zone 或刚进入 transition 区间。如果 PermG=0/8 → onset ≥ 0.40；如果 PermG>0 → onset 在 [0.30, 0.40]。\", \"parent\": \"alpha_sweep_a025_s42_fp32\", \"conclusion\": \"failed\"}, \"alpha_sweep_a025_s44_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T06:18:29.952Z\", \"updated_at\": \"2026-05-19T14:02:39.466Z\", \"hypothesis\": \"α=0.25 位于 canary-diversity lead-lag 的 blind zone 内，PermG 应为 0/8，因为低合成比例下 calibration drift 不足以产生可检测的 Granger 因果信号\", \"metrics\": {\"drift_pct\": {\"d1\": -38.35, \"d2\": -53.44, \"d3\": -55.35, \"entropy\": -4.11, \"ece\": 68.01, \"ppl\": -16.27, \"mauve\": -40.63, \"eff_rank\": -0.87}, \"gen0_abs\": {\"token_entropy\": 3.234, \"distinct_1\": 0.0974, \"perplexity\": 26.95, \"ece\": 0.0108}, \"gen9_abs\": {\"token_entropy\": 3.101, \"distinct_1\": 0.06, \"perplexity\": 22.57, \"ece\": 0.0182}, \"lead_lag\": {\"perm_granger_fwd\": \"0/8\", \"perm_granger_rev\": \"0/8\", \"consensus_k4\": \"0/8\", \"naive_xcorr\": \"8/8\", \"diff_xcorr\": \"0/8\", \"threshold_onset\": \"0/8\", \"ty_granger\": \"1/8\"}, \"mmct_detection_rate\": 0}, \"conclusion\": \"success\", \"notes\": \"D098 3-seed onset 第三个 seed。α=0.25 confirmed as blind zone upper bound. PermG=0/8, K≥4=0/8, MMCT=0.0 — consistent across all 3 seeds. d1 drift tightly clustered (-39.15%/-38.95%/-38.35%, σ=0.33pp). TY Granger seed-unstable (3→6→1/8), confirming C003.\"}, \"alpha_sweep_a050_s44_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T05:31:02.887Z\", \"updated_at\": \"2026-05-19T09:50:41.134Z\", \"hypothesis\": \"D091: α=0.50 fp32 s44 boundary regime. Pre-D080 data was fp16. fp32 rerun confirms PermG step function lower bound at boundary regime. 3-seed parallel with s42/s43.\", \"metrics\": {\"token_entropy_gen0\": 3.234, \"token_entropy_gen10\": 2.697, \"token_entropy_drift_pct\": -16.61, \"distinct_1_gen0\": 0.0915, \"distinct_1_gen10\": 0.066, \"distinct_1_drift_pct\": -27.93, \"distinct_2_drift_pct\": -34.64, \"distinct_3_drift_pct\": -30.6, \"ece_gen0\": 0.0108, \"ece_gen10\": 0.0874, \"ece_drift_pct\": 709.03, \"perplexity_gen0\": 26.949, \"perplexity_gen10\": 31.424, \"perplexity_drift_pct\": 16.61, \"effective_rank_drift_pct\": 25.06, \"mauve_drift_pct\": -13.88, \"naive_xcorr_fwd\": \"8/8\", \"diff_xcorr_fwd\": \"8/8\", \"threshold_onset_fwd\": \"8/8\", \"perm_granger_fwd\": \"6/8\", \"perm_granger_rev\": \"0/8\", \"ty_granger_fwd\": \"4/8\", \"consensus_k4\": \"6/8\", \"mmct_wpair_fwd\": 0.75, \"precision\": \"fp32\", \"n_perm\": 5000}, \"conclusion\": \"success\"}, \"interv_pred_a075_s42_fp32_v4\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T00:22:52.832Z\", \"updated_at\": \"2026-05-19T05:27:05.538Z\", \"hypothesis\": \"D080 fix: predictive intervention α=0.75 fp32 (torch_dtype=float32). Resubmit with dtype bug fixed.\", \"parent\": \"interv_pred_a075_s42_fp32\", \"conclusion\": \"success\", \"metrics\": {\"final_ppl\": 20.81, \"final_entropy\": 3.05, \"final_eff_rank\": 44.8, \"final_mauve\": 0.031, \"precision\": \"fp32\", \"intervention_trigger_gen\": 1, \"recovery_gen\": 2, \"token_entropy_drift\": -5.74, \"ece_drift\": 55.78, \"perplexity_drift\": -22.76, \"distinct_1_drift\": -7.97, \"distinct_2_drift\": -5.22, \"distinct_3_drift\": -3.9, \"perm_granger_fwd\": \"6/8\", \"perm_granger_rev\": \"0/8\", \"ty_granger_fwd\": \"8/8\", \"threshold_onset_fwd\": \"0/8\", \"consensus_k4\": \"6/8\", \"mmct_wpair_fwd\": 0.75}}, \"alpha_sweep_a010_s43_fp32\": {\"status\": \"DONE\", \"created_at\": \"2026-05-19T00:39:09.725Z\", \"updated_at\": \"2026-05-19T05:07:17.324Z\", \"hypothesis\": \"α=0.10 dose-response fp32 multi-seed (s43): D083 requires cross-seed variance for fp32 main axis. α=0.10 is the canary blind zone boundary (D075: entropy canary shows NO signal despite -39.7% diversity collapse). fp32 s43 validates whether this blind zone is seed-invariant.\", \"parent\": \"alpha_sweep_a010_s43\", \"conclusion\": \"success\", \"metrics\": {\"token_entropy_drift\": -4.49, \"distinct_1_drift\": -22.08, \"distinct_2_drift\": -23.47, \"distinct_3_drift\": -16.39, \"perplexity_drift\": -18.04, \"perm_granger_fwd\": \"0/8\", \"perm_granger_rev\": \"0/8\", \"ty_granger_fwd\": \"6/8\", \"threshold_onset_fwd\": \"4/8\", \"consensus_k4\": \"0/8 (C003 corrected)\", \"precision\": \"fp32\", \"blind_zone_confirmed_fp32\": true, \"vs_bf16_note\": \"fp32 reduces drift ~2x but does not change detection failure (PermG=0/8, k4=0/8 same as bf16)\"}}, \"alpha_sweep_a060_s42_fp32_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T22:11:35.152Z\", \"updated_at\": \"2026-05-19T01:34:42.831Z\", \"hypothesis\": \"fp32 α=0.60 dose-response 主轴数据点: D079 要求 fp32 数据填补 dose-response map。与 alpha_sweep_a060_s42_bf16 完全相同配置，唯一区别 fp32 精度。bf16 的 stochastic rounding 系统性抑制 collapse 5-730x，fp32 数据是 Table 7 主轴必需。\", \"parent\": \"\", \"conclusion\": \"killed\", \"notes\": \"D080: torch_dtype=None bug. Killed for code fix\"}, \"alpha_sweep_a010_s43\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T20:31:10.893Z\", \"updated_at\": \"2026-05-19T00:45:43.701Z\", \"hypothesis\": \"α=0.10 multi-seed s43: Validates D075 canary blind zone finding (α=0.10 diversity collapse saturated at -39.7% but entropy canary shows no signal). Single-seed → confirmed if s43 replicates same pattern.\", \"conclusion\": \"success\", \"metrics\": {\"token_entropy_drift\": -13.1, \"ece_drift\": -61.1, \"perplexity_drift\": -38.9, \"distinct_1_drift\": -29.1, \"distinct_2_drift\": -40.3, \"distinct_3_drift\": -31.9, \"effective_rank_drift\": 23.5, \"mauve_drift\": -46.3, \"naive_xcorr_fwd\": \"7/8\", \"diff_xcorr_fwd\": \"8/8\", \"threshold_onset_fwd\": \"3/8\", \"perm_granger_fwd\": \"0/8\", \"perm_granger_rev\": \"0/8\", \"ty_granger_fwd\": \"0/8\", \"k_gte4\": \"0/8\"}}, \"qwen35_08b_wiki_a100_s42\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T20:52:52.006Z\", \"updated_at\": \"2026-05-19T00:28:40.620Z\", \"hypothesis\": \"Qwen3.5-0.8B cross-architecture validation: 第5个独立架构族(Alibaba Qwen3.5, hybrid linear+full attention), WikiText-103 α=1.0 s42. 验证 canary lead-lag 是否跨架构泛化。\", \"conclusion\": \"killed\", \"notes\": \"D080: torch_dtype/dtype param ignored by Qwen3.5 in transformers 5.8.1 — model loads as bfloat16 regardless. Killed and restarting with patched code (explicit .to(dtype=target_dtype) after from_pretrained).\"}, \"smollm3_3b_wiki_a100_s42_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T21:54:58.834Z\", \"updated_at\": \"2026-05-19T00:24:45.562Z\", \"hypothesis\": \"SmolLM3-3B fp32 cross-architecture validation: 6th independent architecture family (HuggingFace SmolLM3, 3.08B params, 128K vocab). Tests if entropy-leads-diversity canary pattern transfers. D079 requires fp32 for Table 7 main axis comparability.\", \"conclusion\": \"failed\", \"notes\": \"D080: torch_dtype=None → loaded as bfloat16 (native), not fp32 as D079 requires. Data invalid. Kill and restart with fixed code.\"}, \"scale_14b_a050_s42\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T16:34:35.480Z\", \"updated_at\": \"2026-05-19T00:21:09.604Z\", \"hypothesis\": \"Pythia-1.4B α=0.50 scale spot-check: Verifies whether canary lead-lag persists at 1.4B scale in the boundary regime (α=0.50). Tests if method sensitivity findings from 410M transfer to larger models.\", \"conclusion\": \"success\", \"metrics\": {\"token_entropy_g0\": 2.946, \"token_entropy_g10\": 2.227, \"token_entropy_drift_pct\": -24.4, \"distinct_1_g0\": 0.0993, \"distinct_1_g10\": 0.0636, \"distinct_1_drift_pct\": -36, \"distinct_2_g0\": 0.521, \"distinct_2_g10\": 0.262, \"distinct_2_drift_pct\": -49.7, \"distinct_3_g0\": 0.813, \"distinct_3_g10\": 0.408, \"distinct_3_drift_pct\": -49.8, \"perplexity_g0\": 19.68, \"perplexity_g10\": 35.14, \"perplexity_drift_pct\": 78.6, \"mauve_g0\": 0.033, \"mauve_g10\": 0.024, \"mauve_drift_pct\": -28.2, \"ece_g0\": 0.007, \"ece_g10\": 0.153, \"effective_rank_g0\": 50.76, \"effective_rank_g10\": 82.21, \"num_generations\": 11}}, \"conditional_granger_d061\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T22:49:34.807Z\", \"updated_at\": \"2026-05-18T23:45:27.746Z\", \"hypothesis\": \"Conditional Granger analysis: 控制 ECE 后测 token_entropy→diversity，控制 token_entropy 后测 ECE→diversity。验证两个 canary 是否提供独立信息。\", \"conclusion\": \"success\"}, \"interv_pred_a075_s42_fp32_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T23:22:16.709Z\", \"updated_at\": \"2026-05-18T23:24:17.150Z\", \"hypothesis\": \"Predictive intervention (token_entropy threshold 0.15) at synthetic_ratio=0.75 will prevent collapse compared to no-intervention baseline. v2 resubmit with metrics.py LinAlgError fix.\", \"parent\": null, \"conclusion\": \"killed\"}, \"interv_pred_s43_bf16\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T18:03:58.328Z\", \"updated_at\": \"2026-05-18T21:59:45.463Z\", \"hypothesis\": \"Intervention predictive multi-seed s43 (bf16): Pythia-410M WikiText α=1.0, token_entropy >15% drop trigger, switch to α=0.0. Validates s42 result (trigger Gen 1, recovery Gen 2) is reproducible across seeds.\", \"conclusion\": \"success\", \"metrics\": {\"trigger_gen\": 1, \"trigger_entropy_drop_pct\": -22.54, \"gen0_ppl\": 27.68, \"gen0_entropy\": 3.2574, \"gen0_distinct_1\": 0.0917, \"gen0_ece\": 0.0123, \"gen1_ppl\": 24.65, \"gen1_entropy\": 2.5233, \"gen1_distinct_1\": 0.0897, \"gen1_ece\": 0.0469, \"gen2_ppl\": 17.49, \"gen2_entropy\": 2.9029, \"gen10_ppl\": 16.68, \"gen10_entropy\": 2.8169, \"gen10_eff_rank\": 58.8, \"gen10_mauve\": 0.0299, \"recovery_complete_by_gen\": 2, \"converges_to_alpha0_baseline\": true, \"precision_note\": \"bf16; collapse milder than fp32 s42 (entropy drop 22.54% vs 40.71%, ppl 24.65 vs 56.99) due to stochastic rounding regularization. Core pattern (G1 trigger, G2 recovery) confirmed.\", \"cross_seed_note\": \"s42(fp32): trigger G1 entropy -40.71%, ppl spike 56.99. s43(bf16): trigger G1 entropy -22.54%, no ppl spike. Pattern consistent, magnitude differs due to precision.\"}}, \"smollm3_3b_wiki_a100_s42\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T21:14:35.317Z\", \"updated_at\": \"2026-05-18T21:54:45.986Z\", \"hypothesis\": \"SmolLM3-3B cross-architecture validation: 6th independent architecture family (HuggingFace SmolLM3, 3.08B params, 128K vocab, 2025-07 release). Tests if entropy-leads-diversity canary pattern transfers to a recent 3B-scale model. Paired with Qwen3.5-0.8B to cover both 0.8B and 3B parameter scales for modern architectures.\", \"conclusion\": \"killed\"}, \"interv_react_s43_bf16\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T17:26:47.159Z\", \"updated_at\": \"2026-05-18T21:53:48.772Z\", \"hypothesis\": \"Intervention reactive multi-seed s43: Pythia-410M WikiText α=1.0, distinct_1 >10% drop trigger, switch to α=0.0. Validates s42 reactive result.\", \"conclusion\": \"success\"}, \"alpha_sweep_a060_s42_bf16\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T17:26:43.407Z\", \"updated_at\": \"2026-05-18T21:21:41.457Z\", \"hypothesis\": \"α=0.60 regime map with bf16: Fills gap between α=0.50 (boundary, high seed variance) and α=0.75 (3/8 FDR-sig). Pinpoints detectability threshold.\", \"conclusion\": \"success\", \"metrics\": {\"gen0\": {\"token_entropy\": 3.2574, \"ece\": 0.0123, \"perplexity\": 27.68, \"distinct_1\": 0.0914, \"distinct_2\": 0.5043, \"distinct_3\": 0.8329}, \"gen10\": {\"token_entropy\": 2.6404, \"ece\": 0.0426, \"perplexity\": 20.27, \"distinct_1\": 0.0663, \"distinct_2\": 0.3157, \"distinct_3\": 0.5707}, \"drift_pct\": {\"token_entropy\": -18.9, \"ece\": 246.5, \"perplexity\": -26.8, \"distinct_1\": -27.5, \"distinct_2\": -37.4, \"distinct_3\": -31.5}, \"lead_lag_unified_2sigma\": {\"naive_xcorr_fwd\": \"8/8\", \"diff_xcorr_fwd\": \"8/8\", \"threshold_onset_fwd\": \"6/8\", \"perm_granger_fwd\": \"8/8\", \"perm_granger_rev\": \"0/8\", \"ty_granger_fwd\": \"0/8\", \"consensus_K4\": \"6/8\"}, \"mmct\": {\"uniform_forward\": \"0/8\", \"uniform_bidirectional\": \"0/8\", \"weighted_pair_forward\": \"6/8\", \"weighted_pair_bidirectional\": \"6/8\", \"weighted_global_forward\": \"0/8\", \"weighted_global_bidirectional\": \"0/8\"}}}, \"alpha_sweep_c4_a050_s42_bf16\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T17:26:50.191Z\", \"updated_at\": \"2026-05-18T20:54:50.198Z\", \"hypothesis\": \"C4 α=0.50 cross-domain with bf16: Pythia-410M C4 at synthetic_ratio=0.50. Validates whether canary ranking and regime boundary transfer from WikiText to C4 domain.\", \"conclusion\": \"success\", \"metrics\": {\"token_entropy_gen0\": 3.136, \"token_entropy_gen10\": 1.94, \"token_entropy_delta_pct\": -38.2, \"distinct_1_gen0\": 0.111, \"distinct_1_gen10\": 0.089, \"distinct_1_delta_pct\": -20.3, \"perplexity_gen0\": 24.4, \"perplexity_gen10\": 122.8, \"perplexity_delta_pct\": 402, \"mauve_gen0\": 0.691, \"mauve_gen10\": 0.078, \"ece_gen0\": 0.011, \"ece_gen10\": 0.259, \"diff_xcorr_te_d1_lag\": 1, \"diff_xcorr_te_d1_r\": 0.914, \"permg_fwd_fdr_sig\": \"0/8\", \"permg_rev_fdr_sig\": \"0/8\"}}, \"gen_opt13b_a100_s43_bf16\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T20:29:50.031Z\", \"updated_at\": \"2026-05-18T20:31:14.879Z\", \"hypothesis\": \"OPT-1.3B multi-seed s43 bf16: facebook/opt-1.3b × WikiText-103 × α=1.0 × seed=43. Validates cross-architecture canary lead-lag at 1.3B scale (Meta OPT family, 6th architecture).\", \"conclusion\": \"killed\"}, \"alpha_sweep_a010_s42_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T14:55:45.450Z\", \"updated_at\": \"2026-05-18T19:55:24.464Z\", \"hypothesis\": \"α=0.10 regime map gap fill: Pythia-410M WikiText s42 at synthetic_ratio=0.10 (between 0.00 pure-real and 0.25). Tests whether the near-zero contamination regime shows detectable canary signal or behaves like null control, establishing the lower detection boundary for the dose-response curve.\", \"conclusion\": \"negative\"}, \"interv_pred_s43\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T16:33:43.711Z\", \"updated_at\": \"2026-05-18T18:43:15.800Z\", \"hypothesis\": \"Intervention predictive multi-seed s43: Pythia-410M WikiText α=1.0, token_entropy >15% drop trigger, switch to α=0.0. Validates s42 result (trigger Gen 1, recovery Gen 2) is reproducible across seeds.\", \"conclusion\": \"killed\"}, \"alpha_sweep_c4_a050_s42\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T16:33:48.244Z\", \"updated_at\": \"2026-05-18T18:43:14.860Z\", \"hypothesis\": \"C4 α=0.50 cross-domain: Pythia-410M C4 at synthetic_ratio=0.50. Validates whether canary ranking and regime boundary transfer from WikiText to C4 domain.\", \"conclusion\": \"killed\"}, \"alpha_sweep_a060_s42_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T16:33:46.539Z\", \"updated_at\": \"2026-05-18T18:43:13.901Z\", \"hypothesis\": \"α=0.60 regime map: Pythia-410M WikiText s42 at synthetic_ratio=0.60. Fills gap between α=0.50 (boundary, high seed variance) and α=0.75 (3/8 FDR-sig). Pinpoints detectability threshold.\", \"conclusion\": \"killed\"}, \"intervention_predictive_s42\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T11:31:03.869Z\", \"updated_at\": \"2026-05-18T16:33:33.782Z\", \"hypothesis\": \"Predictive intervention: monitoring token_entropy drop >15% as early-warning trigger, switching α from 1.0 to 0.0 at trigger generation. Tests whether canary-triggered intervention halts collapse earlier than reactive (downstream-triggered) intervention, demonstrating canary's practical utility.\", \"conclusion\": \"success\", \"metrics\": {\"trigger_gen\": 1, \"trigger_entropy_drop_pct\": -40.71, \"gen0_ppl\": 26.95, \"gen0_entropy\": 3.234, \"gen0_distinct_1\": 0.0982, \"gen0_ece\": 0.0108, \"gen1_ppl\": 56.99, \"gen1_entropy\": 1.918, \"gen1_distinct_1\": 0.0975, \"gen1_ece\": 0.205, \"gen2_ppl\": 20.81, \"gen2_entropy\": 3.055, \"gen10_ppl\": 21.29, \"gen10_entropy\": 3.079, \"gen10_eff_rank\": 44.1, \"gen10_mauve\": 0.0272, \"recovery_complete_by_gen\": 2, \"vs_reactive_trigger_advantage\": \"1 gen earlier\", \"vs_reactive_peak_ppl_reduction\": \"63% (56.99 vs 157.09)\", \"vs_reactive_recovery_advantage\": \"1 gen faster (Gen 2 vs Gen 4)\", \"converges_to_alpha0_baseline\": true}}, \"intervention_reactive_s42\": {\"status\": \"DONE\", \"created_at\": \"2026-05-18T10:25:52.494Z\", \"updated_at\": \"2026-05-18T14:54:52.686Z\", \"hypothesis\": \"Reactive intervention baseline: monitoring distinct_1 drop >10% as trigger, switching α from 1.0 to 0.0 at trigger generation. Tests whether downstream-triggered intervention (without canary) can halt collapse, serving as comparison for predictive (canary-triggered) intervention.\", \"conclusion\": \"success\", \"metrics\": {\"trigger_gen\": 2, \"trigger_distinct1_drop_pct\": -15.58, \"gen0_distinct_1\": 0.0982, \"gen0_ppl\": 26.95, \"gen0_entropy\": 3.234, \"gen2_distinct_1\": 0.0823, \"gen2_ppl\": 157.09, \"gen2_entropy\": 1.478, \"gen10_distinct_1\": 0.0844, \"gen10_ppl\": 21.24, \"gen10_entropy\": 3.071, \"gen10_ece\": 0.0152, \"gen10_mauve\": 0.0289, \"distinct_1_drift_pct\": -14.1, \"ppl_drift_pct\": -21.2, \"entropy_drift_pct\": -5, \"vs_no_intervention_ppl_gen10\": 1003.73, \"vs_no_intervention_distinct1_gen10\": 0.0704, \"recovery_complete_by_gen\": 4, \"converges_to_alpha0_baseline\": true}}, \"alpha_sweep_a050_s44\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T06:58:50.550Z\", \"updated_at\": \"2026-05-17T06:40:50.861Z\", \"hypothesis\": \"α=0.50 第三 seed 将确认 boundary 的 seed-dependent 性质；若 PermG sig >0/8 则 2/3 seeds 有信号（boundary 偏 transitional），若 0/8 则 1/3（boundary 偏 null）\", \"parent\": \"alpha_sweep_a050_s43\", \"conclusion\": \"success\", \"metrics\": {\"perm_granger_fdr_fwd\": \"3/8\", \"perm_granger_fdr_rev\": \"0/8\", \"consensus_ge3\": \"0/8\", \"consensus_ge4\": \"0/8\", \"naive_xcorr_fwd\": \"4/8\", \"diff_xcorr_fdr_fwd\": \"6/8\", \"threshold_onset_fwd\": \"0/8\", \"ty_granger_fwd\": \"0/8\", \"ece_d1_fdr_p\": 0.016, \"ece_d2_fdr_p\": 0.0408, \"ece_d3_fdr_p\": 0.0536, \"ece_ppl_fdr_p\": 0.0475, \"entropy_d1_fdr_p\": 0.0862, \"entropy_d2_fdr_p\": 0.0862, \"entropy_d3_fdr_p\": 0.0862, \"entropy_ppl_fdr_p\": 0.0862, \"cross_seed_note\": \"s42:0/8, s43:6/8, s44:3/8 — confirms boundary regime with high seed variance; ECE only canary with signal at α=0.50\"}}, \"mvp_v4_rep45\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T13:41:26.286Z\", \"updated_at\": \"2026-05-17T02:58:36.890Z\", \"conclusion\": \"success\", \"metrics\": {\"gen0_token_entropy\": 3.234195, \"gen0_ece\": 0.010805, \"gen0_perplexity\": 26.948959, \"gen0_distinct_1\": 0.098574, \"gen0_distinct_2\": 0.51463, \"gen0_distinct_3\": 0.808362, \"gen10_token_entropy\": 1.31536, \"gen10_ece\": 0.41654, \"gen10_perplexity\": 1016.22, \"gen10_distinct_1\": 0.069859, \"gen10_distinct_2\": 0.329549, \"gen10_distinct_3\": 0.543743, \"token_entropy_drift_pct\": -59.3296, \"ece_drift_pct\": 3755.0671, \"perplexity_drift_pct\": 3670.9063, \"distinct_1_drift_pct\": -29.1304, \"distinct_2_drift_pct\": -35.9639, \"distinct_3_drift_pct\": -32.7352}, \"hypothesis\": \"α=1.0 full replacement baseline: 完全合成污染下 canary→downstream 因果领先性在多 seeds 可复现，建立 confirmatory regime 证据基础\", \"parent\": \"mvp_v4_rep42\"}, \"mvp_v4_rep43\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T07:48:50.161Z\", \"updated_at\": \"2026-05-17T02:58:36.247Z\", \"conclusion\": \"success\", \"metrics\": {\"gen0_token_entropy\": 3.234195, \"gen0_ece\": 0.010805, \"gen0_perplexity\": 26.948959, \"gen0_distinct_1\": 0.098334, \"gen0_distinct_2\": 0.513178, \"gen0_distinct_3\": 0.805669, \"gen10_token_entropy\": 1.25961, \"gen10_ece\": 0.41951, \"gen10_perplexity\": 1014.66, \"gen10_distinct_1\": 0.070383, \"gen10_distinct_2\": 0.329651, \"gen10_distinct_3\": 0.539571, \"token_entropy_drift_pct\": -61.0534, \"ece_drift_pct\": 3782.5544, \"perplexity_drift_pct\": 3665.1176, \"distinct_1_drift_pct\": -28.4246, \"distinct_2_drift_pct\": -35.7628, \"distinct_3_drift_pct\": -33.0282}, \"hypothesis\": \"α=1.0 full replacement baseline: 完全合成污染下 canary→downstream 因果领先性在多 seeds 可复现，建立 confirmatory regime 证据基础\", \"parent\": \"mvp_v4_rep42\"}, \"alpha_sweep_a050_s43\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T06:58:45.880Z\", \"updated_at\": \"2026-05-17T02:58:35.307Z\", \"conclusion\": \"success\", \"metrics\": {\"gen0_token_entropy\": 3.234195, \"gen0_ece\": 0.010805, \"gen0_perplexity\": 26.948959, \"gen10_token_entropy\": 2.672, \"gen10_ece\": 0.097, \"gen10_perplexity\": 32.633, \"gen0_distinct_1\": 0.09833, \"gen0_distinct_2\": 0.5132, \"gen0_distinct_3\": 0.8057, \"gen10_distinct_1\": 0.0624, \"gen10_distinct_2\": 0.2617, \"gen10_distinct_3\": 0.4126, \"token_entropy_drift_pct\": -17.4, \"ece_drift_pct\": 799, \"perplexity_drift_pct\": 21.1, \"distinct_1_drift_pct\": -36.5, \"distinct_2_drift_pct\": -49, \"distinct_3_drift_pct\": -48.8, \"cross_seed_note\": \"vs s42: drift direction identical, magnitude <7% deviation, ppl near-identical (32.633 vs 32.64)\"}, \"hypothesis\": \"α=0.50 multi-seed: 中等污染下 PermG 信号是否跨种子稳定——如 signal 出现则 boundary 在 α&lt;0.50，如无则 boundary 在 α>0.50\", \"parent\": \"alpha_sweep_a050_s42\"}, \"alpha_sweep_a025_s44\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T06:58:48.224Z\", \"updated_at\": \"2026-05-17T02:58:34.439Z\", \"metrics\": \"{\\n  \\\"gen0\\\": {\\n    \\\"token_entropy\\\": 3.2342, \\\"ece\\\": 0.01080, \\\"perplexity\\\": 26.949,\\n    \\\"distinct_1\\\": 0.09809, \\\"distinct_2\\\": 0.51324, \\\"distinct_3\\\": 0.80577,\\n    \\\"effective_rank\\\": 46.613, \\\"mauve\\\": 0.02954\\n  },\\n  \\\"gen10\\\": {\\n    \\\"token_entropy\\\": 3.0721, \\\"ece\\\": 0.01804, \\\"perplexity\\\": 21.984,\\n    \\\"distinct_1\\\": 0.05884, \\\"distinct_2\\\": 0.22703, \\\"distinct_3\\\": 0.33644,\\n    \\\"effective_rank\\\": 44.354, \\\"mauve\\\": 0.01753\\n  },\\n  \\\"drift_pct\\\": {\\n    \\\"token_entropy\\\": -5.01, \\\"ece\\\": +67.0, \\\"perplexity\\\": -18.42,\\n    \\\"distinct_1\\\": -40.01, \\\"distinct_2\\\": -55.77, \\\"distinct_3\\\": -58.24,\\n    \\\"effective_rank\\\": -4.85, \\\"mauve\\\": -40.65\\n  }\\n}\", \"conclusion\": \"success\", \"hypothesis\": \"α=0.25 multi-seed 复现: 低污染下 diversity collapse (40-59%) 但无 Granger causal signal (0/8 PermG) 的模式跨种子稳定，定义 sub-threshold regime 下界\", \"parent\": \"alpha_sweep_a025_s42_v3\"}, \"alpha_sweep_a025_s43\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T06:58:43.090Z\", \"updated_at\": \"2026-05-17T02:58:33.559Z\", \"metrics\": {\"gen0\": {\"token_entropy\": 3.2342, \"ece\": 0.0108, \"perplexity\": 26.949, \"distinct_1\": 0.09833, \"distinct_2\": 0.5132, \"distinct_3\": 0.8057, \"effective_rank\": 46.61, \"mauve\": 0.03351}, \"gen10\": {\"token_entropy\": 3.0723, \"ece\": 0.02146, \"perplexity\": 21.899, \"distinct_1\": 0.05849, \"distinct_2\": 0.2236, \"distinct_3\": 0.333, \"effective_rank\": 45.37, \"mauve\": 0.01871}, \"drift_pct\": {\"token_entropy\": -5, \"ece\": 98.6, \"perplexity\": -18.7, \"distinct_1\": -40.5, \"distinct_2\": -56.4, \"distinct_3\": -58.7, \"effective_rank\": -2.7, \"mauve\": -44.2}}, \"conclusion\": \"success\", \"hypothesis\": \"α=0.25 multi-seed 复现: 低污染下 diversity collapse (40-59%) 但无 Granger causal signal (0/8 PermG) 的模式跨种子稳定，定义 sub-threshold regime 下界\", \"parent\": \"alpha_sweep_a025_s42_v3\"}, \"mvp_v4_rep42\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T07:29:48.857Z\", \"updated_at\": \"2026-05-17T02:58:25.998Z\", \"conclusion\": \"success\", \"metrics\": {\"gen0_token_entropy\": 3.234195, \"gen0_ece\": 0.010805, \"gen0_perplexity\": 26.948959, \"gen0_distinct_1\": 0.098216, \"gen0_distinct_2\": 0.517803, \"gen0_distinct_3\": 0.812728, \"gen10_token_entropy\": 1.27592, \"gen10_ece\": 0.41734, \"gen10_perplexity\": 1003.73, \"gen10_distinct_1\": 0.070383, \"gen10_distinct_2\": 0.335471, \"gen10_distinct_3\": 0.555579, \"token_entropy_drift_pct\": -60.5491, \"ece_drift_pct\": 3762.4711, \"perplexity_drift_pct\": 3624.5595, \"distinct_1_drift_pct\": -28.3386, \"distinct_2_drift_pct\": -35.2126, \"distinct_3_drift_pct\": -31.6402}, \"hypothesis\": \"α=1.0 full replacement baseline: 完全合成污染下 canary→downstream 因果领先性在多 seeds 可复现，建立 confirmatory regime 证据基础\"}, \"gen_wiki_gpt2m_a025_s42\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T10:35:16.032Z\", \"updated_at\": \"2026-05-17T02:56:16.958Z\", \"conclusion\": \"success\", \"metrics\": {\"gen0\": {\"token_entropy\": 3.5714, \"ece\": 0.0112, \"perplexity\": 32.63, \"distinct_1\": 0.1044, \"distinct_2\": 0.5483, \"distinct_3\": 0.8441, \"effective_rank\": 2.3722, \"mauve\": 0.0315}, \"gen10\": {\"token_entropy\": 2.3999, \"ece\": 0.0583, \"perplexity\": 18.12, \"distinct_1\": 0.0799, \"distinct_2\": 0.375, \"distinct_3\": 0.5893, \"effective_rank\": 8.4833, \"mauve\": 0.0282}, \"drift_pct\": {\"token_entropy\": -32.81, \"ece\": 422, \"perplexity\": -44.47, \"distinct_1\": -23.47, \"distinct_2\": -31.6, \"distinct_3\": -30.19, \"effective_rank\": 257.6, \"mauve\": -10.48}, \"lead_lag_consensus\": {\"tier3_pairs\": 1, \"tier2_pairs\": 7, \"perm_granger_sig\": \"0/8\", \"ty_sig\": \"1/8\"}}, \"hypothesis\": \"跨架构验证: GPT-2-medium (355M) 在 α=0.25 下展示与 Pythia-410M 相同的 regime-dependent 模式（diversity collapse 显著但 causal signal sub-threshold），确认 detectability boundary 非模型特异性\", \"parent\": \"alpha_sweep_a025_s42_v3\"}, \"alpha_sweep_a075_s44\": {\"status\": \"DONE\", \"created_at\": \"2026-05-16T06:16:20.468Z\", \"updated_at\": \"2026-05-17T02:56:11.121Z\", \"notes\": \"第三次重启 (17:57 UTC)：第二次运行 (09:56-~17:00, Gen 0-3) 被另一 Agent 会话 kill+rm-rf+重启，~7h GPU 浪费。原因：并发 Agent 会话判断需重跑。当前为第三次运行，从 Gen 0 开始，预计 ~10-12h 完成。\", \"conclusion\": \"success\", \"metrics\": {\"gen0\": {\"token_entropy\": 3.234, \"ece\": 0.0108, \"perplexity\": 26.95, \"distinct_1\": 0.0982, \"distinct_2\": 0.5178, \"distinct_3\": 0.8127}, \"gen10\": {\"token_entropy\": 2.336, \"ece\": 0.206, \"perplexity\": 76.35, \"distinct_1\": 0.067, \"distinct_2\": 0.309, \"distinct_3\": 0.508}, \"drift_pct\": {\"token_entropy\": -27.8, \"ece\": 1774, \"perplexity\": 183.4, \"distinct_1\": -31.8, \"distinct_2\": -39.9, \"distinct_3\": -37.5}}, \"hypothesis\": \"α=0.75 multi-seed 复现: Permutation Granger 因果信号（≥4/8 FDR sig forward, 0/8 reverse）在不同随机种子下稳定存在，确认 transitional regime 非单种子偶然\", \"parent\": \"alpha_sweep_a075_s42\"}, \"alpha_sweep_a000_s44\": {\"status\": \"DONE\", \"created_at\": \"2026-05-16T11:29:15.357Z\", \"updated_at\": \"2026-05-17T02:56:00.115Z\", \"metrics\": {\"gen0\": {\"token_entropy\": 3.2342, \"ece\": 0.0108, \"perplexity\": 26.949, \"distinct_1\": 0.0981, \"distinct_2\": 0.5132, \"distinct_3\": 0.8058, \"effective_rank\": 46.613}, \"gen10\": {\"token_entropy\": 3.0957, \"ece\": 0.0134, \"perplexity\": 21.616, \"distinct_1\": 0.0838, \"distinct_2\": 0.4665, \"distinct_3\": 0.7749, \"effective_rank\": 44.498}, \"drift_pct\": {\"token_entropy\": -4.3, \"ece\": 24, \"perplexity\": -19.8, \"distinct_1\": -14.6, \"distinct_2\": -9.1, \"distinct_3\": -3.8, \"effective_rank\": -4.5}, \"five_method\": {\"perm_granger_fdr_sig\": \"0/8\", \"ty_sig\": \"0/8\", \"robust_pairs_ge3\": \"0/8\", \"fpr_controlled\": true}}, \"conclusion\": \"success\", \"hypothesis\": \"α=0.0 null control multi-seed: 无合成数据再训练在跨 seed 复现下仍不产生 spurious causal signal（PermG FDR 0/8），证实 signal 源于合成污染而非训练随机性\", \"parent\": \"alpha_sweep_a000_s42\"}, \"alpha_sweep_a000_s43\": {\"status\": \"DONE\", \"created_at\": \"2026-05-16T11:29:13.444Z\", \"updated_at\": \"2026-05-17T02:55:58.475Z\", \"conclusion\": \"success\", \"metrics\": {\"gen0\": {\"token_entropy\": 3.2342, \"ece\": 0.0108, \"perplexity\": 26.949, \"distinct_1\": 0.0983, \"distinct_2\": 0.5132, \"distinct_3\": 0.8057, \"effective_rank\": 46.613}, \"gen10\": {\"token_entropy\": 3.0907, \"ece\": 0.0148, \"perplexity\": 21.469, \"distinct_1\": 0.0847, \"distinct_2\": 0.4631, \"distinct_3\": 0.7672, \"effective_rank\": 43.72}, \"drift_pct\": {\"token_entropy\": -4.4, \"ece\": 37.2, \"perplexity\": -20.3, \"distinct_1\": -13.9, \"distinct_2\": -9.8, \"distinct_3\": -4.8, \"effective_rank\": -6.2}, \"five_method\": {\"perm_granger_fdr_sig\": \"0/8\", \"ty_sig\": \"1/8 (df_resid=1 unreliable)\", \"robust_pairs_ge3\": \"0/8\", \"fpr_controlled\": true}}, \"hypothesis\": \"α=0.0 null control multi-seed: 无合成数据再训练在跨 seed 复现下仍不产生 spurious causal signal（PermG FDR 0/8），证实 signal 源于合成污染而非训练随机性\", \"parent\": \"alpha_sweep_a000_s42\"}, \"mvp_v2_rep44\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T05:38:10.762Z\", \"updated_at\": \"2026-05-16T00:10:26.251Z\", \"conclusion\": \"killed\"}, \"mvp_rep44\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T05:12:15.033Z\", \"updated_at\": \"2026-05-16T00:10:25.605Z\", \"metrics\": {\"gen10_token_entropy\": 1.2205, \"gen10_ece\": 0.4237, \"gen10_perplexity\": 1033.16, \"gen10_distinct_1\": 0.0731, \"gen10_distinct_2\": 0.3637, \"gen10_distinct_3\": 0.6075}, \"conclusion\": \"killed\"}, \"alpha_sweep_a025_s42\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T19:01:39.527Z\", \"updated_at\": \"2026-05-16T00:10:24.973Z\", \"conclusion\": \"killed\"}, \"alpha_sweep_a025_s42_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T19:25:52.094Z\", \"updated_at\": \"2026-05-16T00:10:24.568Z\", \"conclusion\": \"killed\"}, \"alpha_sweep_a060_s42\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T21:52:22.516Z\", \"updated_at\": \"2026-05-16T00:04:01.429Z\", \"conclusion\": \"killed\"}, \"alpha_sweep_a010_s42\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T21:52:19.712Z\", \"updated_at\": \"2026-05-16T00:03:53.018Z\", \"conclusion\": \"killed\"}, \"plan_006_s43\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T23:31:37.257Z\", \"updated_at\": \"2026-05-16T00:03:51.617Z\", \"conclusion\": \"killed\"}, \"gen_wiki_gpt2m_a100_s42_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T12:07:20.050Z\", \"updated_at\": \"2026-05-15T22:30:21.573Z\", \"metrics\": {\"token_entropy_drift_pct\": -86.5, \"ece_drift_pct\": 4543, \"perplexity_drift_pct\": 44703, \"distinct_1_drift_pct\": -12.4, \"distinct_2_drift_pct\": -14.7, \"distinct_3_drift_pct\": -12.7, \"five_method_forward_consensus\": \"6/6 pairs at 4/5 methods (Tier 3)\", \"five_method_reverse_consensus\": \"0/6 pairs\", \"naive_xcorr_forward\": \"|r|>0.98, all sig\", \"diff_xcorr_forward\": \"all p_fdr<0.001\", \"diff_xcorr_reverse\": \"all p>0.18 (clean directional separation)\", \"threshold_onset_entropy\": \"gen 1 (earliest canary)\", \"threshold_onset_ece\": \"gen 1-2\", \"threshold_onset_diversity\": \"gen 3\", \"perm_granger_forward\": \"p_fdr=0.003, BH corrected\", \"ty_granger_forward\": \"0/6 sig (df_resid=1-4, underpowered, consistent with Pythia C001)\", \"entropy_leads_diversity_lag\": \"1-2 gen\", \"ece_leads_diversity_lag\": \"1 gen\", \"diversity_plateau_from\": \"gen5\", \"cross_arch_note\": \"Replicates Pythia entropy-leads-diversity pattern at Tier 3 consensus. TY underpowered as expected.\"}, \"conclusion\": \"success\"}, \"mvp_v4_rep44\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T07:48:52.613Z\", \"updated_at\": \"2026-05-15T21:29:52.398Z\", \"conclusion\": \"success\", \"metrics\": {\"gen0_token_entropy\": 3.234195, \"gen0_ece\": 0.010805, \"gen0_perplexity\": 26.948959, \"gen0_distinct_1\": 0.098088, \"gen0_distinct_2\": 0.513235, \"gen0_distinct_3\": 0.805767, \"gen10_token_entropy\": 1.22049, \"gen10_ece\": 0.42369, \"gen10_perplexity\": 1033.16, \"gen10_distinct_1\": 0.073102, \"gen10_distinct_2\": 0.363737, \"gen10_distinct_3\": 0.607502, \"token_entropy_drift_pct\": -62.2629, \"ece_drift_pct\": 3821.2402, \"perplexity_drift_pct\": 3733.7659, \"distinct_1_drift_pct\": -25.473, \"distinct_2_drift_pct\": -29.1286, \"distinct_3_drift_pct\": -24.6057}}, \"alpha_sweep_a075_s42\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T21:52:17.315Z\", \"updated_at\": \"2026-05-15T13:29:46.421Z\", \"metrics\": {\"progress\": \"11/11 gen (complete)\", \"gen0_token_entropy\": 3.234, \"gen10_token_entropy\": 2.337, \"gen0_ece\": 0.0108, \"gen10_ece\": 0.2063, \"gen0_perplexity\": 26.95, \"gen10_perplexity\": 76.03, \"gen0_distinct_1\": 0.0982, \"gen10_distinct_1\": 0.0661, \"gen0_distinct_2\": 0.5178, \"gen10_distinct_2\": 0.3037, \"gen0_distinct_3\": 0.8127, \"gen10_distinct_3\": 0.5011, \"token_entropy_drift_pct\": -27.7, \"ece_drift_pct\": 1809.5, \"perplexity_drift_pct\": 182.1, \"distinct_1_drift_pct\": -32.7, \"distinct_2_drift_pct\": -41.3, \"distinct_3_drift_pct\": -38.4, \"granger_ece_to_d1_p_fdr\": 0.046, \"granger_ece_to_d2_p_fdr\": 0.046, \"granger_entropy_to_d2_p_fdr\": 0.048, \"granger_entropy_to_d1_p_fdr\": 0.054, \"granger_fdr_sig_count\": \"3/8\", \"consensus_robust_pairs\": \"11/16\", \"xcorr_entropy_d1_lag\": 2, \"xcorr_entropy_d1_r\": 0.973}, \"conclusion\": \"success\"}, \"alpha_sweep_a050_s42\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T21:52:15.427Z\", \"updated_at\": \"2026-05-15T13:17:48.134Z\", \"metrics\": {\"progress\": \"11/11 gen (complete)\", \"gen0_token_entropy\": 3.234, \"gen10_token_entropy\": 2.632, \"gen0_ece\": 0.011, \"gen10_ece\": 0.102, \"gen0_perplexity\": 26.95, \"gen10_perplexity\": 32.64, \"gen0_distinct_1\": 0.098, \"gen10_distinct_1\": 0.062, \"gen0_distinct_2\": 0.518, \"gen10_distinct_2\": 0.251, \"gen0_distinct_3\": 0.813, \"gen10_distinct_3\": 0.387, \"token_entropy_drift_pct\": -18.6, \"ece_drift_pct\": 842.8, \"perplexity_drift_pct\": 21.1, \"distinct_1_drift_pct\": -37.3, \"distinct_2_drift_pct\": -51.5, \"distinct_3_drift_pct\": -52.4, \"granger_entropy_to_d1_p_raw\": 0.095, \"granger_entropy_to_d2_p_raw\": 0.097, \"granger_ece_to_d1_p_raw\": 0.019, \"granger_ece_to_d2_p_raw\": 0.039, \"granger_fdr_note\": \"4 tests within alpha=0.50; BH FDR threshold rank1=0.0125, rank2=0.025 → 0/4 FDR-sig at q=0.05. Raw p pattern (ECE < entropy) is qualitative signal only.\", \"d024_non_monotonic\": true, \"d024_ece_vs_entropy_note\": \"ECE raw p < entropy raw p at α=0.50 (0.019 vs 0.095 at 5000 perms), 0/4 FDR-sig; regime switch hypothesis pending α=0.75 confirmation\"}, \"conclusion\": \"success\"}, \"plan_006_s42\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T23:31:35.454Z\", \"updated_at\": \"2026-05-15T12:17:14.093Z\", \"metrics\": {\"progress\": \"18/20 gen (gen_0-17 complete, gen_18-20 timeout)\", \"gen0_token_entropy\": 3.2342, \"gen17_token_entropy\": 1.1819, \"gen0_ece\": 0.0108, \"gen17_ece\": 0.4454, \"gen0_perplexity\": 26.95, \"gen17_perplexity\": 3367.66, \"gen0_distinct_1\": 0.0982, \"gen17_distinct_1\": 0.0756, \"gen0_distinct_2\": 0.5178, \"gen17_distinct_2\": 0.3617, \"gen0_distinct_3\": 0.8127, \"gen17_distinct_3\": 0.5865, \"token_entropy_drift_pct_gen0_17\": -63.4, \"distinct_1_drift_pct_gen0_17\": -23, \"distinct_2_drift_pct_gen0_17\": -30.1, \"distinct_3_drift_pct_gen0_17\": -27.8, \"ece_drift_pct_gen0_17\": 4024, \"ppl_drift_pct_gen0_17\": 12395, \"phase1_rapid_collapse\": \"gen0-5\", \"phase2_apparent_plateau\": \"gen5-12\", \"phase3_secondary_decline\": \"gen13-17\", \"phase3_d2_decline_pct\": -5.8, \"phase3_d3_decline_pct\": -6.9, \"diversity_saturated_at_gen\": 5, \"diversity_secondary_decline_at_gen\": 13, \"perplexity_saturated\": false}, \"conclusion\": \"failed\", \"notes\": \"gen_0-17 complete (T=18). 三相 collapse: Phase1 急速崩塌 gen0-5 (d1 -20.6%, entropy -63.8%), Phase2 表观稳态 gen5-12 (diversity <0.3% 变化, perplexity 仍+167%), Phase3 二次衰退 gen13-17 (d2 -5.8%, d3 -6.9%). Perplexity 未饱和 (26.95→3367.66, +12395%). T=18 vs T=10: 新增 diversity 二次衰退在 T=10 window 不可见. TY power 预估 ~0.28-0.41 (vs T=10 的 0.05-0.21).\"}, \"plan_006_s42_resume\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T11:55:26.236Z\", \"updated_at\": \"2026-05-15T12:10:54.859Z\", \"conclusion\": \"killed\", \"notes\": \"D034 决定不恢复。T=18 数据已足够（超出 T=15 目标）。原 plan_006_s42 gen_0-17 数据可用于 power analysis + supplementary。\"}, \"gen_wiki_gpt2m_a100_s42_v2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T12:02:06.478Z\", \"updated_at\": \"2026-05-15T12:04:50.741Z\", \"conclusion\": \"killed\"}, \"gen_wiki_gpt2m_a100_s42\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T10:35:18.700Z\", \"updated_at\": \"2026-05-15T12:01:58.523Z\", \"conclusion\": \"killed\"}, \"method_ablation_phase2\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T08:58:35.270Z\", \"updated_at\": \"2026-05-15T11:07:42.688Z\", \"conclusion\": \"success\", \"metrics\": {\"n_panel_rows\": 56, \"n_alphas\": 4, \"alphas\": [0, 0.25, 0.5, 1], \"naive_sig_rate_overall\": 1, \"perm_granger_sig_rate_a000_raw\": 0, \"perm_granger_sig_rate_a000_fdr\": 0, \"perm_granger_sig_rate_a025_raw\": 0.25, \"perm_granger_sig_rate_a025_fdr\": 0, \"perm_granger_sig_rate_a050_raw\": 0.25, \"perm_granger_sig_rate_a050_fdr\": 0, \"perm_granger_sig_rate_a100_raw\": 0.75, \"perm_granger_sig_rate_a100_fdr\": 0.75, \"TY_sig_rate_a000_raw\": 0, \"TY_sig_rate_a000_fdr\": 0, \"TY_sig_rate_a025_raw\": 0.625, \"TY_sig_rate_a025_fdr\": 0.375, \"TY_sig_rate_a050_raw\": 0, \"TY_sig_rate_a050_fdr\": 0, \"TY_sig_rate_a100_raw\": 0.5938, \"TY_sig_rate_a100_fdr\": 0.5938, \"diff_sig_rate_a000_raw\": 0.5, \"diff_sig_rate_a000_fdr\": 0.375, \"mean_inter_method_kappa\": 0.185, \"naive_vs_perm_granger_flip_rate\": 0.5, \"naive_vs_TY_flip_rate\": 0.57, \"fdr_flips_perm_granger\": 4, \"pair_verdict_a100_perm_granger\": \"6/8\", \"pair_verdict_a100_TY\": \"6/8\", \"entropy_to_diversity_a100_all_5methods_sig\": true, \"fdr_correction\": \"BH q=0.05\"}}, \"alpha_sweep_a025_s42_v3\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T21:04:05.726Z\", \"updated_at\": \"2026-05-15T05:13:22.207Z\", \"conclusion\": \"success\", \"metrics\": {\"gen0_token_entropy\": 3.2342, \"gen10_token_entropy\": 3.1017, \"gen0_ece\": 0.0108, \"gen10_ece\": 0.01942, \"gen0_perplexity\": 26.95, \"gen10_perplexity\": 22.32, \"gen0_distinct_1\": 0.0982, \"gen10_distinct_1\": 0.0586, \"gen0_distinct_2\": 0.5178, \"gen10_distinct_2\": 0.2219, \"gen0_distinct_3\": 0.8127, \"gen10_distinct_3\": 0.3263, \"token_entropy_drift_pct\": -4.1, \"ece_drift_pct\": 79.7, \"perplexity_drift_pct\": -17.2, \"distinct_1_drift_pct\": -40.3, \"distinct_2_drift_pct\": -57.1, \"distinct_3_drift_pct\": -59.9}, \"notes\": \"实际磁盘路径为 results/alpha_sweep/a025_s42/（无 v3 后缀）。Registry ID 带 v3 是历史原因，数据已核实无误。\"}, \"method_ablation_phase1\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T23:49:16.519Z\", \"updated_at\": \"2026-05-14T23:49:40.162Z\", \"conclusion\": \"success\", \"metrics\": {\"spurious_rate_5method\": 0.75, \"spurious_rate_4method\": 0.625, \"naive_sig\": \"16/16\", \"differenced_sig\": \"14/16\", \"threshold_sig\": \"9/16\", \"permutation_granger_sig\": \"6/16\", \"ty_sig\": \"4/16\", \"ty_power_T10\": \"0.05-0.20\", \"bh_fdr_flips\": 0}}, \"plan_009_bootstrap_ty\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T21:33:04.665Z\", \"updated_at\": \"2026-05-14T21:33:27.106Z\", \"conclusion\": \"success\", \"metrics\": {\"T10_d0_type1\": 0.081, \"T10_d0_power\": 0.205, \"T10_d1_type1\": 0.047, \"T10_d1_power\": 0.09, \"T10_dadapt_type1\": 0.052, \"T10_dadapt_power\": 0.05, \"T20_d0_power\": 0.409, \"T20_d1_power\": 0.172, \"T30_d0_power\": 0.606, \"T30_d1_power\": 0.283}}, \"mvp_v3_rep43\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T06:25:42.195Z\", \"updated_at\": \"2026-05-14T06:48:01.316Z\", \"conclusion\": \"failed\"}, \"mvp_v3_rep42\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T06:25:39.728Z\", \"updated_at\": \"2026-05-14T06:47:59.908Z\", \"conclusion\": \"failed\"}, \"mvp_v2_rep43\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T05:38:10.434Z\", \"updated_at\": \"2026-05-14T06:25:28.345Z\", \"conclusion\": \"killed\"}, \"mvp_v2_rep42\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T05:38:05.054Z\", \"updated_at\": \"2026-05-14T06:25:27.286Z\", \"conclusion\": \"killed\"}, \"mvp_rep43\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T05:12:14.237Z\", \"updated_at\": \"2026-05-14T05:37:18.575Z\", \"conclusion\": \"killed\"}, \"mvp_rep42\": {\"status\": \"DONE\", \"created_at\": \"2026-05-14T05:12:13.930Z\", \"updated_at\": \"2026-05-14T05:37:17.438Z\", \"conclusion\": \"killed\"}}, \"count\": 126, \"total\": 126, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.5558}}"
    }
  },
  "sourceToolAssistantUUID": "4620d78e-4233-4efc-9e7c-4d1b358f752b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Runtime record

_source line 793_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Director 指令] [Reframe — D130] 论文从 Methodology Paper 转型为 Detection Phase Transition Discovery Paper  投稿目标：EMNLP 2026 ARR June cycle，8 页 main text + unlimited references + appendix。当前 37 页需大幅压缩。  ## 核心…",
  "leafUuid": "7383800d-9a92-4720-b4d2-3601d06517c8",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


### Runtime record

_source line 794_

```json
{
  "type": "ai-title",
  "aiTitle": "Correct effective_rank framework and add phase transition citations",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


### Tool call

_source line 795 · 2026-05-20T10:05:08.856Z_

<details open><summary>🔧 Tool call — Read · `toolu_014HvzxML3iThvjQitpJ2K5N`</summary>

```json
{
  "file_path": "/home/ubuntu/agent-ml-research/skills/global/paper-plan.skill.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7383800d-9a92-4720-b4d2-3601d06517c8",
  "isSidechain": false,
  "requestId": "req_011CbDddjCFQnk3JfQ7an8MD",
  "type": "assistant",
  "uuid": "c453db12-e810-425d-ba01-98e5c0a18d74",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01A8vQGi4iNaeXfrcMDVHy55",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 669,
      "cache_read_input_tokens": 95064,
      "output_tokens": 74,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 669,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 74,
          "cache_read_input_tokens": 95064,
          "cache_creation_input_tokens": 669,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 669
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

_source line 796 · 2026-05-20T10:05:08.865Z_

<details><summary>↩ Tool result · `toolu_014HvzxML3iThvjQitpJ2K5N`</summary>

````text
1	---
2	name: paper-plan
3	description: 论文规划——生成 writing_plan.yaml 作为下游 Worker 的共享合约（投稿目标、outline、可视化、表格、文献策略、写作顺序）。当 Director 说"写论文"/"准备投稿"/"论文计划"时使用。
4	scope: global
5	tags:
6	  - workflow
7	  - research
8	  - planning
9	  - academic
10	version: 2
11	roles:
12	- agent
13	- paper_agent
14	---
15	
16	## 触发条件
17	
18	- 用户/Director 说"论文规划"/"paper plan"/"投稿计划"/"目标 NeurIPS/ICML/..."
19	- 核心方法验证成功后，主动建议制定论文计划
20	- 用户要求调整已有论文计划（重新生成 writing_plan.yaml）
21	
22	## 产出
23	
24	**唯一产出**：`projects/{name}/writing_plan.yaml` —— 所有下游 Worker（章节写作、画图、文献搜索）的共享合约。
25	
26	文件格式见下方 §writing_plan.yaml 格式。生成后通过 `save_project_file("writing_plan.yaml", content)` 写入项目根目录。
27	
28	## 步骤
29	
30	### Step 1: 收集现状
31	
32	1. `read_project_file("ideas.md")` — DECIDED（已验证）和 ACTIVE（待做）分区
33	2. `read_registry()` — 所有实验及状态、baseline 指标、metrics
34	3. `read_roadmap()` — 研究方向、实验矩阵、决策日志
35	4. `read_project_file("literature_map.yaml")` — 已有文献库（如存在）
36	5. `ls templates/latex/` — 确认目标 venue 模板可用性
37	
38	### Step 2: 分析论文可行性（纯推理）
39	
40	投稿门槛 mirror 自 `experiment-matrix` skill：
41	
42	**投稿门槛（按 Director 指定的目标 venue 对标）**
43	- A 类（NeurIPS/ICML/ICLR）：3 个核心 contribution、主结果 ≥ 3 benchmark（含 ≥ 1 OOD）、Baseline ≥ 5、≥ 3 seed + 显著性、完整 ablation、≥ 1 efficiency、≥ 3 qualitative case
44	- 具体门槛由 Director 在审批 writing_plan 时把关，你只按 Director 指定的 venue 标准规划
45	
46	**时间紧张时的应对（禁止降级目标 venue）**：
47	- 升级并行度：多 Worker 同时铺代码/数据/图表
48	- 砍低优先级维度（P2: efficiency/qualitative 可后补），集中火力在 P0 硬门槛
49	- 向 Director 汇报，由 Director 决定申请云 GPU 扩容或调整实验优先级
50	- **禁止自行建议更换目标会议**——venue 决策是 Director + 用户的权限
51	
52	### Step 3: 模板选择
53	
54	1. 查本地 `templates/latex/{venue}{year}/`
55	2. 缺失时 WebSearch 搜索官方最新模板，spawn Worker 下载到 `templates/latex/{venue}{year}/`
56	3. 仍找不到 → 复用最近版本（如 neurips2025），在 `meta.template_note` 标注原因
57	4. 在 `writing_plan.yaml` 的 `meta.template` 字段写入实际路径
58	
59	### Step 4: 生成 writing_plan.yaml
60	
61	按 §writing_plan.yaml 格式生成完整 YAML，包含：
62	
63	- `meta`：venue/track/template/page_limit/deadline/core_claim/created_at
64	- `paper_outline`：各章节 word_budget + core_bullets + dependencies + 章节关联的 `tables`/`figures`/`registry_refs`/`citation_hints`
65	- `visualization_plan`：每张图的 fig_id/type/tool/data_source/placement
66	- `table_plan`：每张表的 table_id/caption/type/columns/data_source（§3.7 新增）
67	- `literature_strategy`：citation_budget + macro_context + micro_clusters
68	- `writing_order`：严格串行的章节写作顺序
69	
70	**关键填写规则**：
71	
72	- `visualization_plan.tool`：概念图（架构图/流程图）→ `paperbanana`；统计图（柱/线/热力）→ `matplotlib`
73	- `visualization_plan.narrative_intent`：**必填**，一句话写出"读者应该相信什么"。写不出来说明这张图不该画。详见 `paper-visualization.skill.md` L2
74	- `visualization_plan.design_notes`：从 `paper-visualization.skill.md` L3 pattern 库选 0-4 个 pattern（如 `Pattern A: regime bands`、`Pattern D: hollow for n<50`）。Worker 据此添加叙事层，避免出"正确但平庸"的图
75	- 重要的图（hero / main result / 新颖实验）填 `design_notes` 前**先看同领域代表性论文的图**——`paper-visualization.skill.md` L0 讲了怎么挑、怎么看、怎么把学到的写进 `design_notes`。你有判断权决定哪些图值得这样做
76	- `table_plan.type`：`comparison` / `ablation` / `statistics` / `configuration`
77	- `table_plan.data_source`：能从 registry 提取的写 `"registry: exp_xxx, exp_yyy"`；不能的写 `"manual"`
78	- `paper_outline.{section}.tables` / `.figures`：把 `table_plan` / `visualization_plan` 的 id 关联到对应章节
79	- `paper_outline.{section}.registry_refs`：该章节会引用的 exp_id 列表
80	- `writing_order`：先 Experiments、Method，再 Intro/Related Work，最后 Abstract/Conclusion
81	
82	### Step 5: 写入 + 确认
83	
84	1. `save_project_file("writing_plan.yaml", yaml_content)` — 写入项目根目录
85	2. 向 Director 汇报摘要（投稿目标、core claim、章节数、图表数、引用预算）
86	3. 等待 Director 审批；如有调整，更新 writing_plan.yaml 重新提交
87	
88	## writing_plan.yaml 格式
89	
90	```yaml
91	meta:
92	  venue: NeurIPS 2026
93	  track: main
94	  template: templates/latex/neurips2026/   # Step 3 确认的实际路径
95	  template_note: ""                         # 复用旧模板时标注原因
96	  page_limit: 9
97	  deadline: 2026-06-15
98	  core_claim: "..."                         # 一句话核心 claim
99	  created_at: 2026-05-11T14:00:00Z
100	
101	paper_outline:
102	  - section: abstract
103	    word_budget: 200
104	    core_bullets:
105	      - "问题：..."
106	      - "方法：..."
107	      - "结果：..."
108	    dependencies: [experiments, method]
109	
110	  - section: introduction
111	    word_budget: 1200
112	    core_bullets:
113	      - "Hook: 一个具体、令人惊讶的事实"
114	      - "Gap: 现有方法的盲点（因为什么导致不够好）"
115	      - "Insight: 我们发现了什么别人没发现的东西"
116	      - "Mechanism: 基于 insight 我们做了什么不同的事"
117	      - "Contributions: [C1, C2, C3]"
118	    dependencies: [experiments]
119	    citation_hints:
120	      - "baseline X 引用原始论文"
121	      - "dataset Y 引用来源"
122	    figures: [fig1_overview]
123	
124	  - section: related_work
125	    word_budget: 800
126	    core_bullets:
127	      - "Cluster 1: ... → 我们的区别"
128	      - "Cluster 2: ... → 我们的区别"
129	    dependencies: [introduction]
130	
131	  - section: method
132	    word_budget: 1500
133	    core_bullets:
134	      - "Problem formulation"
135	      - "Proposed method"
136	      - "Theoretical justification"
137	    dependencies: []
138	    notation_table:
139	      X: "input features"
140	      Y: "target labels"
141	
142	  - section: experiments
143	    word_budget: 2000
144	    core_bullets:
145	      - "Setup: datasets, baselines, metrics"
146	      - "Main results: Table 1"
147	      - "Ablation: Table 2"
148	      - "Analysis"
149	    dependencies: []
150	    registry_refs: [exp_001, exp_002, exp_003]
151	    tables: [tab1_main_results, tab2_ablation, tab3_hyperparams]
152	    figures: [fig2_main_results, fig3_ablation]
153	
154	  - section: conclusion
155	    word_budget: 400
156	    core_bullets:
157	      - "Summary"
158	      - "Limitations (honest)"
159	      - "Future work"
160	    dependencies: [experiments, method]
161	
162	visualization_plan:
163	  # 每张图必填 narrative_intent（一句话 takeaway）+ design_notes（pattern 列表）
164	  # 设计原则和 pattern 目录见 skills/global/paper-visualization.skill.md
165	  - fig_id: fig1_overview
166	    type: conceptual              # conceptual | statistical
167	    tool: paperbanana             # 概念图走 paperbanana
168	    description: "系统架构概览图"
169	    narrative_intent: "我们的 pipeline 在 X 阶段引入 Y 模块，把 Z 问题转化为可学习目标"
170	    design_notes: []              # 概念图通常不需要 pattern，靠 paperbanana
171	    placement: introduction
172	    aspect_ratio: "16:9"
173	
174	  - fig_id: fig2_main_results
175	    type: statistical
176	    tool: matplotlib              # 统计图走 matplotlib
177	    description: "主实验结果对比柱状图"
178	    narrative_intent: "我们的方法在所有 3 个 benchmark 上超过 baseline 5pp，但在 OOD 上优势消失"
179	    design_notes:                  # 从 paper-visualization L3 选
180	      - "Pattern A: regime bands 分 in-domain / OOD"
181	      - "Pattern E: Wilson CI 标注不确定性"
182	    data_source: "registry: exp_001, exp_002"
183	    placement: experiments
184	    aspect_ratio: "4:3"
185	
186	  - fig_id: fig3_ablation
187	    type: statistical
188	    tool: matplotlib
189	    description: "Ablation 热力图"
190	    narrative_intent: "去掉 module M 时性能掉 8pp，证明 M 是不可替代的关键组件"
191	    design_notes:
192	      - "用 diverging colormap（TwoSlopeNorm vcenter=0）让正负差异可见"
193	      - "Pattern J: 热力图数值描边防遮挡"
194	    data_source: "registry: exp_003"
195	    placement: experiments
196	
197	table_plan:
198	  - table_id: tab1_main_results
199	    caption: "Main experimental results on ..."
200	    placement: experiments
201	    type: comparison              # comparison | ablation | statistics | configuration
202	    columns: [Method, Dataset1, Dataset2, Dataset3]
203	    data_source: "registry: exp_001, exp_002, exp_003"
204	    notes: "加粗最优结果，次优下划线"
205	
206	  - table_id: tab2_ablation
207	    caption: "Ablation study of ..."
208	    placement: experiments
209	    type: ablation
210	    columns: [Component, Metric1, Metric2]
211	    data_source: "registry: exp_004, exp_005"
212	    baseline_row: "Full model"    # ablation 基准行
213	
214	  - table_id: tab3_hyperparams
215	    caption: "Hyperparameter settings"
216	    placement: experiments
217	    type: configuration
218	    columns: [Parameter, Value]
219	    data_source: "manual"         # 不从 registry 自动填充
220	
221	literature_strategy:
222	  citation_budget: 40
223	  macro_context:
224	    - "large language model calibration"
225	    - "post-training quantization"
226	  micro_clusters:
227	    - cluster_name: "PTQ Methods"
228	      search_queries:
229	        - "post-training quantization LLM 2024 2025"
230	        - "GPTQ AWQ weight quantization"
231	      must_cite:
232	        - "GPTQ original paper"
233	        - "AWQ original paper"
234	      target_count: 8
235	    - cluster_name: "Calibration in NLP"
236	      search_queries:
237	        - "calibration large language models"
238	        - "temperature scaling neural networks"
239	      must_cite:
240	        - "Guo et al. 2017 calibration"
241	      target_count: 6
242	
243	writing_order:                    # 严格串行，前序章节产出是后续章节的依赖
244	  - experiments
245	  - method
246	  - introduction
247	  - related_work
248	  - abstract
249	  - conclusion
250	```
251	
252	## 排版规划（Step 1 视角——规划阶段就要定的事）
253	
254	### Figure 1 策略
255	
256	Figure 1 是审稿人第一眼看到的图，决定论文的"第一印象锚定"。三选一：
257	
258	| 类型 | 适用场景 | 工具 |
259	|------|---------|------|
260	| A. 解释性 diagram（架构/流程/概念概览） | 方法创新型论文 | **paperbanana** |
261	| B. 关键结果组合图 | 实证驱动型论文（一张图讲完核心发现） | matplotlib |
262	| C. 方法对比图 | 问题定义型论文（直观展示 gap） | 按内容判断 |
263	
264	大多数 ML 论文 Figure 1 是概念图/架构图——类型 A 是默认选择。
265	
266	### Display Items 预算
267	
268	| 正文页数 | Display Items（figure + table）总数 |
269	|---------|-----------------------------------|
270	| 9 页 | 5–8 个 |
271	| 8 页 | 4–7 个 |
272	| 7 页 | 4–6 个 |
273	
274	每个 display item 传达一个明确 message（`narrative_intent`）。传达不了就不画。
275	
276	### 贡献类型 → 视觉策略
277	
278	- **概念贡献**（新框架/新视角）→ 少图表、清爽，Figure 1 是核心
279	- **实证贡献**（新 benchmark/大规模实验）→ 多表格 + 统计图，表格密度高
280	- **方法贡献**（新算法/新模块）→ 架构图 + ablation 表 + 对比图均衡
281	
282	### 图表类型分类决策树（填 `visualization_plan[].tool` 时使用）
283	
284	- 架构图 / 流程图 / framework / 概念对比 / 直觉解释 → `type: conceptual` → `tool: paperbanana`
285	- 折线 / 柱状 / 散点 / 热力图 / forest plot / 从 registry 数据生成 → `type: statistical` → `tool: matplotlib`
286	- 判断困难时问自己："这张图的输入是数值数据还是概念？" 数值 → matplotlib，概念 → paperbanana
287	
288	---
289	
290	## Story Arc（写作前必须回答）
291	
292	在 `meta.core_claim` 中只写一句话核心 claim，但生成 writing_plan.yaml 前内部必须回答完整 Story Arc，并将关键答案分散到对应章节的 `core_bullets`：
293	
294	1. **Hook**: 读者为什么应该关心？（具体、令人惊讶的事实/矛盾，不是泛泛"很重要"）→ Introduction 第一条 bullet
295	2. **Gap**: 现有方法的核心盲点是什么？（不是"不够好"，而是"因为 X 导致不够好"）→ Introduction
296	3. **Insight**: 我们发现了什么别人没发现的东西？→ 必须能回答；回答不上来说明还没准备好写
297	4. **Mechanism**: 基于 insight，我们的方法做了什么不同的事？→ Method
298	5. **Evidence**: 最强的一个数字是什么？→ Abstract / Experiments
299	
300	## 禁止清单（写入 Worker prompt 时强制下传）
301	
302	以下句式在全文禁止：
303	- "XXX has achieved remarkable success in recent years"
304	- "This demonstrates the effectiveness of our approach"
305	- "To the best of our knowledge, we are the first to..."
306	- "Extensive experiments demonstrate that..."
307	
308	## 约束
309	
310	- 时间线基于当前日期和 `meta.deadline` 倒推，按 AI 团队速度估 buffer：初稿 1-2 天（Paper Agent 全流水线）、内审 1 天（Reviewer 即时）、修订 1-2 天、提交准备 0.5 天。**不要按人类"初稿 2 周 + 内审 1 周"的节奏留 buffer**
311	- `paper_outline.{section}.registry_refs` 必须真实存在于 registry，引用未完成实验时在 `core_bullets` 标注 "[TODO exp_xxx]"
312	- `table_plan.data_source` 写明从 registry 哪些 exp_id 抽数，便于 Worker 后续 `write_paper_section` 时构建 provenance
313	- 不要过度承诺——只列实际能做完的实验；时间紧张时砍低优先级维度（P2/P3），集中火力在核心 claim，**禁止自行降级目标 venue**（venue 决策是 Director + 用户的权限）
314	- writing_plan.yaml 是合约——一旦 Director 审批通过，下游 Worker 严格按此执行；如需修改重新提交 Director 审批
315	
````

</details>

<details><summary>Recorded metadata</summary>

````json
{
  "recorded_role": "user",
  "parentUuid": "c453db12-e810-425d-ba01-98e5c0a18d74",
  "isSidechain": false,
  "promptId": "0bc1eef6-835a-4ee4-a8a1-06010792cb3b",
  "type": "user",
  "uuid": "630bec84-88c2-4907-8de6-c92e5c853295",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/agent-ml-research/skills/global/paper-plan.skill.md",
      "content": "---\nname: paper-plan\ndescription: 论文规划——生成 writing_plan.yaml 作为下游 Worker 的共享合约（投稿目标、outline、可视化、表格、文献策略、写作顺序）。当 Director 说\"写论文\"/\"准备投稿\"/\"论文计划\"时使用。\nscope: global\ntags:\n  - workflow\n  - research\n  - planning\n  - academic\nversion: 2\nroles:\n- agent\n- paper_agent\n---\n\n## 触发条件\n\n- 用户/Director 说\"论文规划\"/\"paper plan\"/\"投稿计划\"/\"目标 NeurIPS/ICML/...\"\n- 核心方法验证成功后，主动建议制定论文计划\n- 用户要求调整已有论文计划（重新生成 writing_plan.yaml）\n\n## 产出\n\n**唯一产出**：`projects/{name}/writing_plan.yaml` —— 所有下游 Worker（章节写作、画图、文献搜索）的共享合约。\n\n文件格式见下方 §writing_plan.yaml 格式。生成后通过 `save_project_file(\"writing_plan.yaml\", content)` 写入项目根目录。\n\n## 步骤\n\n### Step 1: 收集现状\n\n1. `read_project_file(\"ideas.md\")` — DECIDED（已验证）和 ACTIVE（待做）分区\n2. `read_registry()` — 所有实验及状态、baseline 指标、metrics\n3. `read_roadmap()` — 研究方向、实验矩阵、决策日志\n4. `read_project_file(\"literature_map.yaml\")` — 已有文献库（如存在）\n5. `ls templates/latex/` — 确认目标 venue 模板可用性\n\n### Step 2: 分析论文可行性（纯推理）\n\n投稿门槛 mirror 自 `experiment-matrix` skill：\n\n**投稿门槛（按 Director 指定的目标 venue 对标）**\n- A 类（NeurIPS/ICML/ICLR）：3 个核心 contribution、主结果 ≥ 3 benchmark（含 ≥ 1 OOD）、Baseline ≥ 5、≥ 3 seed + 显著性、完整 ablation、≥ 1 efficiency、≥ 3 qualitative case\n- 具体门槛由 Director 在审批 writing_plan 时把关，你只按 Director 指定的 venue 标准规划\n\n**时间紧张时的应对（禁止降级目标 venue）**：\n- 升级并行度：多 Worker 同时铺代码/数据/图表\n- 砍低优先级维度（P2: efficiency/qualitative 可后补），集中火力在 P0 硬门槛\n- 向 Director 汇报，由 Director 决定申请云 GPU 扩容或调整实验优先级\n- **禁止自行建议更换目标会议**——venue 决策是 Director + 用户的权限\n\n### Step 3: 模板选择\n\n1. 查本地 `templates/latex/{venue}{year}/`\n2. 缺失时 WebSearch 搜索官方最新模板，spawn Worker 下载到 `templates/latex/{venue}{year}/`\n3. 仍找不到 → 复用最近版本（如 neurips2025），在 `meta.template_note` 标注原因\n4. 在 `writing_plan.yaml` 的 `meta.template` 字段写入实际路径\n\n### Step 4: 生成 writing_plan.yaml\n\n按 §writing_plan.yaml 格式生成完整 YAML，包含：\n\n- `meta`：venue/track/template/page_limit/deadline/core_claim/created_at\n- `paper_outline`：各章节 word_budget + core_bullets + dependencies + 章节关联的 `tables`/`figures`/`registry_refs`/`citation_hints`\n- `visualization_plan`：每张图的 fig_id/type/tool/data_source/placement\n- `table_plan`：每张表的 table_id/caption/type/columns/data_source（§3.7 新增）\n- `literature_strategy`：citation_budget + macro_context + micro_clusters\n- `writing_order`：严格串行的章节写作顺序\n\n**关键填写规则**：\n\n- `visualization_plan.tool`：概念图（架构图/流程图）→ `paperbanana`；统计图（柱/线/热力）→ `matplotlib`\n- `visualization_plan.narrative_intent`：**必填**，一句话写出\"读者应该相信什么\"。写不出来说明这张图不该画。详见 `paper-visualization.skill.md` L2\n- `visualization_plan.design_notes`：从 `paper-visualization.skill.md` L3 pattern 库选 0-4 个 pattern（如 `Pattern A: regime bands`、`Pattern D: hollow for n<50`）。Worker 据此添加叙事层，避免出\"正确但平庸\"的图\n- 重要的图（hero / main result / 新颖实验）填 `design_notes` 前**先看同领域代表性论文的图**——`paper-visualization.skill.md` L0 讲了怎么挑、怎么看、怎么把学到的写进 `design_notes`。你有判断权决定哪些图值得这样做\n- `table_plan.type`：`comparison` / `ablation` / `statistics` / `configuration`\n- `table_plan.data_source`：能从 registry 提取的写 `\"registry: exp_xxx, exp_yyy\"`；不能的写 `\"manual\"`\n- `paper_outline.{section}.tables` / `.figures`：把 `table_plan` / `visualization_plan` 的 id 关联到对应章节\n- `paper_outline.{section}.registry_refs`：该章节会引用的 exp_id 列表\n- `writing_order`：先 Experiments、Method，再 Intro/Related Work，最后 Abstract/Conclusion\n\n### Step 5: 写入 + 确认\n\n1. `save_project_file(\"writing_plan.yaml\", yaml_content)` — 写入项目根目录\n2. 向 Director 汇报摘要（投稿目标、core claim、章节数、图表数、引用预算）\n3. 等待 Director 审批；如有调整，更新 writing_plan.yaml 重新提交\n\n## writing_plan.yaml 格式\n\n```yaml\nmeta:\n  venue: NeurIPS 2026\n  track: main\n  template: templates/latex/neurips2026/   # Step 3 确认的实际路径\n  template_note: \"\"                         # 复用旧模板时标注原因\n  page_limit: 9\n  deadline: 2026-06-15\n  core_claim: \"...\"                         # 一句话核心 claim\n  created_at: 2026-05-11T14:00:00Z\n\npaper_outline:\n  - section: abstract\n    word_budget: 200\n    core_bullets:\n      - \"问题：...\"\n      - \"方法：...\"\n      - \"结果：...\"\n    dependencies: [experiments, method]\n\n  - section: introduction\n    word_budget: 1200\n    core_bullets:\n      - \"Hook: 一个具体、令人惊讶的事实\"\n      - \"Gap: 现有方法的盲点（因为什么导致不够好）\"\n      - \"Insight: 我们发现了什么别人没发现的东西\"\n      - \"Mechanism: 基于 insight 我们做了什么不同的事\"\n      - \"Contributions: [C1, C2, C3]\"\n    dependencies: [experiments]\n    citation_hints:\n      - \"baseline X 引用原始论文\"\n      - \"dataset Y 引用来源\"\n    figures: [fig1_overview]\n\n  - section: related_work\n    word_budget: 800\n    core_bullets:\n      - \"Cluster 1: ... → 我们的区别\"\n      - \"Cluster 2: ... → 我们的区别\"\n    dependencies: [introduction]\n\n  - section: method\n    word_budget: 1500\n    core_bullets:\n      - \"Problem formulation\"\n      - \"Proposed method\"\n      - \"Theoretical justification\"\n    dependencies: []\n    notation_table:\n      X: \"input features\"\n      Y: \"target labels\"\n\n  - section: experiments\n    word_budget: 2000\n    core_bullets:\n      - \"Setup: datasets, baselines, metrics\"\n      - \"Main results: Table 1\"\n      - \"Ablation: Table 2\"\n      - \"Analysis\"\n    dependencies: []\n    registry_refs: [exp_001, exp_002, exp_003]\n    tables: [tab1_main_results, tab2_ablation, tab3_hyperparams]\n    figures: [fig2_main_results, fig3_ablation]\n\n  - section: conclusion\n    word_budget: 400\n    core_bullets:\n      - \"Summary\"\n      - \"Limitations (honest)\"\n      - \"Future work\"\n    dependencies: [experiments, method]\n\nvisualization_plan:\n  # 每张图必填 narrative_intent（一句话 takeaway）+ design_notes（pattern 列表）\n  # 设计原则和 pattern 目录见 skills/global/paper-visualization.skill.md\n  - fig_id: fig1_overview\n    type: conceptual              # conceptual | statistical\n    tool: paperbanana             # 概念图走 paperbanana\n    description: \"系统架构概览图\"\n    narrative_intent: \"我们的 pipeline 在 X 阶段引入 Y 模块，把 Z 问题转化为可学习目标\"\n    design_notes: []              # 概念图通常不需要 pattern，靠 paperbanana\n    placement: introduction\n    aspect_ratio: \"16:9\"\n\n  - fig_id: fig2_main_results\n    type: statistical\n    tool: matplotlib              # 统计图走 matplotlib\n    description: \"主实验结果对比柱状图\"\n    narrative_intent: \"我们的方法在所有 3 个 benchmark 上超过 baseline 5pp，但在 OOD 上优势消失\"\n    design_notes:                  # 从 paper-visualization L3 选\n      - \"Pattern A: regime bands 分 in-domain / OOD\"\n      - \"Pattern E: Wilson CI 标注不确定性\"\n    data_source: \"registry: exp_001, exp_002\"\n    placement: experiments\n    aspect_ratio: \"4:3\"\n\n  - fig_id: fig3_ablation\n    type: statistical\n    tool: matplotlib\n    description: \"Ablation 热力图\"\n    narrative_intent: \"去掉 module M 时性能掉 8pp，证明 M 是不可替代的关键组件\"\n    design_notes:\n      - \"用 diverging colormap（TwoSlopeNorm vcenter=0）让正负差异可见\"\n      - \"Pattern J: 热力图数值描边防遮挡\"\n    data_source: \"registry: exp_003\"\n    placement: experiments\n\ntable_plan:\n  - table_id: tab1_main_results\n    caption: \"Main experimental results on ...\"\n    placement: experiments\n    type: comparison              # comparison | ablation | statistics | configuration\n    columns: [Method, Dataset1, Dataset2, Dataset3]\n    data_source: \"registry: exp_001, exp_002, exp_003\"\n    notes: \"加粗最优结果，次优下划线\"\n\n  - table_id: tab2_ablation\n    caption: \"Ablation study of ...\"\n    placement: experiments\n    type: ablation\n    columns: [Component, Metric1, Metric2]\n    data_source: \"registry: exp_004, exp_005\"\n    baseline_row: \"Full model\"    # ablation 基准行\n\n  - table_id: tab3_hyperparams\n    caption: \"Hyperparameter settings\"\n    placement: experiments\n    type: configuration\n    columns: [Parameter, Value]\n    data_source: \"manual\"         # 不从 registry 自动填充\n\nliterature_strategy:\n  citation_budget: 40\n  macro_context:\n    - \"large language model calibration\"\n    - \"post-training quantization\"\n  micro_clusters:\n    - cluster_name: \"PTQ Methods\"\n      search_queries:\n        - \"post-training quantization LLM 2024 2025\"\n        - \"GPTQ AWQ weight quantization\"\n      must_cite:\n        - \"GPTQ original paper\"\n        - \"AWQ original paper\"\n      target_count: 8\n    - cluster_name: \"Calibration in NLP\"\n      search_queries:\n        - \"calibration large language models\"\n        - \"temperature scaling neural networks\"\n      must_cite:\n        - \"Guo et al. 2017 calibration\"\n      target_count: 6\n\nwriting_order:                    # 严格串行，前序章节产出是后续章节的依赖\n  - experiments\n  - method\n  - introduction\n  - related_work\n  - abstract\n  - conclusion\n```\n\n## 排版规划（Step 1 视角——规划阶段就要定的事）\n\n### Figure 1 策略\n\nFigure 1 是审稿人第一眼看到的图，决定论文的\"第一印象锚定\"。三选一：\n\n| 类型 | 适用场景 | 工具 |\n|------|---------|------|\n| A. 解释性 diagram（架构/流程/概念概览） | 方法创新型论文 | **paperbanana** |\n| B. 关键结果组合图 | 实证驱动型论文（一张图讲完核心发现） | matplotlib |\n| C. 方法对比图 | 问题定义型论文（直观展示 gap） | 按内容判断 |\n\n大多数 ML 论文 Figure 1 是概念图/架构图——类型 A 是默认选择。\n\n### Display Items 预算\n\n| 正文页数 | Display Items（figure + table）总数 |\n|---------|-----------------------------------|\n| 9 页 | 5–8 个 |\n| 8 页 | 4–7 个 |\n| 7 页 | 4–6 个 |\n\n每个 display item 传达一个明确 message（`narrative_intent`）。传达不了就不画。\n\n### 贡献类型 → 视觉策略\n\n- **概念贡献**（新框架/新视角）→ 少图表、清爽，Figure 1 是核心\n- **实证贡献**（新 benchmark/大规模实验）→ 多表格 + 统计图，表格密度高\n- **方法贡献**（新算法/新模块）→ 架构图 + ablation 表 + 对比图均衡\n\n### 图表类型分类决策树（填 `visualization_plan[].tool` 时使用）\n\n- 架构图 / 流程图 / framework / 概念对比 / 直觉解释 → `type: conceptual` → `tool: paperbanana`\n- 折线 / 柱状 / 散点 / 热力图 / forest plot / 从 registry 数据生成 → `type: statistical` → `tool: matplotlib`\n- 判断困难时问自己：\"这张图的输入是数值数据还是概念？\" 数值 → matplotlib，概念 → paperbanana\n\n---\n\n## Story Arc（写作前必须回答）\n\n在 `meta.core_claim` 中只写一句话核心 claim，但生成 writing_plan.yaml 前内部必须回答完整 Story Arc，并将关键答案分散到对应章节的 `core_bullets`：\n\n1. **Hook**: 读者为什么应该关心？（具体、令人惊讶的事实/矛盾，不是泛泛\"很重要\"）→ Introduction 第一条 bullet\n2. **Gap**: 现有方法的核心盲点是什么？（不是\"不够好\"，而是\"因为 X 导致不够好\"）→ Introduction\n3. **Insight**: 我们发现了什么别人没发现的东西？→ 必须能回答；回答不上来说明还没准备好写\n4. **Mechanism**: 基于 insight，我们的方法做了什么不同的事？→ Method\n5. **Evidence**: 最强的一个数字是什么？→ Abstract / Experiments\n\n## 禁止清单（写入 Worker prompt 时强制下传）\n\n以下句式在全文禁止：\n- \"XXX has achieved remarkable success in recent years\"\n- \"This demonstrates the effectiveness of our approach\"\n- \"To the best of our knowledge, we are the first to...\"\n- \"Extensive experiments demonstrate that...\"\n\n## 约束\n\n- 时间线基于当前日期和 `meta.deadline` 倒推，按 AI 团队速度估 buffer：初稿 1-2 天（Paper Agent 全流水线）、内审 1 天（Reviewer 即时）、修订 1-2 天、提交准备 0.5 天。**不要按人类\"初稿 2 周 + 内审 1 周\"的节奏留 buffer**\n- `paper_outline.{section}.registry_refs` 必须真实存在于 registry，引用未完成实验时在 `core_bullets` 标注 \"[TODO exp_xxx]\"\n- `table_plan.data_source` 写明从 registry 哪些 exp_id 抽数，便于 Worker 后续 `write_paper_section` 时构建 provenance\n- 不要过度承诺——只列实际能做完的实验；时间紧张时砍低优先级维度（P2/P3），集中火力在核心 claim，**禁止自行降级目标 venue**（venue 决策是 Director + 用户的权限）\n- writing_plan.yaml 是合约——一旦 Director 审批通过，下游 Worker 严格按此执行；如需修改重新提交 Director 审批\n",
      "numLines": 315,
      "startLine": 1,
      "totalLines": 315
    }
  },
  "sourceToolAssistantUUID": "c453db12-e810-425d-ba01-98e5c0a18d74",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
````

</details>

---


### Assistant

_source line 797 · 2026-05-20T10:08:23.876Z_

<details><summary>Logged reasoning block</summary>

```text
Now I have a comprehensive understanding of:
1. The current paper structure and content (39 pages, heavily methodology-focused)
2. The paper-plan skill requirements
3. The D130 Reframe directive requirements

Let me now generate the writing_plan.yaml for the D130 Reframe. Key elements from D130:

**New title**: "A Detection Phase Transition in Iterative Training Collapse"

**New narrative**: From "Method Matters" methodology paper → "Detection Phase Transition Discovery" paper

**4 contributions**:
- C1 (Phase Transition): Near-discontinuous onset at α_c=0.476


- C2 (S×R Theory): Signal × Resolution framework predicting 4 regimes (D130 mentions 5 regimes but current paper has 4)
- C3 (Multi-Method Toolkit): Downgraded from primary contribution to supporting tool
- C4 (Practical Applications): Canary-based cessation

**8-page budget**: 
- Abstract+Intro: 1.5p
- Background+RW: 1.0p
- Theory+Method: 2.0p
- Results: 2.5p
- Discussion+Conclusion: 1.0p

**Key changes**: Shift focus from methodological rigor to the discovery narrative, emphasizing the phase transition phenomenon as the central finding while repositioning the toolkit as evidence rather than the main story.

There's a discrepancy I need to track—D130 describes five regimes (blind, onset, sync dip, recovery, saturation) but the current paper only has four. The detection phase seems to be split differently in D130's framework. I should flag this distinction when planning the revision, though I'll follow D130's structure going forward.

Now I'm working through the page budget for the main text. EMNLP 2026 gives us 8 pages plus unlimited references, so I need to estimate how to distribute the content across roughly 4,200-4,400 words total.

I'm allocating space strategically: the introduction gets the most room to set up the problem, experiments and results take up the bulk since that's where the contribution lives, while background and methods get compressed since they're supporting material. I need to be ruthless about what goes in the main text versus appendix.

Now I'm planning the display items — figures and tables need to fit within the 8-page constraint, so I'm aiming for 4-7 total items to leave room for text.

The three main figures tell the story: the phase transition detection, the dose-response regimes, and the token entropy trajectory showing diversity gains. For tables, I'm keeping the method comparison and cross-architecture validation in the main text since they directly support the claims, but moving the drift summary to appendix.

Everything else — the detailed algorithm formalization, consensus workflow, Shapley analysis, calibration tables, and all the limitation deep-dives — goes to the appendix where readers can find it if they need the technical details.

Now I'm restructuring the paper around the discovery narrative. Instead of leading with methodology, I'm making the phase transition the hero result. The new flow moves from introduction straight into the theoretical framework, then experimental design, and finally results organized by the three key findings. This is tighter and lets the discovery speak for itself rather than getting buried in method details.

For the page budget, I need to be disciplined: Background and Related Work compress to a single page, Theory and Method share two pages where the S×R framework gets proper treatment alongside the calibration approach, and Results expand to 2.5 pages to showcase the phase transition detection, cross-architecture validation, and canary prediction findings. Discussion and Conclusion merge into one page, with Limitations as a separate section that doesn't count toward the page limit.

For figures and tables, I'm prioritizing the phase transition sigmoid as the hero visual, the dose-response profile showing the four regimes, the metric trajectory demonstrating canary lead, and compressed comparison tables for methods and generalization results—keeping the display items to around six or seven maximum to stay within space constraints.

Now I'm thinking through the structure more carefully: the phase transition should anchor Figure 1 in the introduction as the core discovery hook, then I'll map out which supporting visualizations belong in the main text versus the appendix to manage the eight-page limit. I'm also flagging the ambiguity around five versus four regimes and need to establish a clear writing order that prioritizes results first, since this is a reframe of the paper's narrative.

Writing YAML structure...

The story arc hinges on showing that method choice alone drives spurious signals up to 62.5% in model collapse analysis, but the real breakthrough is discovering a detection phase transition when using the correct methodology—existing work treats detectability as binary rather than as a continuous phenomenon with sharp transitions.

The key insight is that causal detectability undergoes a near-discontinuous onset around α_c=0.476 with a sigmoid fit of R²=0.969, which is striking because cumulative contamination barely changes across this boundary. The S×R framework explains this through the interaction of signal and resolution, predicting four distinct regimes including a non-monotonic dip in the synchronous case. The evidence is strong: 12 out of 14 cross-architecture conditions confirm PermG detection, and there's perfect directional asymmetry with forward detection in all 24 cases but zero reverse detections.

For contributions, I'm highlighting the detection phase transition itself as the primary finding, the S×R theory that explains the regime structure, and the multi-method toolkit as a supporting contribution.

Now I'm working through the page budget for an 8-page EMNLP submission. With display items taking up roughly 1.5-2 pages of space, I have about 6-6.5 pages for actual text, which translates to roughly 3,500 words total. I'm allocating 700 words to the introduction, 450 to background and related work, 900 to theory and methods, and 1,000 to results, leaving room for discussion and conclusion.

Now I'm mapping out where the figures and tables will sit within the paper. I have five main display items planned: a sigmoid phase transition curve for the introduction, a dose-response profile showing four regimes in the results, a metric trajectory visualization, a compressed method comparison table, and another table that appears to be cut off.

With these display items taking up roughly 1.7 pages, that leaves me about 6.3 pages for the actual text. I'm reconsidering the placement of the hero figure—it makes sense to put the phase transition sigmoid in the introduction as the central visual that anchors the whole discovery narrative.

I'm also identifying what should move to the appendix to keep the main paper focused: the detailed algorithm formalization, workflow diagrams, Shapley analysis, calibration tables, practical guidance tiers, diagnostic figures, error tables, power analysis, transfer entropy results, and sequential monitoring content.

The main text should concentrate on the phase transition as the centerpiece, the four-regime dose-response pattern, metric trajectories showing canary lead times, a compressed method comparison emphasizing PermG, the generalization results, brief intervention findings, the full S×R theory section, and just a single paragraph on the three pitfalls rather than a full section.

Now I'm ready to generate the writing plan YAML file.

Writing config YAML... The abstract needs to capture the key findings: the phase transition in causal detectability occurs sharply around α_c=0.476 across multiple model architectures, and the entropy-based method for training cessation significantly reduces perplexity. The introduction will establish the motivation by contrasting two seemingly identical training runs that diverge based on methodological choices. I'm pulling together the key citations for the background section—foundational work on model collapse from Shumailov and Alemohammad, early warning systems theory from Scheffer and Boettiger, and the Granger methodology papers that ground the causal analysis approach.

Now I'm mapping out the theory section with the signal-resolution framework at its core: how detectability depends on both the strength of the collapse signal and the resolution of our monitoring approach, with predictions across four distinct regimes from blind spots to clear detection, where the per-generation signal threshold scales with the mixing ratio rather than accumulating over time.

For the methods section, I'm highlighting three critical pitfalls that plague existing approaches—method sensitivity varying wildly, spurious correlations, and regime-dependent results—then recommending PermG as the most robust choice since it achieves zero false positives while maintaining high sensitivity, with the formal mathematical framework and detailed comparisons deferred to the appendix.

Now moving into results, I'm laying out the detection phase transition across a 12-point grid of alpha values, showing a sharp sigmoid-like jump from zero detections up to alpha=0.50 where we suddenly get 6 out of 8 successes, with a dip at 0.60 and recovery beyond 0.75—the sigmoid fit captures this far better than a power law. There's also this striking cumulative contamination paradox where slightly different contamination levels (99.75% versus 99.90%) flip the outcome from complete failure to success, and I'm visualizing this four-regime dose-response pattern in Figure 2.

For cross-architecture validation, I'm testing across 14 different conditions spanning 6 model families from 345M to 6.9B parameters, and PermG hits 6 or more detections in 12 of those 14 cases. The directionality is remarkably consistent—all 24 forward-direction tests succeed while all 24 reverse-direction tests fail on WikiText, though C4 shows the opposite pattern for PermG. The onset boundary stays robust around alpha=0.50 across architectures, with just a couple exceptions like Pythia-1.4B showing seed-dependent behavior and SmolLM3 exhibiting canary splitting.

Now I'm looking at how canary-based intervention performs—using a 15% entropy threshold to trigger cessation predictively rather than reactively. The approach cuts peak perplexity by 58% with a confidence interval of 29-64%, and it fires one generation earlier while recovering one generation faster than the baseline. This pattern holds consistently across both 410M and 1.4B scale models, and the threshold activates at alpha=0.60 even in cases where Granger causality doesn't detect the effect.

For the discussion section, I need to address the Granger causation caveat, lay out a four-layer detection taxonomy spanning dimensionality through instability to coupling and dynamical stability, and highlight the practical paradox that the method works best where it's least needed—though continuous monitoring can resolve this tension. I'll also note how directionality varies by domain between WikiText and C4, summarize the key contributions, and outline future directions like extending to longer sequences, multivariate VAR models, and larger architectures.

The limitations section is starting to come into focus, covering the constraints and boundary conditions of this approach. scale ≤1.4B; 7B+ untested"
      - "Data domain: 5K WikiText-103 subset; C4 has pre-training confound"
      - "Short time series T=10 (11 points)"
      - "Bivariate Granger ≠ causality"
      - "Replace-only protocol; accumulate mode untested"
      - "Scoped to diversity metrics, not model collapse broadly"
    note: "Does not count toward 8-page limit per EMNLP 2026 rules"

visualization_plan:
  # Main text figures (3)
  - fig_id: fig_phase_transition
    type: statistical
    tool: matplotlib
    description: "Hero figure: Sigmoid fit to PermG forward detection rate across 12 α levels. Shows near-discontinuous onset at α_c=0.476."
    narrative_intent: "Causal detectability jumps from 0/8 to 6/8 across a <0.05 α interval, despite cumulative contamination barely changing — this is a detection phase transition."
    design_notes:
      - "Pattern A: regime bands (blind / onset / sync dip / detection) as shaded background"
      - "Sigmoid curve overlaid on empirical points"
      - "Annotate α_c=0.476, R²=0.969"
      - "Inset or annotation: cumulative contamination C at α=0.45 vs 0.50 (99.75% vs 99.90%)"
    placement: "Figure 1, Introduction or Results §5.1"
    aspect_ratio: "single column (3.25in × 2.5in)"
    data_source: "registry: phase transition data; Generating visualization..." I'm specifying the figure dimensions and data sources for the dose-response plot, noting it's already complete but may need relabeling. Now moving to the metric trajectory figure, which tracks token entropy and diversity metrics across four seeds at α=1.0, showing that entropy drops a full generation ahead of other diversity signals. I'm cataloging the remaining figures for the appendix—there's a consensus heatmap that's already done, a differencing diagnostic with sensitivity analysis still to complete, a consensus pipeline funnel diagram that's finished, and a Shapley value analysis figure coming up.

Now I'm moving into the table planning section, starting with a method comparison table that will go in the main text showing how different lead-lag detection approaches perform on false positive rates and detection sensitivity across various thresholds. Generating markdown table...

Now I'm mapping out the literature strategy around model collapse and detection phase transitions, with a focus on Granger causality methodology. I need to stay within a 35-40 citation budget while ensuring the core collapse cluster has those four essential papers and the canary monitoring cluster pulls in the geometric and spectral detection work. I'm finishing up the citation requirements for the analytical robustness cluster, then mapping out the writing sequence—starting with results to lock down the key numbers, followed by theory and methods that depend on those findings, then introduction to frame the discovery, and finally background work that needs the full context.

The compression strategy is clear: this 39-page paper needs to fit into 8 pages, so I'm moving the detailed MMCT formalization, calibration procedures, and other technical content into the appendix while keeping the essential narrative in the main text. I'm organizing the remaining discussion sections into appendices—transfer entropy, change-point detection, sequential monitoring, and NLP-specific constraints go into an extended discussion appendix, while metric drift tables get their own reference section. For the main paper, I'm keeping the phase transition sigmoid, S×R theory, the three key pitfalls, PermG recommendation with supporting evidence, a compressed cross-architecture summary, and brief intervention results. I'm also noting presentation constraints around consensus score comparisons and framing rules that affect how I can present certain findings. I'm working through a set of constraints for paper D130, clarifying what language is acceptable for different claims—like distinguishing between "detection phase transition" versus claiming phase transitions universally, and noting that the CSD findings at T=11 are suggestive rather than confirmed. There's also an open question about whether to expand the current four regimes into five by splitting the detection phase into recovery and saturation stages.

For that regime question, the data doesn't support the split—detection rates are nearly identical at α=0.75 and α=1.0, so keeping four regimes is the right call without stronger evidence of distinct dynamics. I'm also tracking a citation decision about which Gu paper to include pending director confirmation, and noting that a figure file needs to be transferred before the main text can compile.

Now I'm realizing I should wrap this up and save the project file using the available MCP tool rather than continuing to iterate manually.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "630bec84-88c2-4907-8de6-c92e5c853295",
  "isSidechain": false,
  "requestId": "req_011CbDddvUQUgCcX5HvXhKM7",
  "type": "assistant",
  "uuid": "95171d77-ac79-45ec-83e0-d22e500c8a4c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013EkUE5pTtvWXaLrruFLYsA",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5686,
      "cache_read_input_tokens": 95733,
      "output_tokens": 9638,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5686,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 9638,
          "cache_read_input_tokens": 95733,
          "cache_creation_input_tokens": 5686,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5686
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

_source line 798 · 2026-05-20T10:08:23.918Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01Vb4WKCH8tcHaVaTtJvjxeV`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__save_project_file,mcp__agent-ml-research__paper_agent_post_to_director",
  "max_results": 2
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "95171d77-ac79-45ec-83e0-d22e500c8a4c",
  "isSidechain": false,
  "requestId": "req_011CbDddvUQUgCcX5HvXhKM7",
  "type": "assistant",
  "uuid": "b7272a9b-204e-492c-af49-ac2336ccf158",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013EkUE5pTtvWXaLrruFLYsA",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5686,
      "cache_read_input_tokens": 95733,
      "output_tokens": 9638,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5686,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 9638,
          "cache_read_input_tokens": 95733,
          "cache_creation_input_tokens": 5686,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5686
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

_source line 799 · 2026-05-20T10:08:23.929Z_

<details><summary>↩ Tool result · `toolu_01Vb4WKCH8tcHaVaTtJvjxeV`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__save_project_file"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__paper_agent_post_to_director"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b7272a9b-204e-492c-af49-ac2336ccf158",
  "isSidechain": false,
  "promptId": "0bc1eef6-835a-4ee4-a8a1-06010792cb3b",
  "type": "user",
  "uuid": "17289597-f9e4-4d31-a6b2-8afcc9f67733",
  "toolUseResult": {
    "matches": [
      "mcp__agent-ml-research__save_project_file",
      "mcp__agent-ml-research__paper_agent_post_to_director"
    ],
    "query": "select:mcp__agent-ml-research__save_project_file,mcp__agent-ml-research__paper_agent_post_to_director",
    "total_deferred_tools": 51
  },
  "sourceToolAssistantUUID": "b7272a9b-204e-492c-af49-ac2336ccf158",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Runtime record

_source line 800_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Director 指令] [Reframe — D130] 论文从 Methodology Paper 转型为 Detection Phase Transition Discovery Paper  投稿目标：EMNLP 2026 ARR June cycle，8 页 main text + unlimited references + appendix。当前 37 页需大幅压缩。  ## 核心…",
  "leafUuid": "17289597-f9e4-4d31-a6b2-8afcc9f67733",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


### Runtime record

_source line 801_

```json
{
  "type": "ai-title",
  "aiTitle": "Correct effective_rank framework and add phase transition citations",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


### Assistant

_source line 802 · 2026-05-20T10:08:31.473Z_

Now I have everything needed to generate the writing_plan.yaml. Let me also quickly check the current paper's appendix structure to plan content migration.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "17289597-f9e4-4d31-a6b2-8afcc9f67733",
  "isSidechain": false,
  "requestId": "req_011CbDdtJb56dTpiUGbe8mxu",
  "type": "assistant",
  "uuid": "e6a5dd4b-98cd-4b86-97ef-cbd46e7615ae",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01D42NH9nAbbRBzdyEnT46AE",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 10171,
      "cache_read_input_tokens": 101419,
      "output_tokens": 140,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 10171,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 140,
          "cache_read_input_tokens": 101419,
          "cache_creation_input_tokens": 10171,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 10171
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

_source line 803 · 2026-05-20T10:08:33.116Z_

<details open><summary>🔧 Tool call — Read · `toolu_01DZmhFRx4A783jzS5rk6yYP`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/appendix.tex",
  "limit": 60
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e6a5dd4b-98cd-4b86-97ef-cbd46e7615ae",
  "isSidechain": false,
  "requestId": "req_011CbDdtJb56dTpiUGbe8mxu",
  "type": "assistant",
  "uuid": "40b1aca9-7e94-4b2b-91e2-cd4b1e7813ca",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01D42NH9nAbbRBzdyEnT46AE",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 10171,
      "cache_read_input_tokens": 101419,
      "output_tokens": 140,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 10171,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 140,
          "cache_read_input_tokens": 101419,
          "cache_creation_input_tokens": 10171,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 10171
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

_source line 804 · 2026-05-20T10:08:33.128Z_

<details><summary>↩ Tool result · `toolu_01DZmhFRx4A783jzS5rk6yYP`</summary>

```text
1	\appendix
2	
3	\section{Distinct-3 Results}
4	\label{app:distinct3}
5	
6	Table~\ref{tab:distinct3_drift} reports distinct-3 drift across all contamination levels.
7	Distinct-3 exhibits the largest absolute decline among diversity metrics at low contamination ($-58.9{\pm}0.9\%$ at $\alpha{=}0.25$) but attenuates at higher levels ($-30.5\%$ at $\alpha{=}1.0$), consistent with the diversity--calibration dissociation discussed in \S\ref{sec:discussion}.
8	
9	\begin{table}[h]
10	\centering
11	\small
12	\caption{Distinct-3 drift (\%, generation~0$\to$10) across contamination levels. $\alpha{=}0.00$, $\alpha{=}0.25$, $\alpha{=}0.75$: 3-seed mean${\pm}$std; $\alpha{=}1.0$: 4-seed mean${\pm}$std; $\alpha{=}0.50$: single seed.}
13	\label{tab:distinct3_drift}
14	\begin{tabular}{lc}
15	\toprule
16	$\alpha$ & Distinct-3 drift (\%) \\
17	\midrule
18	0.00 & $-4.4{\pm}0.5$ \\
19	0.25 & $-58.9{\pm}0.9$ \\
20	0.50 & $-52.4$ \\
21	0.75 & $-38.6{\pm}1.3$ \\
22	1.00 & $-30.5{\pm}4.0$ \\
23	\bottomrule
24	\end{tabular}
25	\end{table}
26	
27	\paragraph{Lead-lag analysis.}
28	At $\alpha{=}1.0$, token entropy Granger-precedes distinct-3 at the same consensus level as distinct-1 and distinct-2: $K{\geq}4/5$ methods, $S{\geq}3/4$ seeds (Tier~3).
29	However, the optimal lag is less stable than for distinct-1/2: at max\_lag${=}7$, the lag standard deviation across seeds exceeds 1.5 generations, compared to $<0.5$ for distinct-1/2.
30	This instability reflects bimodal lag distributions (modes at lag~1 and lag~3--4), suggesting that distinct-3 captures two temporally distinct diversity loss mechanisms: rapid n-gram homogenization (lag~1) and slower distributional narrowing (lag~3--4).
31	
32	\paragraph{Sensitivity to sequence length.}
33	Higher-order $n$-gram diversity metrics are more sensitive to generation length and random sampling variability.
34	With our 512-token generation length, distinct-3 has a smaller effective denominator (number of possible unique trigrams observed) than distinct-1 or distinct-2, amplifying stochastic fluctuations.
35	This partially explains the higher lag instability: the signal-to-noise ratio for temporal precedence is lower for distinct-3, requiring more observations (longer $T$ or more seeds) to achieve stable estimates.
36	For this reason, we report distinct-3 in this appendix rather than in the main text, where distinct-1 and distinct-2 provide cleaner evidence of the entropy-leads-diversity pattern.
37	
38	
39	\section{Observation Window Sensitivity}
40	\label{app:window_sensitivity}
41	
42	Table~\ref{tab:window_sensitivity} reports how the Tier~3 consensus classification ($K{\geq}4/5$ methods) varies as a function of the minimum observation window $T_{\min}$, where analysis uses only generations $0$ through $T_{\min}$.
43	The consensus classification stabilizes at $T_{\min}{\geq}5$ (6 data points), well below our full observation window of $T{=}10$: all six effect-size reference pairs (token entropy and ECE $\to$ distinct-1, distinct-2, distinct-3) reach $K{\geq}4/5$ agreement at every window length from $T_{\min}{=}5$ through $T_{\min}{=}10$, with no spurious pairs (canary$\to$perplexity) admitted.
44	
45	Toda--Yamamoto is the only method exhibiting window-dependent sensitivity: after correcting the statsmodels API incompatibility (\S\ref{sec:ty_limitation}), TY consensus stabilizes at $T_{\min}{\geq}6$, slightly later than the primary methods, reflecting the additional degrees of freedom consumed by the augmentation order $d_{\max}$.
46	This does not affect the consensus classification because the remaining four methods provide stable $K{\geq}4/5$ agreement independently of Toda--Yamamoto's vote.
47	
48	\begin{table}[h]
49	\centering
50	\small
51	\caption{Observation window sensitivity for Tier~3 consensus ($K{\geq}4/5$) at $\alpha{=}1.0$ (Pythia-410M, 4~seeds). Tier~3 pairs: number of canary$\to$downstream pairs (out of 8 validated) reaching $K{\geq}4/5$ method agreement. TY pairs: number of effect-size reference pairs (out of 6) reaching Toda--Yamamoto significance (moderate supplementary method; \S\ref{sec:ty_limitation}). Consensus stabilizes at $T_{\min}{\geq}5$; TY stabilizes at $T_{\min}{\geq}6$.}
52	\label{tab:window_sensitivity}
53	\begin{tabular}{lccccccccc}
54	\toprule
55	& \multicolumn{8}{c}{Minimum observation window $T_{\min}$} \\
56	\cmidrule(lr){2-9}
57	& 3 & 4 & 5 & 6 & 7 & 8 & 9 & 10 \\
58	\midrule
59	Tier~3 pairs (/8)    & $\dagger$ & $\dagger$ & 6 & 6 & 6 & 6 & 6 & 6 \\
60	TY pairs (/6)        & $\dagger$ & $\dagger$ & 3--6 & 3--6 & 3--6 & 3--6 & 3--6 & 6 \\
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "40b1aca9-7e94-4b2b-91e2-cd4b1e7813ca",
  "isSidechain": false,
  "promptId": "0bc1eef6-835a-4ee4-a8a1-06010792cb3b",
  "type": "user",
  "uuid": "7d9145de-95c8-49a6-ac50-be92b9336747",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/appendix.tex",
      "content": "\\appendix\n\n\\section{Distinct-3 Results}\n\\label{app:distinct3}\n\nTable~\\ref{tab:distinct3_drift} reports distinct-3 drift across all contamination levels.\nDistinct-3 exhibits the largest absolute decline among diversity metrics at low contamination ($-58.9{\\pm}0.9\\%$ at $\\alpha{=}0.25$) but attenuates at higher levels ($-30.5\\%$ at $\\alpha{=}1.0$), consistent with the diversity--calibration dissociation discussed in \\S\\ref{sec:discussion}.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Distinct-3 drift (\\%, generation~0$\\to$10) across contamination levels. $\\alpha{=}0.00$, $\\alpha{=}0.25$, $\\alpha{=}0.75$: 3-seed mean${\\pm}$std; $\\alpha{=}1.0$: 4-seed mean${\\pm}$std; $\\alpha{=}0.50$: single seed.}\n\\label{tab:distinct3_drift}\n\\begin{tabular}{lc}\n\\toprule\n$\\alpha$ & Distinct-3 drift (\\%) \\\\\n\\midrule\n0.00 & $-4.4{\\pm}0.5$ \\\\\n0.25 & $-58.9{\\pm}0.9$ \\\\\n0.50 & $-52.4$ \\\\\n0.75 & $-38.6{\\pm}1.3$ \\\\\n1.00 & $-30.5{\\pm}4.0$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Lead-lag analysis.}\nAt $\\alpha{=}1.0$, token entropy Granger-precedes distinct-3 at the same consensus level as distinct-1 and distinct-2: $K{\\geq}4/5$ methods, $S{\\geq}3/4$ seeds (Tier~3).\nHowever, the optimal lag is less stable than for distinct-1/2: at max\\_lag${=}7$, the lag standard deviation across seeds exceeds 1.5 generations, compared to $<0.5$ for distinct-1/2.\nThis instability reflects bimodal lag distributions (modes at lag~1 and lag~3--4), suggesting that distinct-3 captures two temporally distinct diversity loss mechanisms: rapid n-gram homogenization (lag~1) and slower distributional narrowing (lag~3--4).\n\n\\paragraph{Sensitivity to sequence length.}\nHigher-order $n$-gram diversity metrics are more sensitive to generation length and random sampling variability.\nWith our 512-token generation length, distinct-3 has a smaller effective denominator (number of possible unique trigrams observed) than distinct-1 or distinct-2, amplifying stochastic fluctuations.\nThis partially explains the higher lag instability: the signal-to-noise ratio for temporal precedence is lower for distinct-3, requiring more observations (longer $T$ or more seeds) to achieve stable estimates.\nFor this reason, we report distinct-3 in this appendix rather than in the main text, where distinct-1 and distinct-2 provide cleaner evidence of the entropy-leads-diversity pattern.\n\n\n\\section{Observation Window Sensitivity}\n\\label{app:window_sensitivity}\n\nTable~\\ref{tab:window_sensitivity} reports how the Tier~3 consensus classification ($K{\\geq}4/5$ methods) varies as a function of the minimum observation window $T_{\\min}$, where analysis uses only generations $0$ through $T_{\\min}$.\nThe consensus classification stabilizes at $T_{\\min}{\\geq}5$ (6 data points), well below our full observation window of $T{=}10$: all six effect-size reference pairs (token entropy and ECE $\\to$ distinct-1, distinct-2, distinct-3) reach $K{\\geq}4/5$ agreement at every window length from $T_{\\min}{=}5$ through $T_{\\min}{=}10$, with no spurious pairs (canary$\\to$perplexity) admitted.\n\nToda--Yamamoto is the only method exhibiting window-dependent sensitivity: after correcting the statsmodels API incompatibility (\\S\\ref{sec:ty_limitation}), TY consensus stabilizes at $T_{\\min}{\\geq}6$, slightly later than the primary methods, reflecting the additional degrees of freedom consumed by the augmentation order $d_{\\max}$.\nThis does not affect the consensus classification because the remaining four methods provide stable $K{\\geq}4/5$ agreement independently of Toda--Yamamoto's vote.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Observation window sensitivity for Tier~3 consensus ($K{\\geq}4/5$) at $\\alpha{=}1.0$ (Pythia-410M, 4~seeds). Tier~3 pairs: number of canary$\\to$downstream pairs (out of 8 validated) reaching $K{\\geq}4/5$ method agreement. TY pairs: number of effect-size reference pairs (out of 6) reaching Toda--Yamamoto significance (moderate supplementary method; \\S\\ref{sec:ty_limitation}). Consensus stabilizes at $T_{\\min}{\\geq}5$; TY stabilizes at $T_{\\min}{\\geq}6$.}\n\\label{tab:window_sensitivity}\n\\begin{tabular}{lccccccccc}\n\\toprule\n& \\multicolumn{8}{c}{Minimum observation window $T_{\\min}$} \\\\\n\\cmidrule(lr){2-9}\n& 3 & 4 & 5 & 6 & 7 & 8 & 9 & 10 \\\\\n\\midrule\nTier~3 pairs (/8)    & $\\dagger$ & $\\dagger$ & 6 & 6 & 6 & 6 & 6 & 6 \\\\\nTY pairs (/6)        & $\\dagger$ & $\\dagger$ & 3--6 & 3--6 & 3--6 & 3--6 & 3--6 & 6 \\\\",
      "numLines": 60,
      "startLine": 1,
      "totalLines": 269
    }
  },
  "sourceToolAssistantUUID": "40b1aca9-7e94-4b2b-91e2-cd4b1e7813ca",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Runtime record

_source line 805 · 2026-05-20T10:08:33.200Z_

```json
{
  "parentUuid": "7d9145de-95c8-49a6-ac50-be92b9336747",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "320aaa28-9b33-43ae-bdd7-13561eeeecd5",
  "timestamp": "2026-05-20T10:08:33.200Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

---


### Tool call

_source line 806 · 2026-05-20T10:08:37.497Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01MAhn3gyfgjYprSb2kncjz6`</summary>

```json
{
  "query": "select:TodoWrite",
  "max_results": 1
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "320aaa28-9b33-43ae-bdd7-13561eeeecd5",
  "isSidechain": false,
  "requestId": "req_011CbDdtypVHMo34gXjoZZcU",
  "type": "assistant",
  "uuid": "43cebe67-02be-4511-b38b-cd716b6d718f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017dBk7Mx7GbRFwFtw8sZAS8",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1919,
      "cache_read_input_tokens": 111590,
      "output_tokens": 75,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1919,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 75,
          "cache_read_input_tokens": 111590,
          "cache_creation_input_tokens": 1919,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1919
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

_source line 807 · 2026-05-20T10:08:37.500Z_

<details><summary>↩ Tool result · `toolu_01MAhn3gyfgjYprSb2kncjz6`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "TodoWrite"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "43cebe67-02be-4511-b38b-cd716b6d718f",
  "isSidechain": false,
  "promptId": "0bc1eef6-835a-4ee4-a8a1-06010792cb3b",
  "type": "user",
  "uuid": "edcce8f8-2c34-4927-89c7-bbf54b2fe635",
  "toolUseResult": {
    "matches": [
      "TodoWrite"
    ],
    "query": "select:TodoWrite",
    "total_deferred_tools": 51
  },
  "sourceToolAssistantUUID": "43cebe67-02be-4511-b38b-cd716b6d718f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Tool call

_source line 808 · 2026-05-20T10:08:41.984Z_

<details open><summary>🔧 Tool call — TodoWrite · `toolu_01SDiP9G8UCfnFunQTrfT1kQ`</summary>

```json
{
  "todos": [
    {
      "content": "Generate writing_plan.yaml for D130 Reframe",
      "status": "in_progress",
      "activeForm": "Generating writing_plan.yaml for D130 Reframe"
    },
    {
      "content": "Save writing_plan.yaml via save_project_file",
      "status": "pending",
      "activeForm": "Saving writing_plan.yaml"
    },
    {
      "content": "Post writing_plan summary to Director for approval",
      "status": "pending",
      "activeForm": "Posting writing_plan summary to Director"
    }
  ]
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "edcce8f8-2c34-4927-89c7-bbf54b2fe635",
  "isSidechain": false,
  "requestId": "req_011CbDduJiY2DVAYCNX1R2FF",
  "type": "assistant",
  "uuid": "461157c9-1389-45e9-8a78-2dcd2b86e082",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GKWid25Q3xUCmtjbBQmkxs",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2466,
      "cache_read_input_tokens": 113509,
      "output_tokens": 177,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2466,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 177,
          "cache_read_input_tokens": 113509,
          "cache_creation_input_tokens": 2466,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2466
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

_source line 809 · 2026-05-20T10:08:41.988Z_

<details><summary>↩ Tool result · `toolu_01SDiP9G8UCfnFunQTrfT1kQ`</summary>

```text
Todos have been modified successfully. Ensure that you continue to use the todo list to track your progress. Please proceed with the current tasks if applicable
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "461157c9-1389-45e9-8a78-2dcd2b86e082",
  "isSidechain": false,
  "promptId": "0bc1eef6-835a-4ee4-a8a1-06010792cb3b",
  "type": "user",
  "uuid": "099974e5-b2a9-4dd0-9cb7-74197878cbb3",
  "toolUseResult": {
    "oldTodos": [],
    "newTodos": [
      {
        "content": "Generate writing_plan.yaml for D130 Reframe",
        "status": "in_progress",
        "activeForm": "Generating writing_plan.yaml for D130 Reframe"
      },
      {
        "content": "Save writing_plan.yaml via save_project_file",
        "status": "pending",
        "activeForm": "Saving writing_plan.yaml"
      },
      {
        "content": "Post writing_plan summary to Director for approval",
        "status": "pending",
        "activeForm": "Posting writing_plan summary to Director"
      }
    ],
    "verificationNudgeNeeded": false
  },
  "sourceToolAssistantUUID": "461157c9-1389-45e9-8a78-2dcd2b86e082",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Assistant

_source line 810 · 2026-05-20T10:08:46.824Z_

Now generating the writing_plan.yaml for the D130 Reframe. The current paper is ~39 pages and must compress to 8 pages main text. Key structural changes: phase transition becomes the headline discovery, MMCT downgrades to supporting tool, and most detailed content moves to appendix.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "099974e5-b2a9-4dd0-9cb7-74197878cbb3",
  "isSidechain": false,
  "requestId": "req_011CbDdudWsuy9JCMXxk51u9",
  "type": "assistant",
  "uuid": "1dd9d9a9-bed3-4b96-b1a0-456229effea5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0146E7uTKGZ7hWxPdWVVa99f",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 216,
      "cache_read_input_tokens": 115975,
      "output_tokens": 8556,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 216,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 8556,
          "cache_read_input_tokens": 115975,
          "cache_creation_input_tokens": 216,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 216
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

_source line 811 · 2026-05-20T10:11:45.816Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__save_project_file · `toolu_01A5t9H6oEaRdrisDgNJNWYX`</summary>

```json
{
  "project": "distrib_canary_collapse",
  "file": "writing_plan.yaml",
  "content": "meta:\n  title: \"A Detection Phase Transition in Iterative Training Collapse\"\n  venue: EMNLP 2026\n  track: main\n  deadline: \"2026-06-15 (ARR submission)\"\n  format: \"ACL/EMNLP two-column, 8 pages main text + unlimited references/appendix\"\n  template: \"acl2023\"\n  template_note: \"EMNLP 2026 沿用 ACL 格式。Reframe 不改模板。\"\n  core_claim: \"Causal detectability of iterative training collapse undergoes a near-discontinuous phase transition at α_c=0.476 (sigmoid R²=0.969, Δα≈0.02), predicted by a signal-times-resolution framework that explains the four-regime dose-response and confirmed across 14 model-seed combinations spanning six families (345M–6.9B).\"\n  word_budget_total: 3500\n  citation_budget: 35-40\n  status: pending_approval\n  created_at: \"2026-05-20\"\n  reframe_from: \"Method Matters: Pitfalls and a Multi-Method Consensus Framework for Lead-Lag Analysis in Iterative Training Collapse\"\n  reframe_rationale: >\n    D130: 从 Methodology Paper 转型为 Discovery Paper。\n    Detection phase transition 升格为核心发现 (C1)；\n    S×R theory 升格为理论贡献 (C2)；\n    MMCT 降级为 evaluation tool (C3)；\n    Canary-based cessation 保留为 practical contribution (C4)。\n    当前 39 页正文须压缩至 8 页主文 + 无限附录。\n\n# ============================================================\n# Contributions (D130 四贡献结构)\n# ============================================================\ncontributions:\n  C1:\n    label: \"Detection Phase Transition\"\n    summary: \"Near-discontinuous onset of causal detectability at α_c=0.476 (sigmoid R²=0.969, k≥200, Δα≈0.02) despite only 0.15pp cumulative contamination difference across the boundary.\"\n    primary_evidence: \"Sigmoid regression on 12-point α grid; 0/8→6/8 jump; power-law ΔAIC=18.2\"\n    status: established\n\n  C2:\n    label: \"S×R Theory\"\n    summary: \"Detectability(α) ∝ S(α) × R(α) framework predicts four regimes: blind (α≤0.45), onset (α≈0.50), synchronous dip (α≈0.60), detection (α≥0.75). Per-generation signal threshold explains why cumulative contamination is irrelevant.\"\n    primary_evidence: \"Empirical four-regime dose-response matches predictions; dual-seed confirmation at α=0.60\"\n    status: established\n    open_question: \"D130 mentions 5 regimes (blind→onset→sync dip→recovery→saturation). Current paper has 4 (detection not split). See open_questions.OQ01.\"\n\n  C3:\n    label: \"Multi-Method Evaluation Toolkit\"\n    summary: \"Five-method comparison through MMCT identifies PermG as the only method with zero null-control FPR and high sensitivity. Three pitfalls (method sensitivity 62.5%, spurious regression, regime dependence) condition all subsequent interpretation.\"\n    primary_evidence: \"FPR=0%/FNR=0% at reference extremes; κ=0.185; Shapley analysis\"\n    status: established\n    note: \"Downgraded from C1 (old plan) to C3 (supporting tool). Detailed MMCT formalization → appendix.\"\n\n  C4:\n    label: \"Canary-Based Predictive Cessation\"\n    summary: \"15% entropy threshold fires one generation earlier than reactive cessation, reducing peak perplexity by 58% (bootstrap CI 29–64%). Validated across 410M and 1.4B.\"\n    primary_evidence: \"Intervention experiments at α=1.0; cross-scale replication\"\n    status: established\n\n# ============================================================\n# Story Arc\n# ============================================================\nstory_arc:\n  hook: \"Two training runs with 99.75% vs 99.90% cumulative synthetic contamination produce categorically different detection outcomes (0/8 vs 6/8 Granger-significant pairs).\"\n  gap: \"Existing canary studies lack methodological rigor AND miss the fact that detectability itself has a phase transition — it is not gradual but near-discontinuous.\"\n  insight: \"Causal coupling between canary and downstream metrics emerges abruptly at a critical contamination threshold (α_c=0.476), explained by the competition between rising signal strength and non-monotonic temporal resolution.\"\n  mechanism: \"The S×R framework: Detectability ∝ Signal × Resolution. Signal rises monotonically; resolution dips at intermediate α due to relaxation time matching, creating a four-regime dose-response.\"\n  evidence: \"α_c=0.476, sigmoid R²=0.969, Δα≈0.02; 12/14 cross-architecture conditions; 24/24 forward, 0/24 reverse.\"\n\n# ============================================================\n# Paper Outline (8 pages main text)\n# ============================================================\npaper_outline:\n  - section: abstract\n    word_budget: 200\n    dependencies: [results, theory_and_method, introduction]\n    core_bullets:\n      - \"Hook: Method choice inflates spurious rates to 62.5%; the right method reveals a detection phase transition\"\n      - \"Discovery: Near-discontinuous onset at α_c=0.476 (sigmoid R²=0.969, Δα≈0.02) despite <0.2pp cumulative contamination difference\"\n      - \"Theory: S×R framework predicts four regimes including non-monotonic synchronous dip\"\n      - \"Validation: 12/14 cross-architecture conditions (6 families, 345M–6.9B); directional asymmetry 24/24 fwd, 0/24 rev\"\n      - \"Application: Entropy-based cessation reduces peak perplexity 58%, fires one generation earlier\"\n\n  - section: introduction\n    word_budget: 700\n    page_budget: 1.3\n    dependencies: []\n    core_bullets:\n      - \"Hook: 99.75% vs 99.90% cumulative contamination → 0/8 vs 6/8 detection (specific, surprising)\"\n      - \"Context: Model collapse is established; canary metrics proposed but methodology weak\"\n      - \"Gap: No prior work maps detectability as a function of contamination level; implicit assumption that detection scales smoothly with contamination\"\n      - \"Discovery: Near-discontinuous onset at α_c=0.476 — a detection phase transition\"\n      - \"C1: Phase transition (α_c, sigmoid, Δα)\"\n      - \"C2: S×R theory predicting four-regime structure\"\n      - \"C3: Multi-method toolkit identifying PermG (downgraded from prior framing)\"\n      - \"C4: Canary-based cessation (58% perplexity reduction)\"\n      - \"Scoping: Granger precedence ≠ causality; diversity metrics only\"\n    figures: [fig_phase_transition]\n    citation_hints:\n      - \"shumailov2024curse, alemohammad2024mad — collapse foundations\"\n      - \"scheffer2009early, boettiger2012limits — EWS theoretical motivation\"\n      - \"shojaie2022granger — Granger methodology\"\n\n  - section: background_and_related_work\n    word_budget: 450\n    page_budget: 0.85\n    dependencies: [introduction]\n    core_bullets:\n      - \"Iterative training loop: M_t, D_synth, α mixing (2–3 sentences, compressed from current §3)\"\n      - \"Model collapse: shumailov, alemohammad, dohmatob, truong — 1–2 sentences each\"\n      - \"Canary/monitoring: du2026geometric, SIGMA, DCES — 1 sentence each + shared limitations\"\n      - \"EWS/tipping points: scheffer, boettiger — detection power in short series\"\n      - \"Granger methodology: granger1969, shojaie2022 — brief\"\n      - \"Differentiation from du2026geometric: multi-metric, multi-method, regime mapping, method sensitivity as finding\"\n    tables: []\n    figures: []\n    appendix_refs: [\"Full method comparison table (Table A.x) in Appendix\"]\n\n  - section: theory_and_method\n    word_budget: 900\n    page_budget: 1.7\n    dependencies: [background_and_related_work]\n    subsections:\n      - name: \"Signal × Resolution Framework\"\n        word_budget: 550\n        core_bullets:\n          - \"Continuous vs discrete response: entropy smooth functional, distinct-n counting statistic with threshold τ_n\"\n          - \"Detectability(α) ∝ S(α) × R(α) — Eq.(1)\"\n          - \"S monotonic; R non-monotonic (relaxation time matching at intermediate α)\"\n          - \"Four regime predictions: blind, onset, synchronous dip, detection\"\n          - \"Per-generation signal threshold: Δh(g) ∝ α · d_TV; cumulative contamination irrelevant\"\n          - \"Effective rank mechanistic chain: H↓ → erank↓ → tail below τ_n → D_k↓\"\n          - \"Cross-disciplinary: hormesis dose-response [1 sentence], zero-lag GC failure [1 sentence]\"\n          - \"Speculative connections: gu2024cmr scaling law, truong2025entropy universality classes [2 sentences]\"\n      - name: \"Multi-Method Evaluation\"\n        word_budget: 350\n        core_bullets:\n          - \"Three pitfalls in 1 condensed paragraph: method sensitivity (62.5%, κ=0.185), spurious regression (canary→ppl F≈0 after differencing), regime dependence (0/8→6/8)\"\n          - \"Five methods: naive XCorr, diff XCorr, threshold onset, PermG, TY — listed with 1-sentence characterization each\"\n          - \"Key comparison table (tab_method_summary): null FPR + detection rates\"\n          - \"PermG recommendation: zero FPR, high sensitivity, clean directional separation\"\n          - \"MMCT formalization → Appendix A; main text states result only\"\n          - \"FPR=0%/FNR=0% at reference extremes (1 sentence)\"\n    tables: [tab_method_summary]\n    figures: []\n    registry_refs: [method_ablation_phase1, method_ablation_phase2]\n\n  - section: results\n    word_budget: 1000\n    page_budget: 2.3\n    dependencies: [theory_and_method]\n    subsections:\n      - name: \"Detection Phase Transition\"\n        word_budget: 450\n        core_bullets:\n          - \"12-point α grid: 0/8 through α=0.45, 6/8 at α=0.50 (dual-seed), dip 0–3/8 at 0.60, 5–6/8 at ≥0.75\"\n          - \"Sigmoid regression: α_c=0.476, k≥200, R²=0.969 vs power-law 0.808, ΔAIC=18.2\"\n          - \"Cumulative contamination paradox: C(0.45,10)=99.75% vs C(0.50,10)=99.90% → 0/8 vs 6/8\"\n          - \"Four-regime dose-response (Figure 2): confirms S×R predictions\"\n          - \"Non-monotonic dip at α=0.60: dual-seed confirmed; synchronous collapse zone\"\n          - \"Canary blind spot at α=0.10: distinct-1 ↓39.6% but entropy indistinguishable from null\"\n          - \"Onset boundary narrowed to ≤0.05-wide interval via α=0.35/0.40/0.45 probing\"\n        figures: [fig_dose_response]\n        registry_refs: [alpha_sweep_a000_s42, alpha_sweep_a025_s42_v3, alpha_sweep_a050_s42, alpha_sweep_a075_s42, mvp_v4_rep42]\n\n      - name: \"Cross-Architecture Validation\"\n        word_budget: 300\n        core_bullets:\n          - \"14 conditions, 6 families (Pythia/GPT-2/OPT/Qwen/SmolLM3/Padding), 345M–6.9B\"\n          - \"PermG fwd ≥6/8 in 12/14 (86%); K≥3 in 10/14\"\n          - \"Directional asymmetry: 24/24 forward, 0/24 reverse on WikiText-103 at α=1.0\"\n          - \"Domain-dependent: C4 exhibits bidirectional coupling (PermG rev 7/8 at α=0.50)\"\n          - \"Onset boundary α_c≈0.50 consistent across all six families\"\n          - \"Exceptions: Pythia-1.4B s42 (seed-dependent), SmolLM3 (canary metric splitting — ECE only)\"\n        tables: [tab_generalization]\n        registry_refs: [cross_architecture_experiments]\n\n      - name: \"Canary-Based Intervention\"\n        word_budget: 250\n        core_bullets:\n          - \"Predictive cessation: 15% entropy threshold triggers at gen 1; reactive at gen 2\"\n          - \"Peak perplexity reduced 58% (bootstrap CI 29–64%, 2 seed-precision pairs)\"\n          - \"Cross-scale: 410M (s42 fp32, s43 bf16) and 1.4B (s42 fp32) — identical pattern\"\n          - \"Threshold fires at α=0.75 (entropy ↓31.6% at gen 1) and α=0.60 (↓31.3%)\"\n          - \"At α=0.60, threshold succeeds where formal Granger fails (synchronous zone)\"\n        figures: [fig_metric_trajectory]\n        registry_refs: [intervention_experiments]\n\n  - section: discussion_and_conclusion\n    word_budget: 450\n    page_budget: 0.85\n    dependencies: [results]\n    core_bullets:\n      - \"Granger ≠ causation (1 sentence, cite shojaie2022)\"\n      - \"Four-layer detection taxonomy: (1) dimensionality/erank onset ~0.10, (2) instability/variance onset ~0.25, (3) coupling/PermG onset ~0.50, (4) dynamical/AC1 onset ~0.50 suggestive\"\n      - \"Suggestive CSD: AC1 +0.30 jump at onset, variance 10× at α=0.25 — not conclusive at T=11\"\n      - \"Practical utility paradox: works best at high α; continuous monitoring resolves this\"\n      - \"Domain-dependent directionality: WikiText unidirectional, C4 bidirectional\"\n      - \"Prevention paradox under intervention (brief)\"\n      - \"Summary: 3–4 sentences recapping C1–C4\"\n      - \"Future work: longer T, multivariate VAR, >7B models, accumulate mode, CSD with T≥50\"\n\n  - section: limitations\n    word_budget: 400\n    dependencies: [discussion_and_conclusion]\n    core_bullets:\n      - \"Scale ≤1.4B; 7B+ untested (compute cost)\"\n      - \"Data: 5K WikiText-103 subset; C4 pre-training confound\"\n      - \"Short T=10 (11 points); T≥20 would improve power\"\n      - \"Bivariate Granger ≠ causality; cannot exclude confounders\"\n      - \"Replace-only protocol; accumulate mode untested\"\n      - \"Scoped to diversity metrics (distinct-n), not model collapse broadly\"\n      - \"Regime boundary ±0.05 uncertainty; sigmoid sharpness at other scales open\"\n      - \"Intervention only at α=1.0; 15% threshold at partial contamination unvalidated\"\n    note: \"Does not count toward 8-page limit per EMNLP 2026 rules\"\n\n# ============================================================\n# Visualization Plan\n# ============================================================\nvisualization_plan:\n  # --- Main text (3 figures) ---\n  - fig_id: fig_phase_transition\n    type: statistical\n    tool: matplotlib\n    description: \"HERO FIGURE: Sigmoid fit to PermG forward detection rate across 12 α levels, showing near-discontinuous onset at α_c=0.476.\"\n    narrative_intent: \"Causal detectability jumps from 0/8 to 6/8 within a Δα≈0.02 interval despite cumulative contamination barely changing — this is a detection phase transition, not a gradual onset.\"\n    design_notes:\n      - \"Pattern A: regime bands — four zones (blind/onset/dip/detection) as shaded vertical bands\"\n      - \"Sigmoid curve overlaid on empirical data points with error bars where multi-seed\"\n      - \"Annotate α_c=0.476, R²=0.969 on curve\"\n      - \"Inset or margin annotation: C(0.45)=99.75% vs C(0.50)=99.90%\"\n      - \"Dual y-axis or right margin: cumulative contamination C scale\"\n    placement: \"Figure 1, Introduction\"\n    aspect_ratio: \"single column (3.25in × 2.5in)\"\n    data_source: \"artifacts/phase_transition/; registry alpha_sweep experiments\"\n    output_path: \"projects/distrib_canary_collapse/figures/paper/fig_phase_transition.pdf\"\n    status: DONE_REMOTE\n    note: \"Exists on westd-17855. Need transfer + possible redesign for hero placement.\"\n\n  - fig_id: fig_dose_response\n    type: statistical\n    tool: matplotlib\n    description: \"Four-regime dose-response: PermG forward detection rate vs α across full 12-point grid.\"\n    narrative_intent: \"The non-monotonic profile confirms S×R theory predictions: blind→onset→synchronous dip→detection, with the dip at α≈0.60 confirming relaxation time matching.\"\n    design_notes:\n      - \"Pattern A: regime bands (4 zones) matching fig_phase_transition colors\"\n      - \"Per-seed points where dual/triple-seed available (not just mean)\"\n      - \"Orange diamond or distinct marker for α=0.60 dip\"\n      - \"Consistent color scheme with fig_phase_transition\"\n    placement: \"Results §5.1\"\n    aspect_ratio: \"single column (3.25in × 2.5in)\"\n    data_source: \"registry: alpha_sweep_* experiments\"\n    output_path: \"projects/distrib_canary_collapse/figures/paper/fig_dose_response.pdf\"\n    status: DONE\n    artifact_id: art_20260515_06ffe6\n    note: \"Existing fig_regime_map. May need relabeling/restyling for discovery framing.\"\n\n  - fig_id: fig_metric_trajectory\n    type: statistical\n    tool: matplotlib\n    description: \"Token entropy and distinct-1 trajectories at α=1.0 (4 seeds), showing one-generation canary lead.\"\n    narrative_intent: \"Token entropy drops at generation 1, one full generation before diversity responds — this visible temporal offset is what the canary-based cessation exploits.\"\n    design_notes:\n      - \"Dual panel or normalized overlay\"\n      - \"Vertical annotations: gen 1 (canary fires), gen 2 (diversity responds)\"\n      - \"4-seed individual traces with shaded inter-seed range\"\n      - \"Clean, minimal — let the temporal offset speak\"\n    placement: \"Results §5.3\"\n    aspect_ratio: \"single column (3.25in × 2.5in)\"\n    data_source: \"registry: mvp_v4_rep42, mvp_v4_rep43, mvp_v4_rep44, mvp_v4_rep45\"\n    output_path: \"projects/distrib_canary_collapse/figures/paper/fig_metric_trajectory.pdf\"\n    status: TODO\n\n  # --- Appendix figures (moved from main) ---\n  - fig_id: fig_consensus_heatmap\n    type: heatmap\n    tool: matplotlib\n    description: \"Method×regime consensus heatmap — moved to Appendix\"\n    placement: \"Appendix C: Method Sensitivity Details\"\n    status: DONE\n    artifact_id: art_20260515_97707a\n\n  - fig_id: fig_differencing_dmax\n    type: multi_panel\n    tool: matplotlib\n    description: \"First-differencing diagnostic + d_max sensitivity — moved to Appendix\"\n    placement: \"Appendix C: Method Sensitivity Details\"\n    status: TODO\n\n  - fig_id: fig_consensus_workflow\n    type: multi_panel\n    tool: matplotlib\n    description: \"Consensus pipeline funnel diagram — moved to Appendix\"\n    placement: \"Appendix B: MMCT Formalization\"\n    status: DONE\n    artifact_id: art_20260515_390d50\n\n  - fig_id: fig_shapley\n    type: statistical\n    tool: matplotlib\n    description: \"Shapley method contribution decomposition — moved to Appendix\"\n    placement: \"Appendix D: Shapley Analysis\"\n    status: DONE\n\n# ============================================================\n# Table Plan\n# ============================================================\ntable_plan:\n  # --- Main text (2 tables) ---\n  - table_id: tab_method_summary\n    type: comparison\n    caption: \"Lead-lag detection method comparison. Null-control FPR and forward detection rates across contamination levels. PermG is the only method with zero FPR and consistent detection at α≥0.50.\"\n    columns: [\"Method\", \"FPR (null)\", \"α=0.50\", \"α=0.75\", \"α=1.0\"]\n    data_source: \"registry: method_ablation_phase2; existing tab_method_comparison\"\n    placement: \"Theory+Method §4.2\"\n    notes: \"Compressed from 6-column table. 5 methods, focus on key α levels.\"\n\n  - table_id: tab_generalization\n    type: comparison\n    caption: \"Cross-architecture detection at α=1.0. PermG fwd ≥6/8 in 12/14 confirmed conditions across six model families (345M–6.9B).\"\n    columns: [\"Model\", \"Params\", \"Domain\", \"PermG (fwd)\", \"K≥3\"]\n    data_source: \"registry: cross-architecture experiments\"\n    placement: \"Results §5.2\"\n    notes: \"Compressed. Group by family. 14 rows + footnotes for exceptions.\"\n\n  # --- Appendix tables (moved from main) ---\n  - table_id: tab_drift_summary\n    type: metric_comparison\n    caption: \"Metric drift across contamination levels\"\n    placement: \"Appendix E: Drift and Raw Data\"\n    data_source: \"registry: alpha_sweep experiments\"\n    notes: \"Currently main text Table 1. Moves to appendix in reframe.\"\n\n  - table_id: tab_fpr_fnr\n    type: calibration\n    caption: \"FPR/FNR calibration for individual methods and consensus\"\n    placement: \"Appendix B: Calibration Details\"\n\n  - table_id: tab_practical_guidance\n    type: guidance\n    caption: \"4-tier practical guidance tiers\"\n    placement: \"Appendix B: Calibration Details\"\n\n  - table_id: tab_single_method_errors\n    type: comparison\n    caption: \"Single-method inference errors across α levels\"\n    placement: \"Appendix C: Method Sensitivity\"\n\n  - table_id: tab_cross_arch_regime\n    type: comparison\n    caption: \"Cross-architecture regime map at α=0.25 and 1.0\"\n    placement: \"Appendix F: Cross-Architecture Details\"\n\n  - table_id: tab_mmct_ablation\n    type: comparison\n    caption: \"MMCT per-method detection rates\"\n    placement: \"Appendix B: MMCT Formalization\"\n\n  - table_id: tab_mmct_cross\n    type: comparison\n    caption: \"MMCT cross-condition stability\"\n    placement: \"Appendix B: MMCT Formalization\"\n\n  - table_id: tab_method_comparison_full\n    type: comparison\n    caption: \"Full methodological comparison of canary analyses in literature\"\n    placement: \"Appendix or Related Work\"\n    notes: \"Current tab:method-comparison. May stay in compressed RW or move to appendix.\"\n\n# ============================================================\n# Literature Strategy\n# ============================================================\nliterature_strategy:\n  note: \"No new literature search needed for reframe. Existing literature_map.yaml sufficient. Focus on compression and re-prioritization.\"\n  citation_budget: 35-40\n  macro_context: \"Model collapse → detection phase transition → S×R theory → early-warning signals → Granger methodology\"\n  micro_clusters:\n    - cluster_name: core_collapse\n      must_cite: [shumailov2024curse, alemohammad2024mad, dohmatob2024tale, truong2025entropy]\n      target_count: 4\n    - cluster_name: canary_monitoring\n      must_cite: [du2026geometric, sigma2026spectral]\n      target_count: 3\n    - cluster_name: data_mixing\n      must_cite: [kazdan2025collapse, dey2024breaking]\n      target_count: 2\n    - cluster_name: early_warning\n      must_cite: [scheffer2009early, boettiger2012limits, dakos2012methods]\n      target_count: 3\n    - cluster_name: granger_methodology\n      must_cite: [granger1969investigating, shojaie2022granger, toda1995statistical, granger1974spurious]\n      target_count: 4\n    - cluster_name: phase_transition_theory\n      must_cite: [gu2024cmr, calabrese2003hormesis, titus2020speeding, deshpande2010instantaneous]\n      target_count: 4\n    - cluster_name: analytical_robustness\n      must_cite: [simonsohn2020specification, bell2022modeling]\n      target_count: 2\n    - cluster_name: diversity_metrics\n      must_cite: [li2016diversity, biderman2023pythia]\n      target_count: 2\n\n# ============================================================\n# Writing Order (Reframe = mini Full Draft, all sections rewritten)\n# ============================================================\nwriting_order:\n  - step: 1\n    section: results\n    rationale: \"Hero section. Lock down phase transition numbers, cross-architecture table, intervention data. All other sections reference these.\"\n  - step: 2\n    section: theory_and_method\n    rationale: \"S×R framework predicts results; method comparison justifies PermG. Depends on knowing exact result numbers.\"\n  - step: 3\n    section: introduction\n    rationale: \"Frames the discovery. Needs final numbers from Results + theoretical context from Theory.\"\n  - step: 4\n    section: background_and_related_work\n    rationale: \"Position paper. Needs Introduction's framing to determine emphasis.\"\n  - step: 5\n    section: discussion_and_conclusion\n    rationale: \"Implications, taxonomy, future work. After all results and theory finalized.\"\n  - step: 6\n    section: limitations\n    rationale: \"Honest scope assessment. After all claims finalized.\"\n  - step: 7\n    section: abstract\n    rationale: \"Last — summarizes everything.\"\n\n# ============================================================\n# Appendix Strategy\n# ============================================================\nappendix_strategy:\n  note: >\n    Current 39-page paper compresses to 8 pages main text.\n    Appendix absorbs all detailed formalizations, secondary analyses,\n    and expanded tables. Main text references appendix sections explicitly.\n  structure:\n    - id: \"Appendix A\"\n      title: \"Experimental Setup Details\"\n      content: \"Full training hyperparameters, metric definitions, statistical test parameters. Expanded from current §5.1.\"\n    - id: \"Appendix B\"\n      title: \"MMCT Formalization and Calibration\"\n      content: \"Algorithm 1, FPR-inverse weighting equations, FPR/FNR tables, practical guidance tiers, MMCT ablation tables, consensus workflow figure.\"\n    - id: \"Appendix C\"\n      title: \"Method Sensitivity Analysis\"\n      content: \"Five-method ablation details, differencing diagnostic figure, d_max sensitivity, inter-method agreement (κ), consensus heatmap, single-method error table.\"\n    - id: \"Appendix D\"\n      title: \"Shapley Decomposition and Power Analysis\"\n      content: \"Shapley figure, bootstrap power analysis, transfer entropy results.\"\n    - id: \"Appendix E\"\n      title: \"Metric Drift and Raw Data\"\n      content: \"Drift summary table, distinct-3 results, canary blind spot details.\"\n    - id: \"Appendix F\"\n      title: \"Cross-Architecture Details\"\n      content: \"Per-condition method-level breakdown, SmolLM3 case study, cross-architecture regime table, Pythia-1.4B seed sensitivity.\"\n    - id: \"Appendix G\"\n      title: \"Extended Discussion\"\n      content: \"Token entropy vs perplexity, NLP-specific constraints, prevention paradox details, change-point analysis, sequential monitoring (CUSUM), observation window sensitivity.\"\n    - id: \"Appendix H\"\n      title: \"Intervention Details\"\n      content: \"Full intervention trajectories, bf16 vs fp32 comparison, threshold sensitivity.\"\n\n# ============================================================\n# Presentation Constraints\n# ============================================================\npresentation_constraints:\n  # Inherited from old plan\n  - id: PC01\n    source: D038\n    rule: \"α=0.75 vs α=1.0 consensus scores cannot be directly compared (different standards: single-seed vs 4-seed)\"\n  - id: PC07\n    source: paper_framing\n    rule: \"Cannot claim canary predicts model collapse; only diversity collapse\"\n  - id: PC10\n    source: paper_framing\n    rule: \"f² effect size: Cohen benchmarks forbidden (df_resid<20); permutation p-value is primary inference evidence\"\n  - id: PC11\n    source: paper_framing\n    rule: \"Granger precedence ≠ true causality; Discussion must state this\"\n  - id: PC14\n    source: paper_framing\n    rule: \"Strength words restricted: single dataset → no 'consistently outperforms'/'state-of-the-art'; no stat test → no 'significantly'\"\n  # New D130 constraints\n  - id: PC_D130_01\n    source: D130\n    rule: \"Phase transition is core discovery (C1); MMCT downgraded to C3\"\n  - id: PC_D130_02\n    source: D130\n    rule: \"'detection phase transition' OK on own data; 'phase transition' alone too strong\"\n  - id: PC_D130_03\n    source: D130\n    rule: \"CSD = 'suggestive' not 'confirmed' at T=11\"\n  - id: PC_D130_04\n    source: D130\n    rule: \"'robust across architectures' OK; 'universal' too strong\"\n  - id: PC_D130_05\n    source: D130\n    rule: \"Main text ≤8 pages strictly; unlimited appendix and references\"\n\n# ============================================================\n# Open Questions (for Director decision)\n# ============================================================\nopen_questions:\n  - id: OQ01\n    question: >\n      D130 C2 describes 5 regimes (blind → onset → sync dip → recovery → saturation),\n      but current paper uses 4 regimes (blind → onset → sync dip → detection).\n      Data shows 5–6/8 at α=0.75 and 6/8 at α=1.0 — marginal difference.\n      Should we split 'detection' into 'recovery' and 'saturation'?\n    recommendation: >\n      Keep 4 regimes. The data does not clearly distinguish recovery from saturation\n      (detection rates 5–6/8 vs 6/8, within seed variance). Adding a 5th regime\n      without stronger evidence would weaken the claim. If Director prefers 5,\n      we need to define the boundary criterion.\n\n  - id: OQ02\n    question: >\n      Gu citation: keep only gu2024cmr (EMNLP 2024, verified), or restore\n      gu2025datamixing (claimed NeurIPS 2025 Spotlight, unverified) alongside?\n    recommendation: \"Keep gu2024cmr only until Director provides verified venue/DOI for gu2025datamixing.\"\n\n  - id: OQ03\n    question: \"fig_phase_transition.pdf exists only on westd-17855. Needs transfer to local for compilation.\"\n    action: \"Spawn Worker to transfer, or flag for Main Agent.\"\n\n  - id: OQ04\n    question: >\n      Current main.tex uses basic article class with geometry package.\n      For EMNLP 2026, should we switch to official acl2023.sty two-column format\n      to verify 8-page fit during rewrite?\n    recommendation: \"Yes — switch to acl2023.sty before writing to catch overflow early.\"\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1dd9d9a9-bed3-4b96-b1a0-456229effea5",
  "isSidechain": false,
  "requestId": "req_011CbDdudWsuy9JCMXxk51u9",
  "type": "assistant",
  "uuid": "de64165c-3fd9-4d0b-bd35-c9268227cb75",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0146E7uTKGZ7hWxPdWVVa99f",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 216,
      "cache_read_input_tokens": 115975,
      "output_tokens": 8556,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 216,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 8556,
          "cache_read_input_tokens": 115975,
          "cache_creation_input_tokens": 216,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 216
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

_source line 812 · 2026-05-20T10:11:45.840Z_

<details><summary>↩ Tool result · `toolu_01A5t9H6oEaRdrisDgNJNWYX`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/writing_plan.yaml\", \"saved\": true}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "de64165c-3fd9-4d0b-bd35-c9268227cb75",
  "isSidechain": false,
  "promptId": "0bc1eef6-835a-4ee4-a8a1-06010792cb3b",
  "type": "user",
  "uuid": "e51ae754-ee24-4b2c-a08c-c67c950a70b8",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/writing_plan.yaml\\\", \\\"saved\\\": true}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/writing_plan.yaml\", \"saved\": true}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "de64165c-3fd9-4d0b-bd35-c9268227cb75",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Runtime record

_source line 813_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Director 指令] [Reframe — D130] 论文从 Methodology Paper 转型为 Detection Phase Transition Discovery Paper  投稿目标：EMNLP 2026 ARR June cycle，8 页 main text + unlimited references + appendix。当前 37 页需大幅压缩。  ## 核心…",
  "leafUuid": "e51ae754-ee24-4b2c-a08c-c67c950a70b8",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


### Runtime record

_source line 814_

```json
{
  "type": "ai-title",
  "aiTitle": "Correct effective_rank framework and add phase transition citations",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


### Tool call

_source line 815 · 2026-05-20T10:11:50.190Z_

<details open><summary>🔧 Tool call — TodoWrite · `toolu_01X8975AB6DJt5qf2yh3HQ1D`</summary>

```json
{
  "todos": [
    {
      "content": "Generate writing_plan.yaml for D130 Reframe",
      "status": "completed",
      "activeForm": "Generating writing_plan.yaml for D130 Reframe"
    },
    {
      "content": "Save writing_plan.yaml via save_project_file",
      "status": "completed",
      "activeForm": "Saving writing_plan.yaml"
    },
    {
      "content": "Post writing_plan summary to Director for approval",
      "status": "in_progress",
      "activeForm": "Posting writing_plan summary to Director"
    }
  ]
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e51ae754-ee24-4b2c-a08c-c67c950a70b8",
  "isSidechain": false,
  "requestId": "req_011CbDe9BQtQx5dhR2WUj61d",
  "type": "assistant",
  "uuid": "1e669427-1187-4909-9345-e2b11d0f74ed",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019QyRguS6uFAKMEF83sdasz",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8643,
      "cache_read_input_tokens": 116191,
      "output_tokens": 171,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 8643,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 171,
          "cache_read_input_tokens": 116191,
          "cache_creation_input_tokens": 8643,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 8643
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

_source line 816 · 2026-05-20T10:11:50.193Z_

<details><summary>↩ Tool result · `toolu_01X8975AB6DJt5qf2yh3HQ1D`</summary>

```text
Todos have been modified successfully. Ensure that you continue to use the todo list to track your progress. Please proceed with the current tasks if applicable
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "1e669427-1187-4909-9345-e2b11d0f74ed",
  "isSidechain": false,
  "promptId": "0bc1eef6-835a-4ee4-a8a1-06010792cb3b",
  "type": "user",
  "uuid": "e4ecc4ec-8bda-4142-9cf7-e2f1b4b80648",
  "toolUseResult": {
    "oldTodos": [
      {
        "content": "Generate writing_plan.yaml for D130 Reframe",
        "status": "in_progress",
        "activeForm": "Generating writing_plan.yaml for D130 Reframe"
      },
      {
        "content": "Save writing_plan.yaml via save_project_file",
        "status": "pending",
        "activeForm": "Saving writing_plan.yaml"
      },
      {
        "content": "Post writing_plan summary to Director for approval",
        "status": "pending",
        "activeForm": "Posting writing_plan summary to Director"
      }
    ],
    "newTodos": [
      {
        "content": "Generate writing_plan.yaml for D130 Reframe",
        "status": "completed",
        "activeForm": "Generating writing_plan.yaml for D130 Reframe"
      },
      {
        "content": "Save writing_plan.yaml via save_project_file",
        "status": "completed",
        "activeForm": "Saving writing_plan.yaml"
      },
      {
        "content": "Post writing_plan summary to Director for approval",
        "status": "in_progress",
        "activeForm": "Posting writing_plan summary to Director"
      }
    ],
    "verificationNudgeNeeded": false
  },
  "sourceToolAssistantUUID": "1e669427-1187-4909-9345-e2b11d0f74ed",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Tool call

_source line 817 · 2026-05-20T10:12:14.690Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__paper_agent_post_to_director · `toolu_01TgbuNoyZ327WW94MyNGhRz`</summary>

```json
{
  "text": "[写作进展] D130 Reframe — writing_plan.yaml 已生成，请审批\n\n## 概要\n\n**新标题**: \"A Detection Phase Transition in Iterative Training Collapse\"\n**目标**: EMNLP 2026 ARR June cycle, 8页主文 + 无限附录\n**总词数预算**: 3,500 words 主文 + 附录无限制\n\n## 四贡献结构 (D130)\n\n| # | Contribution | 主文篇幅 |\n|---|-------------|---------|\n| C1 | Detection Phase Transition (α_c=0.476, sigmoid R²=0.969) | Results §5.1 — hero |\n| C2 | S×R Theory (四regime预测) | Theory §4.1 |\n| C3 | Multi-Method Toolkit (PermG推荐) | Theory §4.2 — 压缩 |\n| C4 | Canary-Based Cessation (58% ppl reduction) | Results §5.3 |\n\n## 页面分配\n\n| Section | 页数 | 词数 |\n|---------|------|------|\n| Abstract | — | 200 |\n| Introduction + Fig 1 (hero) | 1.3p | 700 |\n| Background + Related Work | 0.85p | 450 |\n| Theory + Method (S×R + 压缩MMCT) | 1.7p | 900 |\n| Results (phase transition + cross-arch + intervention) | 2.3p + display items | 1,000 |\n| Discussion + Conclusion | 0.85p | 450 |\n| Limitations | 不计入8页 | 400 |\n\n## 主文 Display Items (5)\n\n- **Fig 1** (hero): Phase transition sigmoid — Introduction\n- **Fig 2**: Four-regime dose-response — Results §5.1\n- **Fig 3**: Metric trajectory (canary lead) — Results §5.3\n- **Table 1**: Method comparison (compressed) — Theory §4.2\n- **Table 2**: Cross-architecture generalization — Results §5.2\n\n## 附录迁移\n\n当前39页 → 8页：MMCT 形式化 (Algorithm 1)、Shapley分析、详细FPR/FNR表、differencing诊断图、consensus workflow图、drift summary表、SmolLM3 case study、sequential monitoring、transfer entropy等全部移入 Appendix A–H。\n\n## 需要 Director 决策的 Open Questions\n\n1. **OQ01 (regime数量)**: D130 C2 提到5 regimes (blind→onset→sync dip→recovery→saturation)，但当前论文基于数据使用4 regimes (detection未拆分)。α=0.75 (5–6/8) 与 α=1.0 (6/8) 差异在 seed variance 内。**建议保持4 regimes**，除非 Director 提供拆分标准。\n\n2. **OQ02 (Gu引用)**: 仅保留 gu2024cmr (EMNLP 2024, 已验证)，还是恢复 gu2025datamixing？等待 Director 确认。\n\n3. **OQ03 (fig_phase_transition.pdf)**: 仅存在于 westd-17855，需要传输到本地才能编译。\n\n4. **OQ04 (LaTeX模板)**: 建议在重写前切换到 acl2023.sty 双栏格式，以便在写作过程中验证8页限制。\n\n## 写作顺序\n\nResults → Theory+Method → Introduction → Background+RW → Discussion+Conclusion → Limitations → Abstract\n\n## 执行模式\n\n这是 Reframe (mini Full Draft)——所有章节按 writing_order 串行重写，每章用 write_paper_section() 全量覆写。预计完成时间：1–2天。\n\n**请审批 writing_plan.yaml，批准后立即启动 Step 1 (Results)。**",
  "project": "distrib_canary_collapse"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e4ecc4ec-8bda-4142-9cf7-e2f1b4b80648",
  "isSidechain": false,
  "requestId": "req_011CbDe9VyM6aH2dSRYsuvpM",
  "type": "assistant",
  "uuid": "aeed04e1-83ca-4a29-a8d8-a0c9be7d8868",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BN3Sq3aYWmhNDEwPfmKaoe",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 213,
      "cache_read_input_tokens": 124834,
      "output_tokens": 1149,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 213,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1149,
          "cache_read_input_tokens": 124834,
          "cache_creation_input_tokens": 213,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 213
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

_source line 818 · 2026-05-20T10:12:18.844Z_

<details><summary>↩ Tool result · `toolu_01TgbuNoyZ327WW94MyNGhRz`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"director_session\": \"feishu:group:oc_150c7ce908e05d7932315e0288cf5bfb:director\"}, \"error\": \"\"}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "aeed04e1-83ca-4a29-a8d8-a0c9be7d8868",
  "isSidechain": false,
  "promptId": "0bc1eef6-835a-4ee4-a8a1-06010792cb3b",
  "type": "user",
  "uuid": "655fff55-623f-43c6-b354-4299f46ca2d0",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"director_session\\\": \\\"feishu:group:oc_150c7ce908e05d7932315e0288cf5bfb:director\\\"}, \\\"error\\\": \\\"\\\"}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"director_session\": \"feishu:group:oc_150c7ce908e05d7932315e0288cf5bfb:director\"}, \"error\": \"\"}"
    }
  },
  "sourceToolAssistantUUID": "aeed04e1-83ca-4a29-a8d8-a0c9be7d8868",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Tool call

_source line 819 · 2026-05-20T10:12:22.412Z_

<details open><summary>🔧 Tool call — TodoWrite · `toolu_01TJYgK3FiXyNVoZPDB19AFK`</summary>

```json
{
  "todos": [
    {
      "content": "Generate writing_plan.yaml for D130 Reframe",
      "status": "completed",
      "activeForm": "Generating writing_plan.yaml for D130 Reframe"
    },
    {
      "content": "Save writing_plan.yaml via save_project_file",
      "status": "completed",
      "activeForm": "Saving writing_plan.yaml"
    },
    {
      "content": "Post writing_plan summary to Director for approval",
      "status": "completed",
      "activeForm": "Posting writing_plan summary to Director"
    }
  ]
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "655fff55-623f-43c6-b354-4299f46ca2d0",
  "isSidechain": false,
  "requestId": "req_011CbDeBcQ7AX3RrxUoyxq4v",
  "type": "assistant",
  "uuid": "629669a9-2cb6-420d-956f-6b152d0b7f7e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01V5fx8s1xgXF1LoEL5YHSA4",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1222,
      "cache_read_input_tokens": 125047,
      "output_tokens": 169,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1222,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 169,
          "cache_read_input_tokens": 125047,
          "cache_creation_input_tokens": 1222,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1222
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

_source line 820 · 2026-05-20T10:12:22.413Z_

<details><summary>↩ Tool result · `toolu_01TJYgK3FiXyNVoZPDB19AFK`</summary>

```text
Todos have been modified successfully. Ensure that you continue to use the todo list to track your progress. Please proceed with the current tasks if applicable
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "629669a9-2cb6-420d-956f-6b152d0b7f7e",
  "isSidechain": false,
  "promptId": "0bc1eef6-835a-4ee4-a8a1-06010792cb3b",
  "type": "user",
  "uuid": "7420589e-649f-441d-87b0-080cfb14d40f",
  "toolUseResult": {
    "oldTodos": [
      {
        "content": "Generate writing_plan.yaml for D130 Reframe",
        "status": "completed",
        "activeForm": "Generating writing_plan.yaml for D130 Reframe"
      },
      {
        "content": "Save writing_plan.yaml via save_project_file",
        "status": "completed",
        "activeForm": "Saving writing_plan.yaml"
      },
      {
        "content": "Post writing_plan summary to Director for approval",
        "status": "in_progress",
        "activeForm": "Posting writing_plan summary to Director"
      }
    ],
    "newTodos": [
      {
        "content": "Generate writing_plan.yaml for D130 Reframe",
        "status": "completed",
        "activeForm": "Generating writing_plan.yaml for D130 Reframe"
      },
      {
        "content": "Save writing_plan.yaml via save_project_file",
        "status": "completed",
        "activeForm": "Saving writing_plan.yaml"
      },
      {
        "content": "Post writing_plan summary to Director for approval",
        "status": "completed",
        "activeForm": "Posting writing_plan summary to Director"
      }
    ],
    "verificationNudgeNeeded": false
  },
  "sourceToolAssistantUUID": "629669a9-2cb6-420d-956f-6b152d0b7f7e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Runtime record

_source line 821_

```json
{
  "type": "ai-title",
  "aiTitle": "Correct effective_rank framework and add phase transition citations",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


### Runtime record

_source line 822 · 2026-05-20T10:12:31.445Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-20T10:12:31.445Z",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "content": "[系统提醒] 你刚才完成了 [Director 指令] 但没有调用 main_agent_post_to_director 汇报结果。Director 看不到你的文字回复。请立即调用 main_agent_post_to_director 将结果发给 Director。"
}
```

---


### Runtime record

_source line 823 · 2026-05-20T10:12:31.446Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-20T10:12:31.446Z",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


## Round 30

## Round 30

2 recorded events


### User

_source line 824 · 2026-05-20T10:12:31.433Z_

Continue from where you left off.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "7420589e-649f-441d-87b0-080cfb14d40f",
  "isSidechain": false,
  "promptId": "0cc987cf-2bfd-4fa5-b402-7b6563dc2d62",
  "type": "user",
  "isMeta": true,
  "uuid": "7e810461-c5ed-43bb-8536-a36646d000d3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Assistant

_source line 825 · 2026-05-20T10:12:31.433Z_

No response requested.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7e810461-c5ed-43bb-8536-a36646d000d3",
  "isSidechain": false,
  "type": "assistant",
  "uuid": "e0805ae6-4625-4d9c-9e76-ad989e547aba",
  "isApiErrorMessage": false,
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "id": "a6887206-d21c-403f-bf70-5b5fc3e86664",
    "container": null,
    "model": "&lt;synthetic>",
    "stop_reason": "stop_sequence",
    "stop_sequence": "",
    "type": "message",
    "usage": {
      "input_tokens": 0,
      "output_tokens": 0,
      "cache_creation_input_tokens": 0,
      "cache_read_input_tokens": 0,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": null,
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": null,
      "iterations": null,
      "speed": null
    },
    "context_management": null
  }
}
```

</details>

---


## Round 31

## Round 31

5 recorded events


### User

_source line 826 · 2026-05-20T10:12:31.550Z_

[系统提醒] 你刚才完成了 [Director 指令] 但没有调用 main_agent_post_to_director 汇报结果。Director 看不到你的文字回复。请立即调用 main_agent_post_to_director 将结果发给 Director。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e0805ae6-4625-4d9c-9e76-ad989e547aba",
  "isSidechain": false,
  "promptId": "0cc987cf-2bfd-4fa5-b402-7b6563dc2d62",
  "type": "user",
  "uuid": "cceb0303-3945-4022-be04-11b76fd04572",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Runtime record

_source line 827 · 2026-05-20T10:12:31.550Z_

```json
{
  "parentUuid": "cceb0303-3945-4022-be04-11b76fd04572",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "f05d913a-e953-4a0f-bd3b-80a674192783",
  "timestamp": "2026-05-20T10:12:31.550Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

---


### Runtime record

_source line 828_

```json
{
  "type": "ai-title",
  "aiTitle": "Correct effective_rank framework and add phase transition citations",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


### Runtime record

_source line 829 · 2026-05-20T10:12:39.714Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-20T10:12:39.714Z",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "content": "[系统提醒] 你刚才完成了 [Director 指令] 但没有调用 main_agent_post_to_director 汇报结果。Director 看不到你的文字回复。请立即调用 main_agent_post_to_director 将结果发给 Director。"
}
```

---


### Runtime record

_source line 830 · 2026-05-20T10:12:39.715Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-20T10:12:39.715Z",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


## Round 32

## Round 32

2 recorded events


### User

_source line 831 · 2026-05-20T10:12:39.702Z_

Continue from where you left off.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f05d913a-e953-4a0f-bd3b-80a674192783",
  "isSidechain": false,
  "promptId": "35e4a8ec-fba3-4100-99a2-d61b88d996ff",
  "type": "user",
  "isMeta": true,
  "uuid": "923c1fc6-7b93-4502-8372-98bb5c016a48",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Assistant

_source line 832 · 2026-05-20T10:12:39.702Z_

No response requested.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "923c1fc6-7b93-4502-8372-98bb5c016a48",
  "isSidechain": false,
  "type": "assistant",
  "uuid": "b982ce9f-620f-4d13-b43d-4bc04acd6652",
  "isApiErrorMessage": false,
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "id": "3b6eff4d-d080-4ae1-acd6-afe873421227",
    "container": null,
    "model": "&lt;synthetic>",
    "stop_reason": "stop_sequence",
    "stop_sequence": "",
    "type": "message",
    "usage": {
      "input_tokens": 0,
      "output_tokens": 0,
      "cache_creation_input_tokens": 0,
      "cache_read_input_tokens": 0,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": null,
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": null,
      "iterations": null,
      "speed": null
    },
    "context_management": null
  }
}
```

</details>

---


## Round 33

## Round 33

5 recorded events


### User

_source line 833 · 2026-05-20T10:12:39.818Z_

[系统提醒] 你刚才完成了 [Director 指令] 但没有调用 main_agent_post_to_director 汇报结果。Director 看不到你的文字回复。请立即调用 main_agent_post_to_director 将结果发给 Director。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b982ce9f-620f-4d13-b43d-4bc04acd6652",
  "isSidechain": false,
  "promptId": "35e4a8ec-fba3-4100-99a2-d61b88d996ff",
  "type": "user",
  "uuid": "e1055bbf-23fc-43b7-9737-f73d69515be2",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Runtime record

_source line 834_

```json
{
  "type": "ai-title",
  "aiTitle": "Correct effective_rank framework and add phase transition citations",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


### Runtime record

_source line 835 · 2026-05-20T10:12:48.338Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-20T10:12:48.338Z",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "content": "[系统提醒] 你刚才完成了 [Director 指令] 但没有调用 main_agent_post_to_director 汇报结果。Director 看不到你的文字回复。请立即调用 main_agent_post_to_director 将结果发给 Director。"
}
```

---


### Runtime record

_source line 836 · 2026-05-20T10:12:48.338Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-20T10:12:48.338Z",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


### Assistant

_source line 837 · 2026-05-20T10:12:48.327Z_

No response requested.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e1055bbf-23fc-43b7-9737-f73d69515be2",
  "isSidechain": false,
  "type": "assistant",
  "uuid": "6120b0ae-cc62-41e2-9d48-b514f2a96137",
  "isApiErrorMessage": false,
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "id": "e62bfc2e-8766-4232-9083-a468db4c6fd0",
    "container": null,
    "model": "&lt;synthetic>",
    "stop_reason": "stop_sequence",
    "stop_sequence": "",
    "type": "message",
    "usage": {
      "input_tokens": 0,
      "output_tokens": 0,
      "cache_creation_input_tokens": 0,
      "cache_read_input_tokens": 0,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": null,
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": null,
      "iterations": null,
      "speed": null
    },
    "context_management": null
  }
}
```

</details>

---


## Round 34

## Round 34

5 recorded events


### User

_source line 838 · 2026-05-20T10:12:48.435Z_

[系统提醒] 你刚才完成了 [Director 指令] 但没有调用 main_agent_post_to_director 汇报结果。Director 看不到你的文字回复。请立即调用 main_agent_post_to_director 将结果发给 Director。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "6120b0ae-cc62-41e2-9d48-b514f2a96137",
  "isSidechain": false,
  "promptId": "b389280b-ba18-4a0c-b572-e6f5f7e0fc47",
  "type": "user",
  "uuid": "3c74460a-ae4d-4c4e-a5df-ce0822e7a9b6",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Runtime record

_source line 839_

```json
{
  "type": "ai-title",
  "aiTitle": "Correct effective_rank framework and add phase transition citations",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


### Runtime record

_source line 840 · 2026-05-20T10:12:59.305Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-20T10:12:59.305Z",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "content": "[系统提醒] 你刚才完成了 [Director 指令] 但没有调用 main_agent_post_to_director 汇报结果。Director 看不到你的文字回复。请立即调用 main_agent_post_to_director 将结果发给 Director。"
}
```

---


### Runtime record

_source line 841 · 2026-05-20T10:12:59.305Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-20T10:12:59.305Z",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


### Assistant

_source line 842 · 2026-05-20T10:12:59.293Z_

No response requested.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3c74460a-ae4d-4c4e-a5df-ce0822e7a9b6",
  "isSidechain": false,
  "type": "assistant",
  "uuid": "e211d9d6-a8ef-4d95-a9a2-749a7a49a398",
  "isApiErrorMessage": false,
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "id": "633c2515-5dfb-490e-84a0-7d0cbb29d554",
    "container": null,
    "model": "&lt;synthetic>",
    "stop_reason": "stop_sequence",
    "stop_sequence": "",
    "type": "message",
    "usage": {
      "input_tokens": 0,
      "output_tokens": 0,
      "cache_creation_input_tokens": 0,
      "cache_read_input_tokens": 0,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": null,
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": null,
      "iterations": null,
      "speed": null
    },
    "context_management": null
  }
}
```

</details>

---


## Round 35

## Round 35

5 recorded events


### User

_source line 843 · 2026-05-20T10:12:59.407Z_

[系统提醒] 你刚才完成了 [Director 指令] 但没有调用 main_agent_post_to_director 汇报结果。Director 看不到你的文字回复。请立即调用 main_agent_post_to_director 将结果发给 Director。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e211d9d6-a8ef-4d95-a9a2-749a7a49a398",
  "isSidechain": false,
  "promptId": "b5f79f62-9082-46f5-b4d6-1ddb529ddc2f",
  "type": "user",
  "uuid": "b38b9d1f-a9a2-4b99-ae47-464df511b71d",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Runtime record

_source line 844_

```json
{
  "type": "ai-title",
  "aiTitle": "Correct effective_rank framework and add phase transition citations",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


### Runtime record

_source line 845 · 2026-05-20T10:13:10.315Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-20T10:13:10.315Z",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "content": "[系统提醒] 你刚才完成了 [Director 指令] 但没有调用 main_agent_post_to_director 汇报结果。Director 看不到你的文字回复。请立即调用 main_agent_post_to_director 将结果发给 Director。"
}
```

---


### Runtime record

_source line 846 · 2026-05-20T10:13:10.315Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-20T10:13:10.315Z",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


### Assistant

_source line 847 · 2026-05-20T10:13:10.286Z_

No response requested.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b38b9d1f-a9a2-4b99-ae47-464df511b71d",
  "isSidechain": false,
  "type": "assistant",
  "uuid": "32e7891d-24d9-4cec-ba4d-2448c1182d78",
  "isApiErrorMessage": false,
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "id": "290b96fd-6081-48e7-a4ec-e5268c1f6fae",
    "container": null,
    "model": "&lt;synthetic>",
    "stop_reason": "stop_sequence",
    "stop_sequence": "",
    "type": "message",
    "usage": {
      "input_tokens": 0,
      "output_tokens": 0,
      "cache_creation_input_tokens": 0,
      "cache_read_input_tokens": 0,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": null,
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": null,
      "iterations": null,
      "speed": null
    },
    "context_management": null
  }
}
```

</details>

---


## Round 36

## Round 36

5 recorded events


### User

_source line 848 · 2026-05-20T10:13:10.554Z_

[系统提醒] 你刚才完成了 [Director 指令] 但没有调用 main_agent_post_to_director 汇报结果。Director 看不到你的文字回复。请立即调用 main_agent_post_to_director 将结果发给 Director。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "32e7891d-24d9-4cec-ba4d-2448c1182d78",
  "isSidechain": false,
  "promptId": "b6502fb0-9399-4bf5-80ee-464d2e5e8f40",
  "type": "user",
  "uuid": "84572911-de6f-455c-a09e-ad0df0bfe720",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Runtime record

_source line 849_

```json
{
  "type": "ai-title",
  "aiTitle": "Correct effective_rank framework and add phase transition citations",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


### Runtime record

_source line 850 · 2026-05-20T10:13:19.375Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-20T10:13:19.375Z",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "content": "[系统提醒] 你刚才完成了 [Director 指令] 但没有调用 main_agent_post_to_director 汇报结果。Director 看不到你的文字回复。请立即调用 main_agent_post_to_director 将结果发给 Director。"
}
```

---


### Runtime record

_source line 851 · 2026-05-20T10:13:19.376Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-20T10:13:19.376Z",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


### Assistant

_source line 852 · 2026-05-20T10:13:19.358Z_

No response requested.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "84572911-de6f-455c-a09e-ad0df0bfe720",
  "isSidechain": false,
  "type": "assistant",
  "uuid": "3fadfbd4-b29e-452c-be40-d698f40d015b",
  "isApiErrorMessage": false,
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "id": "866a878e-3abe-4858-8cd8-b301d26355bf",
    "container": null,
    "model": "&lt;synthetic>",
    "stop_reason": "stop_sequence",
    "stop_sequence": "",
    "type": "message",
    "usage": {
      "input_tokens": 0,
      "output_tokens": 0,
      "cache_creation_input_tokens": 0,
      "cache_read_input_tokens": 0,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": null,
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": null,
      "iterations": null,
      "speed": null
    },
    "context_management": null
  }
}
```

</details>

---


## Round 37

## Round 37

5 recorded events


### User

_source line 853 · 2026-05-20T10:13:19.522Z_

[系统提醒] 你刚才完成了 [Director 指令] 但没有调用 main_agent_post_to_director 汇报结果。Director 看不到你的文字回复。请立即调用 main_agent_post_to_director 将结果发给 Director。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3fadfbd4-b29e-452c-be40-d698f40d015b",
  "isSidechain": false,
  "promptId": "838cb4dc-20f9-40d0-8102-6f3afe3de03a",
  "type": "user",
  "uuid": "362d591b-f5ee-4cf3-95c3-5dfac5ab3694",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Runtime record

_source line 854_

```json
{
  "type": "ai-title",
  "aiTitle": "Correct effective_rank framework and add phase transition citations",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


### Runtime record

_source line 855 · 2026-05-20T10:13:29.000Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-20T10:13:29.000Z",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "content": "[Director 指令] [Framing Update — D130 完成] paper_framing.md 已完成 D130 Discovery Paper 全量更新。\n\n变更内容：\n1. **Core Claims** 从旧 4-Claim 结构重写为 D130 C1-C4：C1 Detection Phase Transition (核心发现), C2 S×R Theoretical Framework, C3 MMCT (降级为工具), C4 Practical Applications\n2. **Story Spine** 从 \"Method Matters\" 重写为 Discovery Paper 叙事：Problem→Discovery→Mechanism→Tool→Implications\n3. **Title** 确定为 \"A Detection Phase Transition in Iterative Training Collapse\"\n4. **Venue Fit** 更新为 discovery paper positioning\n5. **Claim Mapping** 添加——旧 Claim 1→C1/C3, 旧 Claim 2→C1/C2, 旧 Claim 3→C3, 旧 Claim 4→C4\n6. **Key Narrative Constraints** (50 条) 全部保留，前置 mapping note\n\n措辞硬约束：\n- \"detection phase transition\" / \"sharp onset\" / \"near-discontinuous onset\" = 允许\n- \"first-order phase transition\" / \"phase transition\" (physical sense) = 禁止\n\n请基于更新后的 paper_framing.md 继续 D130 Reframe 模式。writing_plan.yaml 就绪后提交审批。"
}
```

---


### Runtime record

_source line 856 · 2026-05-20T10:13:29.001Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-20T10:13:29.001Z",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc"
}
```

---


### Assistant

_source line 857 · 2026-05-20T10:13:28.987Z_

No response requested.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "362d591b-f5ee-4cf3-95c3-5dfac5ab3694",
  "isSidechain": false,
  "type": "assistant",
  "uuid": "b6168cc6-1b16-463a-8786-7ce2541beee3",
  "isApiErrorMessage": false,
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "id": "bd81630f-1cd3-4042-8494-bb81a2cdd1f0",
    "container": null,
    "model": "&lt;synthetic>",
    "stop_reason": "stop_sequence",
    "stop_sequence": "",
    "type": "message",
    "usage": {
      "input_tokens": 0,
      "output_tokens": 0,
      "cache_creation_input_tokens": 0,
      "cache_read_input_tokens": 0,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": null,
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": null,
      "iterations": null,
      "speed": null
    },
    "context_management": null
  }
}
```

</details>

---


## Round 38

## Round 38

45 recorded events


### User

_source line 858 · 2026-05-20T10:13:29.109Z_

[Director 指令] [Framing Update — D130 完成] paper_framing.md 已完成 D130 Discovery Paper 全量更新。

变更内容：
1. **Core Claims** 从旧 4-Claim 结构重写为 D130 C1-C4：C1 Detection Phase Transition (核心发现), C2 S×R Theoretical Framework, C3 MMCT (降级为工具), C4 Practical Applications
2. **Story Spine** 从 "Method Matters" 重写为 Discovery Paper 叙事：Problem→Discovery→Mechanism→Tool→Implications
3. **Title** 确定为 "A Detection Phase Transition in Iterative Training Collapse"
4. **Venue Fit** 更新为 discovery paper positioning
5. **Claim Mapping** 添加——旧 Claim 1→C1/C3, 旧 Claim 2→C1/C2, 旧 Claim 3→C3, 旧 Claim 4→C4
6. **Key Narrative Constraints** (50 条) 全部保留，前置 mapping note

措辞硬约束：
- "detection phase transition" / "sharp onset" / "near-discontinuous onset" = 允许
- "first-order phase transition" / "phase transition" (physical sense) = 禁止

请基于更新后的 paper_framing.md 继续 D130 Reframe 模式。writing_plan.yaml 就绪后提交审批。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b6168cc6-1b16-463a-8786-7ce2541beee3",
  "isSidechain": false,
  "promptId": "1b0c9ca2-2633-496d-b536-5a90fa668be9",
  "type": "user",
  "uuid": "98b10cb8-3485-443a-8aaf-26b9cc2cb0ea",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Tool call

_source line 859 · 2026-05-20T10:13:32.160Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01UEFjmAUR5528XkztSbPUBc`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_project_file",
  "max_results": 1
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "98b10cb8-3485-443a-8aaf-26b9cc2cb0ea",
  "isSidechain": false,
  "requestId": "req_011CbDeGnwFcvEhFDutXFGqE",
  "type": "assistant",
  "uuid": "286199de-9746-46ff-b79c-503c2703976d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NbnVvQ4KfQ5fDmadwJimoW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 402,
      "cache_read_input_tokens": 127833,
      "output_tokens": 88,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 402,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 88,
          "cache_read_input_tokens": 127833,
          "cache_creation_input_tokens": 402,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 402
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

_source line 860 · 2026-05-20T10:13:32.170Z_

<details><summary>↩ Tool result · `toolu_01UEFjmAUR5528XkztSbPUBc`</summary>

````text
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
  "parentUuid": "286199de-9746-46ff-b79c-503c2703976d",
  "isSidechain": false,
  "promptId": "1b0c9ca2-2633-496d-b536-5a90fa668be9",
  "type": "user",
  "uuid": "63b93df9-8b01-4a8d-8461-9e10a325be46",
  "toolUseResult": {
    "matches": [
      "mcp__agent-ml-research__read_project_file"
    ],
    "query": "select:mcp__agent-ml-research__read_project_file",
    "total_deferred_tools": 51
  },
  "sourceToolAssistantUUID": "286199de-9746-46ff-b79c-503c2703976d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet"
}
```

</details>

---


### Tool call

_source line 861 · 2026-05-20T10:13:35.254Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01RgMbj3xAb1qyPDU7egUbxv`</summary>

```json
{
  "project": "distrib_canary_collapse",
  "file": "paper_framing.md",
  "max_chars": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "63b93df9-8b01-4a8d-8461-9e10a325be46",
  "isSidechain": false,
  "requestId": "req_011CbDeH26X6p1Lfh16VxQ2Y",
  "type": "assistant",
  "uuid": "92a09195-2b3f-4b34-850a-f390fb2efa00",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/.claude/sessions/paper_agent_73c709c0",
  "sessionId": "71c5797e-c964-4419-a009-2e487a4de1fc",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "ancient-greeting-comet",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EYsRYNKoKvgSdJ7N2tnzwK",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 436,
      "cache_read_input_tokens": 128235,
      "output_tokens": 112,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 436,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 112,
          "cache_read_input_tokens": 128235,
          "cache_creation_input_tokens": 436,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 436
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
