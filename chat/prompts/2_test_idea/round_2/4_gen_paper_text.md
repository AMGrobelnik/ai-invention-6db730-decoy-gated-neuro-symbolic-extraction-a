# gen_paper_text — test_idea

> Phase: `invention_loop` · round 2 · `gen_paper_text`
> Run: `run_MQN7mBg4AhvH` — Neuro Symbolic Pipeline
>
> Full, verbatim record of every prompt the AI Inventor pipeline gave this agent — system-user, human-user and skill-input — in the order they landed. Nothing truncated.

## Task: `gen_paper_text` (terminal_claude_agent)

### [1] SYSTEM-USER prompt · 2026-06-16 07:56:46 UTC

````
<ai_inventor_context>
<ai_inventor_summary>
You are one of many LLMs in AI Inventor — an automated research system that generates NOVEL and FEASIBLE hypotheses, investigates them through experiments and research, and produces a paper.

Your output feeds other LLMs downstream. This demands your ABSOLUTE MAXIMUM reasoning — every output must be deeply thought out and maximally useful. Surface-level responses waste downstream computation.
</ai_inventor_summary>

<your_role>
YOU ARE: A research paper writer (Step 3.4: GEN_PAPER_TEXT in the invention loop)

You received the hypothesis, all artifacts, the previous paper draft (if any), and reviewer feedback.
Write a complete paper draft with figure placeholders.

Publication-quality paper → strong contribution. Weak paper → wasted iteration.
</your_role>
</ai_inventor_context>

<research_methodology>
Write like a researcher drafting a paper, not a chatbot summarizing bullet points.

- Structure as a paper would: research question → methodology → results → analysis → limitations. Not a list of "we did X, then Y."
- Ground every claim in specific artifacts and specific numbers. "Results show improvement" is empty — state effect sizes, baselines, and conditions.
- Be honest about what worked, what didn't, and why. Don't spin failures as "future work."
- The paper's headline contribution should be a positive or surprising finding. Negative results are valuable context but should not be the primary narrative — lead with what works.
- Address reviewer feedback from previous iterations explicitly — show you've thought about each critique.
</research_methodology>

<available_tools>
Web research is available through the aii-web-tools skill, in three levels (broad → specific):

1. web search — Returns titles, URLs, snippets. Use first to discover and scan the landscape.
2. web fetch — Reads a page and returns its content as markdown (HTML or PDF). Use to understand a source. May miss specific details — use fetch_grep below if it doesn't find what you need.
3. fetch_grep — Regex search over a page/PDF's full text. Returns exact matching sections with context. Use for precise details, exact numbers, methodology, or PDFs.

Workflow: search → fetch (understand) → fetch_grep (extract specifics).
</available_tools>

<tool_use>
Maximize parallel tool calls. Parallelize independent operations, only sequentialize dependencies.
- Multiple searches/fetches on different topics → parallel in one turn
- Search then fetch results → sequential (need URLs first)
</tool_use>

<system_reminder>
Do not ask follow up questions and do not ask the user anything. Execute all steps independently.
You must follow the todo list provided in each prompt exactly as written.
No placeholders, stubs, or incomplete code — all code must be complete and functional.
</system_reminder>

<process_isolation>
CRITICAL: Multiple pipeline runs may execute simultaneously on this machine. `ps aux | grep method.py` matches ALL runs, not just yours.
- NEVER kill processes by name (`killall`, `pkill -f`, `ps aux | grep ... | xargs kill`). This kills OTHER runs' processes.
- NEVER monitor processes by name (`ps aux | grep method.py`). You will see other runs' processes and get confused.
- ALWAYS use PID-based process management:
  Run: `uv run method.py & PID=$!` or `timeout <seconds> uv run method.py & PID=$!`
  Check: `kill -0 $PID 2>/dev/null && echo "Running" || echo "Ended"`
  Stop: `kill $PID`
  Wait: `wait $PID; echo "Exit code: $?"`
  Monitor: `tail -f logs/run.log & TAIL_PID=$!` then `kill $TAIL_PID` when done
</process_isolation>

<previous_paper>
STARTING POINT: This is your paper draft from the previous iteration.

# Introduction

Operational pipelines that convert unstructured prose into a formal, computable representation---one a logic engine such as SWI-Prolog can execute---promise the best of two worlds: the broad coverage of an LLM as a semantic translator, and the verifiable, auditable inference of a symbolic reasoner. The recurring failure point of such pipelines is not parsing syntax but the *fuzzy-unification boundary*: when strict symbolic matching fails, an LLM must align a surface predicate to a schema relation and supply implicit background knowledge, and exactly at that interface hallucination re-enters and propagates into every deduction that consumes the admitted fact. The dangerous hallucinations are not random nonsense; they are *plausible, high-confidence false facts* that a downstream solver will treat as ground truth.

The problem is both practically important and technically hard. It is important because a single fabricated premise admitted into a knowledge base contaminates an unbounded set of multi-hop conclusions, and because the application domains that most need auditable reasoning---short legal documents, news, regulatory text---are precisely those where a silently wrong fact is most costly. It is hard because the standard defenses do not act where the damage occurs. Self-consistency and LLM-as-judge are heuristic and provide no quantitative control. Ontology-constraint filtering rejects only encoded violations and needs a rich trusted constraint set. The strongest uncertainty-quantification methods---conformal factuality [15], conformal selection with Benjamini-Hochberg [16], multiple-testing hallucination detection [18], coherent factuality over reasoning chains [17], and the newest online and feedback-driven variants [19]---all require a *labeled* calibration set and certify the *final answer or claim set*, not the *admission* of an intermediate fact or bridge into the symbolic layer.

Why has the admission boundary not been controlled before? Because the natural statistical tool for controlling false admissions among many candidate signals with no ground truth---the *false discovery rate* (FDR)---was developed in numeric feature selection and mass spectrometry, where a synthetic negative control exchangeable *by construction* is available. Genomics and proteomics solved an isomorphic label-poor problem---selecting true signals among overwhelming noise with a guaranteed FDR and no labels---via the knockoff filter [4, 5] and target-decoy competition, and learned the two ways the trick breaks: decoys that are *too unrealistic to fool* the scorer make the estimated FDR optimistic (cured by property-matched decoys [9]), and entrapment false-discovery-proportion (FDP) must be estimated with a valid upper bound built *independently* of the decoys [6]. No prior work imports this machinery to the LLM neural-to-symbolic boundary, label-free.

This paper does so. We propose *decoy-gated extraction*: before any LLM-proposed Prolog fact or bridge enters the knowledge base, it must out-score a *plausibility-matched* synthetic decoy---a document-conditioned counterfactual that the model finds plausible but the document does not entail---in a knockoff+ competition that admits the most permissive cutoff whose estimated corpus-aggregate FDR is at most a target $\alpha$, using zero operation labels. The competition statistic for candidate $i$ is $W_i = \mathrm{score}(\mathrm{real}_i) - \mathrm{score}(\mathrm{decoy}_i)$; knockoff+ thresholding scans cutoffs and admits $\{i : W_i \ge T\}$ at the most permissive $T$ whose estimated $\widehat{\mathrm{FDR}} = (1 + \#\{W_i \le -T\}) / \max(1, \#\{W_i \ge T\}) \le \alpha$ [4]. Validity rests on the *null sign-flip property* (for genuinely-false candidates the sign of $W_i$ is a fair coin conditional on $|W_i|$); because LLM decoys carry no construction-level proof of this property, we treat the gate as an *empirically validated calibration* rather than a theorem, test the property *in the tail* where admissions occur, and protect it against the two LLM-specific dependence channels that break it.

[FIGURE:fig1]

A label-free FDR knob is worth building only if it is *both calibrated and useful*, and the two claims are best proven on different data. We therefore adopt a two-anchor design with a clean division of labor. CLUTRR [1]---free, deterministic, with crisp templated gold over a closed kinship vocabulary---hosts the *calibration-validity* claim (does realized FDR track target $\alpha$?) and a single pre-registered primary disconfirmation. Re-DocRED [2]---human-annotated Wikipedia prose with 96 open relation types and document-level multi-hop structure---hosts the *operational-usefulness* claim (atomic-fact precision and hallucinated-conclusion rate versus baselines at matched recall) and a document-level predictive account of *when* the calibration holds. CLUTRR proves the knob is calibrated; Re-DocRED proves it is useful; the two are never conflated.

**Scope and honesty.** The contribution of this iteration is the method, the prepared and validated evaluation infrastructure, and a falsifiable pre-registered protocol---not yet the realized empirical diagonal. We are explicit about this throughout: the datasets are built, the structural floors and budget are analyzed and shown feasible, and the protocol is registered with a single disconfirmation that can falsify the headline. We do not report fabricated FDR or precision numbers; the empirical run is the registered next step that the prepared anchors are sized to power.

**Summary of contributions.**

- We formulate the *text-to-logic admission boundary* as an FDR-control problem and introduce *decoy-gated extraction*, to our knowledge the first label-free FDR knob at the neural-to-symbolic interface, built from knockoff+ thresholding, plausibility-matched counterfactual decoys, and independent entrapment corroboration (Sections 3--4).
- We identify the two channels by which LLM scoring breaks the knockoff null sign-flip property---within-document score correlation and batched-scoring contrast effects---and neutralize them with a document-block bootstrap and isolated, provenance-blinded scoring, with an *isolated-versus-batched* check that doubles as a discriminator between a scoring artifact and genuine decoy non-exchangeability (Section 4.4).
- We design an auditable neuro-symbolic pipeline whose Prolog proof trace-graphs carry, at every leaf, a decoy-competition certificate and an entrapment certificate alongside the provenance span (Section 4.6).
- We deliver two prepared, schema-validated evaluation anchors---a 190-document crisp-gold CLUTRR calibration set and a 236-document Re-DocRED operational set---with a shared triple schema enabling an apples-to-apples matched-recall comparison against a plain confidence threshold, chain-of-thought, retrieval-augmented generation, and labeled conformal factuality (Sections 5--6).
- We give a structural feasibility analysis: the demonstrable-$\alpha$ grid tied to the $1/k$ minimum-estimable-FDR floor, and a budget arithmetic projecting under three US dollars of LLM cost on commodity CPU, against a hard ten-dollar cap (Sections 4.3, 6.5).
- We pre-register a falsifiable protocol---a single primary disconfirmation gated on populability, a six-row claim chain, and a threat table---so that the eventual empirical outcome is interpretable whether it confirms, disconfirms, or is declared untestable (Section 6).

# Related Work

**Label-free hallucination scoring.** Zero-resource detectors produce per-claim hallucination scores from sampling consistency (SelfCheckGPT [13]) or distractor-normalized verbalized confidence (DINCO [12]); FactSelfCheck [14] operates natively at the fact level over $(h, r, t)$ triples. These methods yield a *score*, not an admission threshold, and offer no exchangeability or competition argument. In our framework they are *candidate elicitations* feeding the gate, not the gate itself; our Phase-0 pilot selects among them by tail discrimination. Verbalized confidence is known to be overconfident in the upper tail [10], and token log-probability calibration degrades under reinforcement learning from human feedback [11]---which is exactly why we test elicitations on tail discrimination rather than average calibration.

**Labeled uncertainty quantification for LLMs.** Conformal factuality [15] removes claims until a factuality level is met, using a labeled calibration set, and certifies the emitted answer; coherent factuality [17] extends this to reasoning chains; conformal selection [16] and online/feedback-driven multiple testing [18, 19] control FDR over candidate outputs but require labeled calibration outcomes. All certify *outputs* and all are *labeled*. Our contribution is orthogonal and complementary: a *label-free* control at the *admission* boundary. Mohri-Hashimoto conformal factuality [15] is our load-bearing *labeled reference baseline*; we report its finite-sample guarantee side by side with our empirical calibration, and charge any baseline's calibration labels symmetrically against our zero labels.

**FDR control by competition.** The knockoff filter [4] and Model-X knockoffs [5] select signals with guaranteed FDR by competing each real candidate against a synthetic negative control exchangeable by construction, relying on the null sign-flip property; the knockoff+ threshold controls FDR exactly via the conservative $+1$ offset [4], which Rajchert and Keich prove is in general necessary [7]. Ebadi et al. give tighter upper prediction bounds on the FDP [8]. In proteomics, entrapment estimation provides an independent FDP bound, with the valid combined estimator and the flawed naive estimator characterized by Wen et al. [6]; property-matched decoy generation (DeepCoy [9]) shows decoys must reproduce the true-positive score distribution. We adapt all three to the LLM boundary, where exchangeability is *not* provable, and therefore add tail-conditioned diagnostics, a document-block bootstrap for within-document dependence [28], and a model of where the property holds.

**Text-to-logic neuro-symbolic reasoning.** LINC [20] and Logic-LM [21] semantic-parse premises into first-order logic or symbolic programs executed by a solver, with majority voting or solver-error self-refinement; LLM-ASP [23] parses CLUTRR into reusable answer-set modules. None exercises principled control over *which* extracted premises are admitted: a syntactically valid but fabricated premise is never challenged, voting merely smooths variance, and refinement fixes only solver and syntax errors. Standard neural baselines---chain-of-thought prompting [22] and retrieval-augmented generation [26]---have no admission boundary at all. Logical-reasoning benchmarks such as RuleTaker [24], ProofWriter [25], and CLUTRR [1] supply controlled reasoning targets; our calibration anchor is CLUTRR for its crisp templated gold, and our operational anchor is Re-DocRED [2], the false-negative-corrected re-annotation of DocRED [3].

# Preliminaries

We control the false admission of two candidate kinds. A *fact* is a ground typed atom (for example `rel_child(e_alice, e_bob)` with a side type table), and a *bridge* is a fuzzy-unification rule---a kinship composition rule for CLUTRR, or a surface-form-to-schema relation alignment for Re-DocRED. Bridges are first-class admission candidates with their own decoy, score, and gate. Each candidate $i$ receives a label-free score $Z_i$ from an isolated elicitation and a matched decoy score $\tilde{Z}_i$; the *competition statistic* is $W_i = (Z_i \vee \tilde{Z}_i)\,[2 \cdot \mathbf{1}(Z_i > \tilde{Z}_i) - 1]$, which reduces to the sign-antisymmetric difference of real and decoy scores [4, 5]. A large positive $W_i$ is evidence that the candidate is a true signal; the sign of $W_i$ is the win/lose of real versus decoy. The target is the corpus-aggregate FDR---the expected fraction of admitted candidates that are document-non-entailed---held at or below a user-chosen $\alpha$, separately for facts and bridges and per anchor, with all confidence intervals computed by resampling whole documents [28]. We use $a \vee b = \max(a, b)$ throughout.

# Method

The pipeline has six stages: over-generating extraction, plausibility-matched decoy generation, isolated provenance-blinded scoring, the knockoff+ FDR gate, independent entrapment corroboration, and symbolic reasoning with auditable trace-graphs. We describe each as the story of the admitted artifact, not of how we arrived at the design. The full implementation specification---verbatim prompt templates, on-disk formats, and library APIs---is provided in the supporting research artifacts [ARTIFACT:art_SLUbUUr6Ul98][ARTIFACT:art_K6AE23HoGqe6].

## Extraction with deliberate over-generation

A cheap LLM proposes typed first-order facts and bridges from the document in a LINC/Logic-LM style, with argument types grounded in a commodity upper-ontology slice. Following the user requirement of an OpenCyc-style taxonomic grounding, we use an offline WordNet hypernym lookup that maps each argument head noun into the coarse vocabulary $\{$PER, LOC, ORG, TIME, NUM, MISC$\}$ via anchor synsets (`person.n.01` to PER, `location.n.01` to LOC, `organization.n.01` to ORG, and so on), reusing Re-DocRED's gold mention types when present and typing all CLUTRR arguments to PER [ARTIFACT:art_K6AE23HoGqe6]. Typing is used *only* to constrain decoy generation and entity linking, never to filter. The extractor deliberately *over-generates*---temperature 0.7, three samples unioned, capped at twenty candidates per document---so that the candidate pool is dense in genuine false positives, which is a precondition for a non-vacuous calibration diagonal: a diagonal can only track $\alpha$ if a meaningful fraction of admitted reals are genuinely false.

## Plausibility-matched counterfactual decoys

The load-bearing design choice is the decoy family. The proteomics lesson is that decoys that are *too easy* let the scorer separate on artifacts and make the estimated FDR optimistic; DeepCoy quantifies the cost of unmatched decoys and the gain from property-matched ones, improving deviation-from-optimal-embedding by 81% (0.166 to 0.032 on DUD-E) and 66% (0.109 to 0.038 on DEKOIS 2.0) with no added false-negative risk [9]. Translated to text, a decoy must reproduce the score distribution of genuine *plausible* hallucinations---same entity types, surface form, and specificity---so that the only feature distinguishing it from a real-but-false fact is document non-entailment. Our primary family is the *document-conditioned counterfactual*: given the document and the relation/type schema, the model produces a maximally plausible fact or bridge that is *not* stated or entailed by the text, matching the surface form and specificity of the document's real facts. Every decoy passes an independent, isolated non-entailment check (an accidentally entailed decoy is actually true and would bias the FDR conservatively); the contamination rate is logged and a sensitivity analysis sweeps the rejection threshold [ARTIFACT:art_SLUbUUr6Ul98]. As a deliberately retained negative control we also generate *random type-matched swaps*, which are predicted to read anti-conservative precisely because they are too easy---validating the diagnostic.

## Isolated, provenance-blinded scoring

Each candidate, whether real, decoy, or entrapment, is scored in its *own* prompt with source identity masked and presentation order randomized, rather than scoring many candidates jointly. Isolation removes the within-batch contrast and ranking effects that would let the model implicitly detect the fabricated item and depress decoy scores---an anti-conservative failure of the second kind below. Isolated scoring is the default for 100% of the confirmatory set; the headroom is bought not by batching but by *document-prefix prompt caching*: the roughly sixty scoring calls that share one document context re-use a cached prefix at a fraction of the input cost. The per-candidate score is produced by a pilot-selected elicitation. Because verbalized confidence is overconfident in the upper tail [10] and log-probability calibration degrades under alignment [11], the elicitation is chosen on *tail* discrimination, not average calibration: a Phase-0 pilot ranks verbalized confidence (a floor baseline), a distractor-normalized DINCO-style score [12], a sampling-consistency score (SelfCheckGPT / FactSelfCheck [13, 14]), and---if the model exposes log-probabilities---a yes/no-token score, selecting the one whose area under the curve restricted to the admission tail exceeds 0.5 with a confidence interval [ARTIFACT:art_SLUbUUr6Ul98].

## The knockoff+ FDR gate and the structural $1/k$ floor

Given the competition statistics, the gate admits $\{i : W_i \ge T\}$ at the smallest (most permissive) cutoff $T$ for which $\widehat{\mathrm{FDR}}(T) = (1 + \#\{W_i \le -T\}) / (\#\{W_i \ge T\} \vee 1) \le \alpha$, which is the knockoff+ threshold controlling the FDR exactly [4]. The $+1$ in the numerator is conservative and, by the analysis of Rajchert and Keich, generally necessary [7]; we keep it for the headline certificate. Its conservativeness has a precise structural consequence we exploit for honesty: with $k$ admissions the smallest attainable FDR estimate is $1/k$, so certifying $\widehat{\mathrm{FDR}} \le \alpha$ requires $k \ge \lceil 1/\alpha \rceil$ admissions. The demonstrable-$\alpha$ grid is therefore tied to a known admission floor: $\alpha \in \{0.05, 0.10, 0.20, 0.30, 0.50\}$ maps to admission floors $\{20, 10, 5, 4, 2\}$ [ARTIFACT:art_SLUbUUr6Ul98]. An $\alpha$ below the floor reachable by a given anchor is structurally undemonstrable regardless of model quality---a fact we report rather than paper over.

[FIGURE:fig4]

## Robustifying the null sign-flip property

[FIGURE:fig2]

Knockoff+ validity rests on a single condition: among genuinely-false candidates, the sign of $W_i$ behaves like an independent fair coin conditional on $|W_i|$ [4]. For Gaussian knockoffs the condition is provable; for LLM decoys it is not, so the gate is an empirically validated calibration and we test the condition *in the tail*. Two LLM-specific channels can break it anti-conservatively.

The first is *within-document score correlation*: candidates from one document share context, entities, and genre, so their null $W$ signs are dependent, and pooling them as independent understates variance and the floor. The remedy is the *document-block bootstrap*: all FDP/FDR confidence intervals are computed by resampling whole documents (blocks) with replacement and re-running the entire gate on each resample, with at least 2000 resamples, following the cluster-bootstrap remedy for within-cluster dependence [28]. The resulting percentile interval is the confidence interval used by the primary disconfirmation.

The second is the *batched-scoring contrast effect*: if candidates are co-presented, the model can implicitly detect the odd fabricated item and depress its score, making the FDP optimistically low. The remedy is isolated, provenance-blinded, order-randomized scoring as the default. Crucially, a pre-registered *isolated-versus-batched* check on a labeled slice doubles as a discriminator: if isolation restores the calibration diagonal while batching is anti-conservative, the anti-conservatism was a scoring artifact; if it persists under isolation, the decoys are genuinely too easy and the decoy family must be fixed. Two measurement-only tail diagnostics complete the picture and are never consumed by the gate: the tail-conditioned win-rate of matched (false-real, decoy) pairs above the operative cutoff should be approximately 0.5, and a one-sided two-sample test (Kolmogorov-Smirnov or tail-restricted Mann-Whitney) on real-false versus decoy scores restricted to the admission region should not find decoy scores stochastically smaller.

## Independent entrapment corroboration

Decoy competition decides admission; *entrapment* provides an independent upper bound on the realized FDP, built by a mechanism *distinct* from the decoys (in-genre cross-document swaps, numeric or temporal perturbation, explicit contradiction) so the two FDR signals are independent corroborations against gold. We use the valid combined estimator $\widehat{\mathrm{FDP}} = N_E(1 + 1/r)/(N_T + N_E)$ as the default certificate and the tighter paired estimator at $r = 1$ when one-to-one pairing is available, where $N_T$ and $N_E$ are admitted target and entrapment counts and $r$ is the entrapment-to-target ratio; we never use the naive sample estimator, which Wen et al. prove biased [6]. The ratio $r$ propagates into the point estimate, the variance, and the achievable-$\alpha$ floor, and is reported. Entrapment carries its own tail-difficulty diagnostic so that an entrapment set that is too easy cannot silently inflate confidence.

## Symbolic reasoning and auditable trace-graphs

Admitted facts and bridges populate an SWI-Prolog knowledge base (via the bundled `janus-swi` bridge, with `pyswip` and a `swipl` subprocess as fallbacks) for multi-hop deduction [ARTIFACT:art_K6AE23HoGqe6]. A vanilla `solve/2` meta-interpreter captures the backward-chaining proof as a *trace-graph* whose nodes are sub-goals and derived facts and whose edges are labeled rule applications. Every leaf resolves against a side table that returns a certificate term: the provenance span, the decoy-competition certificate $(W_i, T, \alpha)$, and the entrapment certificate $(\widehat{\mathrm{FDP}}, r)$. The trace-graph is serialized to JSON for machine audit and to Graphviz DOT for human audit, satisfying the requirement that every conclusion expose the logical path taken and the statistical license of each premise it rests on. Beyond the two quantitative anchors, a small illustrative corpus of roughly fifteen short legal, news, and story documents exercises the trace-graph end to end on the genres the application targets; the corpus is explicitly non-confirmatory and used only to demonstrate the auditable output, never to assert calibration.

# Evaluation Design and Pre-Registered Protocol

The evaluation is split so that calibration and usefulness are proven on the data each suits, and it is pre-registered so that the eventual outcome is interpretable.

[FIGURE:fig3]

## Two anchors with a clean division of labor

CLUTRR [1] is rule-based and templated, so its kinship gold is exact---the property that lets it host the realized-FDR-versus-$\alpha$ *diagonal* and the single primary disconfirmation. Re-DocRED [2] is human-annotated, open-vocabulary, and document-level, so it hosts the *operational* claim, the genuine schema-alignment bridge test, and the document-level predictive account; because Re-DocRED retains residual false negatives, it licenses only *relative* operational comparisons under shared gold, never an absolute diagonal. CLUTRR proves the knob is calibrated; Re-DocRED proves it is useful.

## Prepared datasets

[FIGURE:fig5]

The CLUTRR calibration anchor comprises 190 stories (one story per example) drawn from the pooled test splits of two CLUTRR configurations, of which 1345 of 2191 pooled rows qualified as canonical simple-path chains, stratified over chain length $k = 2$ to $10$ and oversampling long chains: 150 confirmatory and 40 disjoint pilot examples, with the confirmatory $k$-distribution $\{k2{:}12, k3{:}15, k4{:}20, k5{:}20, k6{:}20, k7{:}18, k8{:}18, k9{:}15, k10{:}12\}$ [ARTIFACT:art_XZyKy6QuwxrO]. All gold is derived 100% from CLUTRR's own structured `proof_state` fields---leaf triples give the $k$ directly-stated *atomic* facts and dictionary keys give the $k-1$ *multi-hop* inferred relations---with no homegrown rule reimplementation, over a 20-relation kinship vocabulary. The atomic family is typically too clean to populate the diagonal; the multi-hop inferred-kinship family, where extraction errors are dense, is the *populable* family on which the primary disconfirmation is pre-registered.

The Re-DocRED operational anchor comprises 236 Wikipedia documents (one per example) drawn from 4053 pooled documents under the eligibility filter $80 \le \text{words} \le 400$, at least four entities, and at least five triples: 152 confirmatory, 36 pilot, and 48 reserve, exactly balanced across four dominant-entity-type folds (PER, ORG, LOC, MISC) at 38/9/12 each for leave-one-cluster-out cross-validation [ARTIFACT:art_Jcudmkugg1qT]. Each document carries the full annotated entity inventory with character spans, gold $(head, relation, tail)$ triples over 96 Wikidata relation types and 6 entity types with evidence sentences, and 17 per-document features (triple density ranges from 0.38 to 14.75 across the corpus) that supply the cross-document variance the document-level predictive model needs. Both datasets are schema-validated and regenerable deterministically on pure CPU from cached raw data under a fixed seed.

## Shared operational construct and matched-recall comparison

On Re-DocRED, every system targets the *same* object: $(head\text{-}entity, relation, tail\text{-}entity)$ triples over the document's annotated entities, scored against human gold by the official $(\text{title}, r, h_{\text{idx}}, t_{\text{idx}})$ matching metric [2, 3]. A single fixed claim-decomposition and relation-alignment step maps every system's raw output into this triple space identically: a sentence-embedding shortlist of the top-eight relation codes followed by a temperature-0 LLM pick among the 96 codes or `NO_RELATION`, with a three-tier entity-linking procedure (exact, alias/substring, embedding floor) [ARTIFACT:art_K6AE23HoGqe6]. Recall is matched by sweeping each system's own score to a common operating point; precision and the hallucinated-conclusion rate (the fraction of multi-hop derived conclusions whose triple is not entailed by gold) are compared there with document-block-bootstrap intervals. The comparators are the *plain confidence-threshold gate* (the primary zero-label foil, identical elicitation, no decoy or competition), chain-of-thought [22], retrieval-augmented generation [26], and labeled Mohri-Hashimoto conformal factuality [15] as the labeled reference. The wedge is isolated as decoy-gating versus plain thresholding under identical zero labels: if decoy-gating does not beat plain thresholding at matched recall, the operational claim collapses to "thresholding is enough" and is disconfirmed.

## Pre-registered claim chain and primary disconfirmation

[FIGURE:fig6]

The protocol is a six-row claim chain, each row independently testable so that a break is localized and reported rather than hidden. S0 (score separation) requires the selected elicitation to separate entailed from non-entailed content in the upper tail with isolated-batched agreement. S1 (decoy signature) requires counterfactual decoys to reach tail-conditioned win-rate near 0.5 and pass the upper-tail two-sample test while random swaps read anti-conservative. S2 (calibration validity, CLUTRR) requires realized FDR to track $\alpha$ within tolerance $\tau = 0.05$ above the $1/k$ floor on the populable family, with a document-block-bootstrap interval. S3 (entrapment corroboration) requires the combined-estimator bound to agree with the decoy FDR and gold. S4 (operational wedge, Re-DocRED) requires decoy-gating to beat plain thresholding at matched recall and stay competitive with labeled conformal. S5 (document-level predictive account) predicts the per-document tail-exchangeability gap from document and score features under leave-one-cluster-out and leave-one-document-out cross-validation, reported as *predictive* only if validated out-of-sample on at least a pre-registered minimum of held-out units and as *descriptive* otherwise. S6 (predictable propagation) checks that tightening $\alpha$ lowers the multi-hop hallucinated-conclusion rate in direction and rough magnitude.

The single primary disconfirmation is S4/S5-independent and populability-gated. On the populable CLUTRR family under isolated provenance-blinded scoring at the operative $\alpha^{*}$, the central control claim is *disconfirmed* if realized corpus-aggregate FDR against crisp gold exceeds $\alpha^{*}$ by more than $\tau$ *and* the document-block-bootstrap interval lies entirely on the anti-conservative side. The disconfirmation fires only if Phase-0 first shows the family is populable---yielding at least $N_{\text{false\_min}} = 40$ genuine false admissions pooled at $\alpha^{*}$, enriched if needed by extractor over-generation and harder long-chain splits. If no family reaches the threshold even after enrichment, the diagonal is declared *untestable at this difficulty* and reported as a precondition outcome---never as "confirmed by conservatism." This pre-registration is what converts a likely-partial result into an interpretable one: an uninterpretable null, in which control neither clearly holds nor clearly fails because the tail or the diagonal is underpowered, is the specific failure the Phase-0 power analysis is designed to prevent.

## Budget waterfall and feasibility

Spending follows a strict priority order so the headline cannot be starved by secondary exploration: (i) the Phase-0 pilot, which gates everything; (ii) fully powering the CLUTRR calibration diagonal; (iii) fully powering the Re-DocRED operational wedge; and (iv), only with leftover budget and only after (ii) and (iii) clear their power thresholds, the S5 predictive model, S6 propagation, FDP-bound tightening, and exploratory rule gating. The confirmatory scoring workload is roughly 240 documents times about 20 candidates times 3 item-types (real, decoy, entrapment at $r = 1$), about 14.4K isolated scoring calls, plus about 0.7K generation calls and the pilot, at roughly 450 input and 30 output tokens per call, about 7 to 15 million tokens depending on candidate count. At a model priced under 0.30 US dollars per million tokens with document-prefix caching, the projected cost is approximately one to three US dollars, with cumulative cost logged after every call and a hard stop at ten dollars [ARTIFACT:art_SLUbUUr6Ul98]. The entire pipeline runs on commodity CPU.

# Deliverables and Feasibility Analysis

We report the concrete, verifiable outputs this iteration produces; we do not report empirical FDR or precision results, which are the registered next step.

**Two validated evaluation anchors.** The CLUTRR anchor delivers 190 schema-validated examples with a 190-of-190 independent integrity pass, exact crisp gold derived solely from CLUTRR structured fields, and a stratified $k$-distribution that guarantees per-stratum supply above the admission floors of the demonstrable-$\alpha$ grid [ARTIFACT:art_XZyKy6QuwxrO]. The Re-DocRED anchor delivers 236 schema-validated documents with full entity inventories, gold triples over 96 relations with evidence spans, four balanced cross-validation folds, and 17 per-document features whose spread (triple density 0.38 to 14.75) confirms the cross-document variance that the predictive model S5 requires and that CLUTRR's near-homogeneous documents lack [ARTIFACT:art_Jcudmkugg1qT]. Both regenerate deterministically on CPU under seed 20240617.

**A structural guarantee of falsifiability.** The $1/k$ floor analysis ties each demonstrable $\alpha$ to a known admission count, so the protocol cannot mistake structural unreachability for control: the grid $\{0.05, 0.10, 0.20, 0.30, 0.50\}$ is admissible only where admissions reach $\{20, 10, 5, 4, 2\}$ respectively, and the populability gate ($N_{\text{false\_min}} = 40$) ensures the diagonal is asserted only where genuine false admissions exist [ARTIFACT:art_SLUbUUr6Ul98]. The primary disconfirmation, the threat table, and the claim chain together make every possible outcome---confirmed, disconfirmed, or untestable---reportable as a definite result.

**A feasibility envelope.** The budget arithmetic places the confirmatory run at approximately one to three US dollars against a ten-dollar hard cap, with isolated scoring affordable for 100% of the confirmatory set because document-prefix caching, not batching, buys the headroom---preserving the isolated-versus-batched discriminator that batching would destroy [ARTIFACT:art_SLUbUUr6Ul98]. Two runtime preconditions are flagged for the empirical step: confirming the chosen model returns non-null log-probabilities (else the logprob elicitation is dropped and DINCO, verbalized, and sampling-consistency carry the pilot), and confirming cached tokens are non-zero so the projection holds.

# Discussion

**What the design buys, and what it cannot promise.** Decoy-gated extraction converts an uncontrolled hallucination channel---the fuzzy-unification boundary---into a tunable one, with a per-leaf certificate and no operation labels. Because LLM decoys carry no theoretical guarantee of the null sign-flip property, the most probable empirical outcome is *partial* control rather than an exact diagonal, and we have designed for that honestly: the document-level predictive account S5 is intended to convert a likely-partial result into a generalizable mechanism-level insight about *when* the calibration holds, and the isolated-versus-batched discriminator localizes any anti-conservatism to either a scoring artifact or a decoy-family defect. Even coarse control---at $\alpha$ near 0.1---would be the first label-free FDR knob at this interface.

**Limitations.** First, and most important, this paper presents a validated design and prepared infrastructure, not a realized empirical diagonal; the calibration and operational claims are pre-registered, not demonstrated. Second, the validity condition is engineered and tested, not proven, so a persistent anti-conservatism under isolated scoring would falsify the headline and is a real possibility we have made falsifiable rather than hidden. Third, the calibration diagonal is contingent on populability: if neither CLUTRR family reaches the false-admission threshold even after enrichment, the diagonal is untestable at this difficulty, an honest precondition outcome rather than a success. Fourth, Re-DocRED's residual false negatives confine it to relative comparisons, which is why crisp-gold CLUTRR carries the absolute calibration claim. Fifth, the demonstrable-$\alpha$ grid is floored by the conservative $+1$; tighter FDP bounds [8] are exploratory and carry no finite-sample guarantee here.

**Connection to the target application.** The pipeline ingests short professionally written documents, translates them to first-order logic, executes multi-hop deductions in Prolog, and emits auditable trace-graphs on commodity hardware---the operational profile the task demands. The fuzzy-unification bridges are precisely the LLM-supplied predicate alignments and background-knowledge steps the application needs, and the FDR knob is the quantified hallucination-reduction control that raw LLM generation lacks.

# Conclusion

We have formulated the text-to-logic admission boundary as a label-free FDR-control problem and introduced decoy-gated extraction, which forces every LLM-proposed fact and fuzzy-unification bridge to out-score a plausibility-matched counterfactual decoy in a knockoff+ competition before entering a Prolog knowledge base, with independent entrapment corroboration and per-leaf audit certificates. We transplanted three ideas from genomics and proteomics---knockoff+ thresholding, property-matched decoys, and valid entrapment estimation---and robustified the null sign-flip property against the two channels by which LLM scoring breaks it, using a document-block bootstrap and isolated provenance-blinded scoring. We delivered two prepared and validated evaluation anchors, a structural analysis tying the demonstrable-$\alpha$ grid to a known admission floor, a feasibility envelope under three US dollars on commodity CPU, and a pre-registered protocol whose single primary disconfirmation makes the headline falsifiable. Future work, in registered priority order, is to (1) run the Phase-0 pilot and select the tail-discriminating elicitation; (2) measure the CLUTRR calibration diagonal on the populable multi-hop family with document-block-bootstrap intervals; (3) measure the Re-DocRED operational wedge against the plain-threshold foil at matched recall; and (4), budget permitting, fit the document-level predictive model of when the calibration holds.

# References

[1] K. Sinha, S. Sodhani, J. Dong, J. Pineau, and W. L. Hamilton. CLUTRR: A Diagnostic Benchmark for Inductive Reasoning from Text. In *EMNLP*, 2019.

[2] Q. Tan, L. Xu, L. Bing, H. T. Ng, and S. M. Aljunied. Revisiting DocRED -- Addressing the False Negative Problem in Relation Extraction. In *EMNLP*, 2022.

[3] Y. Yao, D. Ye, P. Li, X. Han, Y. Lin, Z. Liu, Z. Liu, L. Huang, J. Zhou, and M. Sun. DocRED: A Large-Scale Document-Level Relation Extraction Dataset. In *ACL*, 2019.

[4] R. F. Barber and E. J. Candès. Controlling the False Discovery Rate via Knockoffs. *Annals of Statistics*, 43(5):2055--2085, 2015.

[5] E. Candès, Y. Fan, L. Janson, and J. Lv. Panning for Gold: Model-X Knockoffs for High-Dimensional Controlled Variable Selection. *Journal of the Royal Statistical Society: Series B*, 2018.

[6] B. Wen, J. Freestone, M. Riffle, M. J. MacCoss, W. S. Noble, and U. Keich. Assessment of False Discovery Rate Control in Tandem Mass Spectrometry Analysis Using Entrapment. *Nature Methods*, 22:1454--1463, 2025.

[7] A. Rajchert and U. Keich. Controlling the False Discovery Rate via Competition: Is the +1 Needed? *Statistics & Probability Letters*, 2022.

[8] A. Ebadi, D. Luo, J. Freestone, W. S. Noble, and U. Keich. Bounding the FDP in Competition-Based Control of the FDR. *arXiv:2302.11837*, 2023.

[9] F. Imrie, A. R. Bradley, and C. M. Deane. Generating Property-Matched Decoy Molecules Using Deep Learning. *Bioinformatics*, 37(15):2134--2141, 2021.

[10] M. Xiong, Z. Hu, X. Lu, Y. Li, J. Fu, J. He, and B. Hooi. Can LLMs Express Their Uncertainty? An Empirical Evaluation of Confidence Elicitation in LLMs. In *ICLR*, 2024.

[11] K. Tian, E. Mitchell, A. Zhou, A. Sharma, R. Rafailov, H. Yao, C. Finn, and C. D. Manning. Just Ask for Calibration: Strategies for Eliciting Calibrated Confidence Scores from Language Models Fine-Tuned with Human Feedback. In *EMNLP*, 2023.

[12] V. Wang and E. Stengel-Eskin. Calibrating Verbalized Confidence with Self-Generated Distractors (DINCO). *arXiv:2509.25532*, 2025.

[13] P. Manakul, A. Liusie, and M. J. F. Gales. SelfCheckGPT: Zero-Resource Black-Box Hallucination Detection for Generative Large Language Models. In *EMNLP*, 2023.

[14] A. Sawczyn, J. Binkowski, D. Janiak, et al. FactSelfCheck: Fact-Level Black-Box Hallucination Detection for LLMs. In *Findings of EACL*, 2025.

[15] C. Mohri and T. Hashimoto. Language Models with Conformal Factuality Guarantees. In *ICML*, 2024.

[16] Y. Jin and E. J. Candès. Selection by Prediction with Conformal p-values. *Journal of Machine Learning Research*, 2023.

[17] M. Rubin-Toles, M. Gambhir, K. Ramji, et al. Conformal Language Model Reasoning with Coherent Factuality. In *ICLR*, 2025.

[18] J. Li, A. Magesh, and V. V. Veeravalli. Principled Detection of Hallucinations in Large Language Models via Multiple Testing. *arXiv:2508.18473*, 2025.

[19] L. Lu, Y. Huo, H. Ren, Z. Wang, and J. Zou. Feedback-Enhanced Online Multiple Testing with Applications to Conformal Selection. *arXiv:2509.03297*, 2025.

[20] T. X. Olausson, A. Gu, B. Lipkin, C. E. Zhang, A. Solar-Lezama, J. B. Tenenbaum, and R. Levy. LINC: A Neurosymbolic Approach for Logical Reasoning by Combining Language Models with First-Order Logic Provers. In *EMNLP*, 2023.

[21] L. Pan, A. Albalak, X. Wang, and W. Y. Wang. Logic-LM: Empowering Large Language Models with Symbolic Solvers for Faithful Logical Reasoning. In *Findings of EMNLP*, 2023.

[22] J. Wei, X. Wang, D. Schuurmans, M. Bosma, B. Ichter, F. Xia, E. Chi, Q. Le, and D. Zhou. Chain-of-Thought Prompting Elicits Reasoning in Large Language Models. In *NeurIPS*, 2022.

[23] Z. Yang, A. Ishay, and J. Lee. Coupling Large Language Models with Logic Programming for Robust and General Reasoning from Text. In *Findings of ACL*, 2023.

[24] P. Clark, O. Tafjord, and K. Richardson. Transformers as Soft Reasoners over Language. In *IJCAI*, 2020.

[25] O. Tafjord, B. Dalvi, and P. Clark. ProofWriter: Generating Implications, Proofs, and Abductive Statements over Natural Language. In *Findings of ACL*, 2021.

[26] P. Lewis, E. Perez, A. Piktus, et al. Retrieval-Augmented Generation for Knowledge-Intensive NLP Tasks. In *NeurIPS*, 2020.

[27] N. Reimers and I. Gurevych. Sentence-BERT: Sentence Embeddings Using Siamese BERT-Networks. In *EMNLP*, 2019.

[28] A. C. Cameron, J. B. Gelbach, and D. L. Miller. Bootstrap-Based Improvements for Inference with Clustered Errors. *Review of Economics and Statistics*, 90(3):414--427, 2008.
</previous_paper>

<reviewer_feedback>
STEP 1 — REVIEW: A reviewer evaluated the previous paper draft above and produced this feedback.

- [MAJOR] (evidence) No empirical results are reported for any central claim. The realized-FDR-vs-alpha calibration diagonal (S2), the operational wedge of decoy-gating vs. plain thresholding at matched recall (S4), the entrapment corroboration (S3), and the goal's explicit hard requirement of a 'quantified reduction in hallucination rates compared to raw LLM generation' (S6) are all unmeasured. The paper is candid about this, but candor does not change the contribution level: at ACL/EMNLP/NeSy a paper whose headline method is unvalidated is a proposal, and these venues do not run a registered-report track. This is the dominant score blocker.
  Action: Execute the pre-registered protocol in the registered priority order (Phase-0 pilot -> CLUTRR diagonal -> Re-DocRED wedge) and report actual numbers with document-block-bootstrap CIs in the camera-ready tables. The infrastructure and budget are already sized for it; at minimum report the CLUTRR diagonal on the populable multi-hop family and the Re-DocRED wedge vs. the plain-threshold foil. Even a partial, honest result (e.g., calibrated at alpha>=0.1, untestable below) would move the paper from reject toward weak-accept.
- [MAJOR] (methodology) The load-bearing validity condition (the knockoff null sign-flip property) is unprovable for LLM decoys, and the construction is circular: the same LLM generates the counterfactual decoys AND scores both real and decoy candidates. Worse, the relevant matching target is the score distribution of spontaneous false-REAL candidates (the model's own document-anchored hallucinations), which is unknown and uncontrollable a priori, not the true-positive distribution that DeepCoy matches. There is a concrete reason to expect non-exchangeability: a model may systematically score its own document-anchored hallucinations differently from deliberately-constructed counterfactuals, biasing W signs and breaking FDR control in either direction. The paper flags 'decoys too easy -> anti-conservative' but not this asymmetry between matching false-positive vs. true-positive score distributions, nor the shared-model bias channel.
  Action: Make the S1 tail-exchangeability check (win-rate ~0.5 and the upper-tail two-sample test on false-real vs. decoy scores) a first-class, prominently reported result, not just a gating diagnostic. Add an ablation that decouples the generator and scorer (decoys generated and/or scored by a different model) to test whether shared-model bias inflates the gate. Explicitly discuss why matching the false-real (not true-positive) distribution is the crux, and treat the gate's validity as an empirically established property reported with its failure region, not an assumed one.
- [MAJOR] (scope) Scope mismatch with the stated goal and target application. The goal targets ~3000-character professionally written legal/news/regulatory documents, OpenCyc-style upper-ontology grounding, and an LLM 'probabilistic reasoning engine.' The actual anchors are ~355-character synthetic templated kinship stories (CLUTRR; I measured mean 354.9 chars, max 917) and ~200-word Wikipedia paragraphs (Re-DocRED; mean ~199 words); OpenCyc is replaced by a coarse 6-type WordNet hypernym slice {PER,LOC,ORG,TIME,NUM,MISC}; and the Prolog layer is a deterministic backward-chaining meta-interpreter, not probabilistic reasoning. The 15-document legal/news/story corpus is explicitly non-confirmatory. So the headline application genres are never quantitatively evaluated, and two named requirements (OpenCyc, probabilistic reasoning) are substituted without quantitative justification.
  Action: Either (a) add a quantitative anchor in the target genre (a small annotated legal/news set with crisp-enough gold for at least relative comparisons), or (b) reframe the scope claims to match what is evaluated (short-document kinship reasoning + document-level relation extraction). Justify the WordNet-for-OpenCyc and deterministic-for-probabilistic substitutions explicitly, and state plainly which goal requirements are descoped this iteration vs. deferred.
- [MAJOR] (rigor) Statistical power for the diagonal is not demonstrated and may be marginal. To certify alpha=0.05 the 1/k floor requires >=20 admissions, and the populability gate requires N_false_min=40 genuine false admissions pooled. With 150 confirmatory CLUTRR documents each contributing ~5 multi-hop facts (I measured mean 4.9, min 1) and acknowledged within-document dependence, the effective independent sample is small, so the document-block-bootstrap CIs may be too wide to distinguish 'tracks alpha within tau=0.05' from 'anti-conservative.' The paper itself concedes the diagonal may be declared 'untestable' -- a likely outcome that would leave the headline unproven even after the run.
  Action: Report a concrete pre-run power calculation: given expected false-admission counts, the within-document intra-class correlation, and B>=2000 block-bootstrap resamples, which alpha values can actually be demonstrated and at what CI half-width? If power is marginal, enrich the false-positive pool further (harder long-chain CLUTRR splits, more aggressive over-generation) or, where gold permits, pool the CLUTRR atomic and multi-hop families to lift the admission count above the floor for tighter alpha.
- [MINOR] (rigor) The paper risks conflating bootstrap-based inference with dependence-robust validity. Knockoff+ controls FDR in finite samples under the joint sign-flip property; the document-block bootstrap provides percentile CIs for the realized FDP but does not restore the FDR control GUARANTEE when within-document dependence violates the i.i.d.-fair-coin assumption. As written, the bootstrap is sometimes presented as if it addresses the dependence threat to validity itself.
  Action: Separate the two roles cleanly in Section 4.4/Preliminaries: (1) the block bootstrap quantifies FDP/FDR sampling variability; (2) validity under dependence is an empirical property established by the tail diagnostics and the isolated-vs-batched discriminator, not a theorem. Cite the relevant dependent-knockoff literature if you wish to claim any theoretical robustness.
- [MINOR] (novelty) The novelty claim is defensible but under-defended against the closest recent work. Reviewers will probe the boundary with conformal selection (Jin-Candes [16]), multiple-testing hallucination detection [18], COCOCO (conformal sets for neuro-symbolic concept-based models), conformal e-value novelty detection with FDR, and conformal link-prediction FDR. The current prose asserts orthogonality but does not make the distinctions crisp enough to preempt a 'this is just labeled conformal selection at the fact level' rebuttal.
  Action: Add a one-page comparison table contrasting each nearest-neighbor method on (label requirement, unit certified [final answer/claim set vs. intermediate admission/bridge], exchangeability mechanism, whether decoy-based). Explicitly position COCOCO and conformal-selection-FDR as the most adjacent and articulate the precise delta (label-free + decoy competition + admission boundary).
- [MINOR] (clarity) Two inconsistent definitions of the competition statistic W_i appear: the introduction uses W_i = score(real_i) - score(decoy_i) (a signed difference), while Preliminaries uses W_i = (Z_i v Z~_i)[2*1(Z_i>Z~_i)-1] (a signed maximum). These are mathematically distinct statistics; using them interchangeably without comment will confuse expert readers and invites doubt about which guarantee actually applies.
  Action: Choose one canonical statistic, define it once in Preliminaries, and use it consistently. If you intend to support both, state that both are valid antisymmetric knockoff statistics and specify which is used in the experiments.
- [MINOR] (clarity) Figures are referenced only as [FIGURE:figN] markers with no captions or descriptions visible in the manuscript text, so it is impossible to assess whether the planned figures would effectively communicate the (eventual) results. Given that the central evidence will be a calibration diagonal and an operational wedge, the figures are load-bearing.
  Action: Include a complete caption and a short description for each figure in the manuscript. Ensure fig for the realized-FDR-vs-alpha diagonal (with the 1/k floor and bootstrap CIs marked) and fig for the matched-recall precision/hallucination-rate comparison against all baselines are present and self-explanatory.
- [MINOR] (evidence) The baseline suite is well chosen on paper (plain confidence-threshold gate, CoT, RAG, labeled Mohri-Hashimoto conformal factuality) but none has been run, and the 'matched-recall' comparison hinges on a single fixed claim-decomposition + relation-alignment step (MiniLM top-8 shortlist -> temp-0 LLM pick among 96 codes). That alignment step is itself an LLM component that could inject errors uniformly across systems and confound the wedge.
  Action: When running S4, report the alignment step's own error rate (e.g., on a labeled slice) and verify the wedge survives reasonable alignment-error sensitivity. Show the plain-threshold foil and conformal reference at the matched operating point with CIs so the 'decoy-gating beats thresholding' claim is isolated from alignment noise.
</reviewer_feedback>

<pipeline_steps>
STEP 2 — STRATEGY: The pipeline's strategy generator (gen_strat) read the reviewer feedback
and designed a new research strategy to address the critiques.

STEP 3 — PLANNING: The planner (gen_plan) turned the strategy into concrete artifact plans —
specific experiments, datasets, or research tasks to execute.

STEP 4 — EXECUTION: The executor (gen_art) ran those plans and produced the new artifacts
shown in <new_artifacts_this_iteration> below.
</pipeline_steps>

<hypothesis>
STEP 5 — HYPOTHESIS UPDATE: The hypothesis was revised based on evidence from previous iterations.

kind: hypothesis
title: >-
  Decoy-Gated Neuro-Symbolic Extraction: Executing the Label-Free FDR Diagonal, the Operational Wedge, and a Quantified Hallucination-Reduction
  on Professional Documents -- with Generator!=Scorer De-Circularization and Demonstrated Power
hypothesis: |-
  MECHANISM (unchanged, one sentence). Before any LLM-proposed Prolog FACT or fuzzy-unification BRIDGE rule enters a knowledge base, it must out-score a plausibility-matched synthetic DECOY (a candidate the model finds plausible but the document does not entail) in a target-decoy / knockoff+ competition; the gate admits the most permissive cutoff whose estimated corpus-aggregate false-admission rate (FDR) is at most a target alpha, using ZERO operation labels.

  WHAT IS NOW SETTLED (iteration-1 deliverable, reviewer-verified). The two evaluation anchors and two implementation-ready methodology specs EXIST, are schema-validated, deterministically regenerable on commodity CPU under a fixed seed, and were independently confirmed by review to match the paper exactly: (A) CLUTRR calibration anchor -- 190 examples (150 confirmatory + 40 pilot), k=2..10 hop stratification, CRISP gold from proof_state fields; (B) Re-DocRED operational anchor -- 236 documents (152 confirmatory / 36 pilot / 48 reserve), 4 balanced entity-type clusters (PER/ORG/LOC/MISC), 96 relation types, human gold with evidence spans. The pipeline, decoy/entrapment construction, scoring, gate, and the shared-triple operational comparison are specified to formulas and prompt templates. Therefore the next iteration does NOT re-plan or re-build; it EXECUTES.

  THE ONE THING THAT MATTERS NOW (the realized diagonal). The iteration-1 paper was scored below bar (3/10) for a single decisive reason: it reported NO empirical result on any central claim. The contribution of this iteration is the REALIZED numbers: (1) the calibration diagonal -- does realized FDR track target alpha on the populable CLUTRR family? (2) the operational wedge -- does decoy-gating beat a plain confidence threshold at matched recall on Re-DocRED? (3) the goal's HARD REQUIREMENT -- a quantified reduction in hallucination rate versus raw LLM generation, measured on genuine short professionally-written documents with auditable trace-graphs. All three with document-block-bootstrap CIs. Nothing secondary is reported until these land.

  THE GATE (one canonical statistic; clarity fix). For each candidate i with real score Z_i and matched-decoy score Z~_i, the competition statistic is the knockoff+ signed maximum W_i = (Z_i OR Z~_i) * sign(Z_i - Z~_i) (i.e. magnitude max(Z_i, Z~_i), sign by which won). knockoff+ thresholding scans cutoffs t and admits {i : W_i >= t} at the most permissive t whose estimated FDR = (1 + #{W_i <= -t}) / max(1, #{W_i >= t}) <= alpha. The per-pair signed DIFFERENCE d_i = Z_i - Z~_i is used ONLY as a tail diagnostic (win-rate, CDF tests), never as the gating statistic. (Iteration-1 paper used two inconsistent W_i definitions; this iteration fixes the canonical one above.)

  VALIDITY HONESTY (rigor fix). knockoff+ delivers a FINITE-SAMPLE FDR GUARANTEE only under the joint null SIGN-FLIP property; for LLM decoys that property is UNPROVABLE, so the realized-FDR-vs-alpha diagonal IS its empirical test, not a corollary of a theorem. The document-block bootstrap supplies realized-FDP confidence intervals and a within-document-dependence DIAGNOSTIC; it does NOT restore the guarantee. We never conflate the two.

  DE-CIRCULARIZATION (methodology fix -- the deepest review concern). The review's decisive methodological objection is that the SAME LLM both generates the counterfactual decoys and scores real-vs-decoy, and that the relevant matching target is the score distribution of SPONTANEOUS false extractions, not of deliberately generated decoys. Three pre-registered moves break this:
    (a) GENERATOR != SCORER ABLATION. On a labeled slice, decoys generated by model G are scored by a DIFFERENT-FAMILY model S (and the symmetric swap). If the diagonal holds only when G=S, the control is an artifact of shared idiosyncrasy and is REPORTED AS SUCH (a localized negative result), not as confirmation.
    (b) SPONTANEOUS-ERROR CDF MATCH. Phase-0 adds a tail CDF-match test between counterfactual-decoy scores and the scores of GENUINE extractor errors (the spontaneous false admissions the gate must actually catch). A decoy family that does not reproduce the spontaneous-error tail is re-tuned or its matching gap is reported; the diagonal is only asserted on a decoy family that passes this match.
    (c) INDEPENDENT ENTRAPMENT as the non-circular corroborator. Entrapment items are built by DETERMINISTIC perturbation (in-genre cross-document swaps, numeric/temporal perturbation, explicit contradiction) -- constructed WITHOUT the generating LLM -- and provide a valid upper bound FDP_hat = N_E(1+1/r)/(N_T+N_E) that must agree with the decoy-FDR and with gold.

  DEMONSTRATED POWER (rigor fix). The review flagged that diagonal power may be marginal: certifying alpha=0.05 needs >=20 admissions (1/k floor) and the populability gate needs N_false_min=40 genuine false admissions pooled. Phase-0 MUST demonstrate both are reachable on the CLUTRR multi-hop family at the operative alpha* BEFORE the diagonal is asserted; if not, the (regenerable) CLUTRR confirmatory set is SCALED UP -- more documents and harder long-chain (large-k) splits that densify genuine errors -- until the power target is met or declared unreachable. The CERTIFIED-alpha grid is reported honestly: any alpha whose 1/k admission floor is not reached is dropped from the certified diagonal and reported as a precondition (NEVER as 'confirmed by conservatism').

  SCOPE / GOAL ALIGNMENT (scope fix). The goal targets ~3000-character professionally written legal/news/regulatory documents, upper-ontology (OpenCyc-style) grounding, and an LLM probabilistic-reasoning engine at fuzzy unifications. CLUTRR (synthetic ~355-char kinship) and Re-DocRED (Wikipedia prose) remain the CALIBRATION and STATISTICAL-OPERATIONAL anchors -- they buy crisp gold for the exact diagonal and human gold for the wedge -- but they are proxies, not the application. This iteration ADDS a genre-faithful OPERATIONAL DEMONSTRATION slice: ~15-30 genuine short professionally-written documents (legal/news/regulatory), on which we (i) ground argument types in a commodity upper-ontology slice (WordNet/ConceptNet/DBpedia-ontology standing in for OpenCyc) used ONLY for typing, (ii) run an explicit LLM probabilistic-reasoning step at fuzzy unifications, (iii) report the goal's HARD-REQUIRED quantified hallucination-reduction of decoy-gated extraction vs raw LLM generation, and (iv) export auditable trace-graphs whose leaves carry provenance + decoy + entrapment certificates. The application-faithful headline number lives here; the anchors grant it statistical validity.

  CLAIM CHAIN (each row independently testable; a break is localized and reported).
  | # | CLAIM | TEST | PASS CRITERION |
  |---|-------|------|----------------|
  | S0 | Score separation (precondition) | Phase-0: selected elicitation separates entailed vs non-entailed in the UPPER TAIL; isolated~batched agree on a labeled slice | tail-AUC>0.5 with CI; isolated~batched |
  | S1 | Decoy signature + spontaneous-error match (mechanism) | Tail-conditioned win-rate among above-cutoff matched pairs + upper-tail two-sample CDF test + decoy-vs-spontaneous-error tail CDF match | counterfactual decoys ~0.5; decoy tail ~ spontaneous-error tail; random swaps anti-conservative |
  | S2 | Calibration validity / the DIAGONAL (CLUTRR) | Sweep alpha; realized FDR vs crisp gold; document-block-bootstrap CI on the diagonal, on the populable family at demonstrated power | diagonal tracked within tau above the 1/k floor across the CERTIFIED grid |
  | S2b | Generator!=Scorer de-circularization (CLUTRR) | Re-run the diagonal with decoys from G scored by different-family S (and swap) on a labeled slice | diagonal survives G!=S, else reported as shared-model artifact |
  | S3 | Entrapment corroboration (non-circular) | Independent deterministically-built tail-matched entrapment; combined bound FDP_hat=N_E(1+1/r)/(N_T+N_E) | bound agrees with decoy-FDR and gold |
  | S4 | Operational wedge (Re-DocRED) | Matched-recall PR + hallucinated-conclusion rate vs PLAIN CONFIDENCE-THRESHOLD gate (primary zero-label comparator), CoT, RAG, labeled Mohri-Hashimoto conformal | decoy-gating beats plain thresholding at equal zero labels; competitive with labeled conformal |
  | S4b | Application-faithful hallucination reduction (professional docs) | On ~15-30 genuine short legal/news/regulatory docs: hallucinated-fact rate of decoy-gated extraction vs raw LLM generation; trace-graphs exported | quantified reduction reported with CI; trace-graphs auditable (goal hard requirement) |
  | S5 | Document-level predictive account (Re-DocRED) | Predict per-document tail-exchangeability gap; leave-one-cluster-out + leave-one-document-out CV; pre-registered GAP-regression power analysis | out-of-sample predictive IFF >= N_min held-out units; else DESCRIPTIVE |
  | S6 | Predictable propagation (preliminary) | Tightening alpha lowers multi-hop hallucinated-conclusion rate | direction + rough magnitude |

  BUDGET (unchanged ceiling). Isolated, provenance-blinded scoring is the default for the full confirmatory set; document-prefix prompt caching keeps the ~7-15M projected tokens to ~$1-3; the added professional-doc slice and the G!=S ablation slice add a small labeled increment. Cumulative LLM cost logged after every call; HARD STOP at $10. The budget waterfall is unchanged in ORDER but its first three priorities are now the three realized numbers above (diagonal, wedge, professional-doc hallucination reduction); S5/S6/floor-relaxation/rule-gating remain leftover-only.

  SCOPE OF CLAIMS. Facts AND bridges carry the headline. CLUTRR bridges are crisp and host the diagonal + the G!=S de-circularization; Re-DocRED bridges host the operational wedge and the predictive account; the professional-doc slice hosts the application-faithful hallucination-reduction headline. Defeasible bridges, ProbLog/isotonic, TDC-SB/UB and '+1'-floor relaxation, and S6 remain preliminary / if-budget-permits.
motivation: |-
  Text-to-logic pipelines stall at one crux: when strict symbolic unification fails, an LLM must fuzzy-match predicates and supply background knowledge, and that interface is exactly where hallucination re-enters and silently corrupts every downstream deduction. The dangerous hallucinations are not random nonsense but PLAUSIBLE, high-confidence false facts. Practitioners have no quantitative, label-free knob there: self-consistency and LLM-as-judge are heuristic; ontology-constraint filtering needs rich trusted constraints and catches only encoded violations; and the strongest uncertainty-quantification methods (conformal factuality, conformal selection + BH, multiple-testing hallucination detection, coherent factuality, and the newest online and differentiable variants) all need a LABELED calibration set and certify the final answer or claim set, not the neural-to-symbolic admission boundary.

  Genomics and proteomics solved an isomorphic label-poor problem -- selecting true signals among overwhelming noise with a guaranteed FDR and no ground truth -- via the knockoff filter and target-decoy competition, and learned the two ways the trick breaks: decoys 'too unrealistic to fool' the scorer make FDR optimistic (cured by property-matched decoys), and entrapment FDP must be estimated with a valid upper bound built INDEPENDENTLY of the decoys. We import matched decoys, the valid combined estimator, and construction-independence to the fuzzy-unification boundary, turning 'reduce hallucination' from a best-effort aspiration into a self-corroborated, label-free, auditable quantity with per-leaf certificates.

  The two-anchor design makes the value claim honest. A label-free FDR knob is worth building only if it is BOTH calibrated AND useful where plausible hallucinations actually bite. CLUTRR's closed kinship vocabulary is the right place to prove CALIBRATION (free crisp gold, exact realized FDR) but the wrong place to prove USEFULNESS (the relation set is tiny and well-known). Re-DocRED -- realistic Wikipedia prose, 96 open relation types, document-level multi-hop, human gold with evidence spans -- is the right place to prove operational usefulness, with a fixed shared extraction schema so the neuro-symbolic pipeline, a plain zero-label confidence threshold, CoT, RAG, and labeled conformal are all measured on the same triples at matched recall. The plain confidence threshold is the load-bearing comparator: it shows whether the decoy-competition machinery adds value over naive thresholding at the SAME zero-label budget, so the wedge cannot collapse to 'a threshold was enough.'

  Why it matters even at coarse alpha: NO existing label-free method offers ANY FDR knob at the fuzzy-unification interface. A first, auditable, zero-operation-label control -- even at alpha ~0.1 -- converts an uncontrolled hallucination channel into a tunable one. Because LLM decoys carry no theoretical guarantee, the most probable outcome is partial control; the Re-DocRED document-level predictive account (S5) converts a likely-partial result into a generalizable mechanism-level insight about WHEN the calibration holds.
assumptions:
- >-
  NULL SIGN-FLIP PROPERTY IS ENGINEERED AND TESTED, NOT GUARANTEED. knockoff+/TDC validity requires that, among genuinely-false
  candidates, sign(W_i) for W_i = score(real_i) - score(decoy_i) behaves like an independent fair coin conditional on |W_i|,
  with each false real and its matched decoy equally likely to receive any score in the high-score region near the cutoff.
  LLM counterfactual decoys carry no construction-level proof of this, so the claim is an empirically-validated calibration
  (not a theorem), tested IN THE TAIL via tail-conditioned win-rate ~0.5 plus an upper-tail two-sample CDF test.
- >-
  SCORE-DEPENDENCE IS HANDLED, NOT ASSUMED AWAY. Within-document correlation of LLM scoring noise is respected by treating
  the DOCUMENT as a block (document-block bootstrap for all FDP CIs; never i.i.d.-pooled signs). Batched-scoring contrast
  effects are removed by ISOLATED, provenance-blinded, order-randomized scoring as the default, with a pre-registered isolated-vs-batched
  check that doubles as the DISCRIMINATOR between a scoring artifact (isolation restores the diagonal) and genuine decoy non-exchangeability
  (anti-conservatism persists under isolation).
- >-
  THE SCORE-SEPARATION PRECONDITION IS PILOT-GATED. The LLM must emit a roughly monotone score separating document-entailed
  from non-entailed content better than chance SPECIFICALLY in the upper tail; verbalized confidence is documented to be overconfident
  there, so it is not assumed. A Phase-0 pilot selects the best elicitation (verbalized, logprob-derived, self-consistency,
  DINCO-style distractor-normalized), verifies tail separation, and confirms isolated~batched agreement on a labeled slice.
  The headline budget is released only on pilot success; otherwise the precondition-failure analysis is the reported result.
- >-
  THE CALIBRATION DIAGONAL NEEDS GENUINE FALSE ADMISSIONS, AND POPULABILITY IS MEASURED BEFORE IT IS ASSERTED. A realized-FDR-vs-alpha
  diagonal can only TRACK alpha if a meaningful fraction of admitted reals are genuinely false; on CLUTRR's easy closed vocabulary
  atomic facts may be too clean. Phase-0 measures, at the operative alpha*, the genuine false-admission count among CLUTRR
  proposals separately for atomic facts and multi-hop inferred kinship; the primary disconfirmation is pre-registered on whichever
  family reaches N_false_min (default 40 pooled; default expectation: multi-hop). The false-real pool is enriched by extractor
  over-generation and harder long-chain CLUTRR splits. Below N_false_min on all families, the diagonal is declared UNTESTABLE
  (not 'conservative, therefore confirmed'). CLUTRR gold is exact so the diagonal is asserted there; Re-DocRED gold has residual
  false negatives so only RELATIVE operational comparisons under shared gold are asserted there.
- >-
  S5 IS POWERED WHERE FEATURE VARIANCE EXISTS, WITH A PRE-REGISTERED PREDICTIVE-VS-DESCRIPTIVE THRESHOLD. The per-document
  tail-exchangeability gap can only be predicted if its input features vary; CLUTRR documents are near-homogeneous in entity
  density, specificity, and genre, so S5 is based on Re-DocRED (>=4 entity-type/topic clusters supply real cross-document
  variance). The S5 unit is the document nested in clusters, validated by leave-one-cluster-out and leave-one-document-out
  CV with a pre-registered GAP-regression power analysis; below a pre-registered minimum N_min of held-out units with sufficient
  admissions, S5 is reported DESCRIPTIVE, not predictive.
investigation_approach: |-
  Build the pipeline end to end, run a gating pilot first, then execute a strict BUDGET WATERFALL: Phase-0 pilot -> CLUTRR calibration diagonal -> Re-DocRED operational wedge -> (leftover only, gated on the two anchors clearing power thresholds) S5 / S6 / floor-relaxation / rule-gating. CPU-only; cumulative LLM cost logged after every call; HARD STOP at $10.

  FEASIBILITY (published before committing; see the budget arithmetic in the hypothesis). Isolated, provenance-blinded scoring is the default for 100% of the ~14.4K confirmatory scoring items; the ~7-15M projected tokens are kept to ~$1-3 by document-prefix prompt caching (the ~60 scoring calls per document re-use one cached document context at ~0.1x read cost). A sub-$0.30/M model is used; batching appears only in the labeled isolated-vs-batched sensitivity slice.

  PHASE 0 -- PILOT (precondition + powerability). On a few dozen labeled items per anchor: (i) select the elicitation that best separates entailed vs non-entailed IN THE UPPER TAIL; (ii) confirm isolated~batched agreement on a labeled slice (gate batching); (iii) MEASURE the genuine false-admission count among CLUTRR atomic-fact and multi-hop-bridge proposals at alpha* and choose the populable family for the primary disconfirmation (enrich via over-generation + long-chain splits if sparse); (iv) MEASURE on CLUTRR the cross-document variance of the S5 features (demonstrating CLUTRR's unsuitability for S5); (v) run a tail power analysis AND a GAP-regression power analysis for S5 on Re-DocRED. Size both corpora to target; gate the full run.

  PIPELINE. (1) EXTRACTION: a cheap OpenRouter LLM proposes typed first-order facts; argument types grounded in a commodity upper-ontology slice (WordNet/ConceptNet/DBpedia-ontology, standing in for OpenCyc) used ONLY for typing; the extractor OVER-GENERATES on CLUTRR to densify false positives. (2) DECOY GENERATION: PRIMARY family = document-conditioned counterfactual decoys (maximally-plausible, non-entailed facts/bridges); random type-matched swaps retained as the predicted-anti-conservative baseline; every decoy passes a non-entailment check with reported contamination. (3) ENTRAPMENT: independent, tail-matched, false-by-construction (in-genre cross-document swaps, numeric/temporal perturbation, explicit contradiction), mixed at reported ratio r, with its own tail-difficulty diagnostic. (4) SCORING: isolated, provenance-blinded, order-randomized, pilot-selected elicitation; rank-normalized per document. (5) FDR GATE: knockoff+ thresholding picks the most permissive cutoff with estimated corpus-aggregate FDR <= alpha, separately for facts and bridges and per anchor; admitted items enter the KB with a logged certificate. (6) VARIANCE/CIs: document-block bootstrap throughout. (7) ENTRAPMENT VALIDATION: combined estimator upper-bounds realized false-admission; compare against decoy-FDR and gold. (8) TAIL DIAGNOSTICS (measurement only): above-cutoff distribution vs gold false-reals + win-rate + upper-tail two-sample test. (9) REASONING: admitted facts/bridges populate SWI-Prolog for multi-hop deduction; backward-chaining proofs export as trace-graphs whose leaves carry provenance plus the decoy + entrapment certificate.

  SHARED OPERATIONAL EVALUATION (Re-DocRED). A single fixed claim-decomposition + relation-alignment step maps every system's output to (head, Re-DocRED-relation, tail) triples identically -- neuro-symbolic, plain confidence threshold, CoT, RAG, labeled conformal. Recall is matched by sweeping each system's own score to a common operating point; precision and hallucinated-conclusion rate are compared there with document-block-bootstrap CIs.

  EXPERIMENTS. (a) CLUTRR validity-of-control: sweep alpha; realized FDR via gold + entrapment bound on the populable family; diagonal tracking with block-bootstrap CIs; normalization and isolated-vs-batched sensitivity. (b) Decoy-family showdown + entrapment tail-difficulty. (c) Re-DocRED operational: matched-recall PR + hallucinated-conclusion rate vs PLAIN THRESHOLD (primary zero-label comparator), CoT, RAG, and labeled conformal, with guarantee status side by side. (d) [leftover only] S5 LOO-CV on Re-DocRED with the predictive-vs-descriptive threshold; S6 propagation; floor-relaxation; rule gating. (e) Cost check (<$10, CPU-only) + auditable trace-graphs.
success_criteria: |-
  PRECONDITION (gate). Phase-0 must show the selected score separates entailed from non-entailed content better than chance in the upper tail, isolated~batched agree, a CLUTRR family reaches N_false_min genuine false admissions, and the S5 power/variance measurements support a gap regression on Re-DocRED. If the pilot fails any gate, the reported contribution is the precondition-failure analysis.

  PRIMARY DISCONFIRMATION (single, S4/S5-independent). On the populable CLUTRR family (default: multi-hop inferred kinship) under isolated provenance-blinded scoring at alpha*: the central label-free control claim is DISCONFIRMED if realized corpus-aggregate FDR (vs crisp gold) exceeds alpha* by more than tolerance tau AND the document-block-bootstrap CI lies entirely on the anti-conservative side. If no family reaches N_false_min even after enrichment, the diagonal is reported UNTESTABLE (a precondition outcome), never as confirmed-by-conservatism.

  CONFIRMED requires ALL of: (1) CALIBRATION VALIDITY (CLUTRR) -- realized FDR tracks target alpha within tau above the 1/k floor across the demonstrable grid on the populable family, stable under the normalization and isolated-vs-batched checks; (2) DECOY SIGNATURE -- counterfactual decoys reach tail-conditioned win-rate ~0.5 and pass the upper-tail two-sample test while random swaps are measurably anti-conservative, and entrapment passes its tail-difficulty diagnostic with the combined-estimator bound agreeing with gold; (3) OPERATIONAL WEDGE (Re-DocRED) -- at matched recall (PR curves with block-bootstrap CIs), decoy-gating BEATS the plain confidence-threshold gate on atomic-fact precision and hallucinated-conclusion rate under identical zero labels, and stays competitive with the labeled Mohri-Hashimoto conformal reference. A BH multiplicity correction is applied across all validation tests.

  SECONDARY (reported only after the two anchors clear power thresholds; never escape hatches). (4) S5 document-level model: PREDICTIVE if validated out-of-sample across >= N_min held-out Re-DocRED units, else DESCRIPTIVE; either way it characterizes WHICH features govern tail-exchangeability. (5) Entrapment self-corroboration agrees with gold (co-failures reported). (6) S6 -- tightening alpha reduces multi-hop hallucination in the predicted direction. (7) Ablating the decoy gate measurably worsens hallucination. (8) The pipeline runs on commodity CPU within $10 with auditable trace-graphs carrying per-leaf certificates.

  DISCONFIRMED if: the primary disconfirmation fires (populable CLUTRR family anti-conservative beyond tau under isolated scoring); OR, separately for the operational claim, decoy-gating shows no precision/hallucination advantage over the PLAIN CONFIDENCE-THRESHOLD gate at matched recall on Re-DocRED (the wedge collapses to 'thresholding is enough'). An uninterpretable null -- control neither clearly holds nor clearly fails because the tail, the diagonal, or the gap test is underpowered -- is the true failure the Phase-0 power analysis (now including the false-admission base-rate measurement) is designed to prevent.
related_works:
- >-
  Wen, Freestone, Riffle, Noble & Keich, 'Assessment of false discovery rate control in tandem mass spectrometry analysis
  using entrapment' (Nature Methods 22:1454-1463, 2025; FDRBench): gives the theory of entrapment FDP estimation, shows the
  naive 'sample' estimator is flawed, and provides the valid combined upper bound FDP_hat = N_E(1+1/r)/(N_T+N_E). We adopt
  this estimator, report r, propagate r into variance and the alpha-floor, and ADD a tail-difficulty diagnostic for entrapment.
  Difference: their domain is peptide identification; we transplant the estimator and construction-independence to LLM fact/bridge
  admission.
- >-
  Barber & Candes, knockoff filter (Annals of Statistics 2015) and Candes et al., Model-X knockoffs (2018), plus target-decoy
  competition in proteomics: select true signals among many candidates with guaranteed FDR by competing each real against
  a synthetic negative control exchangeable BY CONSTRUCTION, relying on the null sign-flip property (signs of null statistics
  are i.i.d. coin flips conditional on magnitude). Difference: this machinery lives in numeric feature selection and mass
  spectrometry where exchangeability is provable; we adapt knockoff+ thresholding to the LLM neuro-symbolic boundary where
  decoys carry NO such guarantee, so we test the sign-flip condition empirically in the tail, use a document-block bootstrap
  for within-document sign dependence, and model where it holds.
- >-
  Property-matched decoy generation in cheminformatics/proteomics (DeepCoy, Bioinformatics 2021; protein-language-model decoys):
  generate decoys that reproduce the score properties of true positives so target-decoy FDR is well-calibrated. Difference:
  lives in molecular screening; we import the PRINCIPLE -- decoys must reproduce the false-positive score distribution, not
  be 'too easy' -- to design LLM fact/bridge decoys as document-conditioned counterfactuals.
- >-
  Tan, Xu, Bing et al., 'Revisiting DocRED -- Addressing the False Negative Problem in Relation Extraction' (EMNLP 2022; Re-DocRED).
  DocRED comprises 5,053 Wikipedia documents (distant-supervised from Wikidata), averaging 196.7 words and 19.5 entities,
  with 97 predefined relation types (96 real + no_relation) and human evidence sentences; Re-DocRED re-annotates 4,053 by
  adding missed triples (~13 F1 of headroom) and is public. We USE Re-DocRED as the open-vocabulary operational anchor (a
  fixed shared (head, relation, tail) extraction schema for ALL systems), asserting only RELATIVE operational comparisons
  (shared residual false negatives affect all methods equally), not the absolute FDR diagonal, which we assert on crisp-gold
  CLUTRR. Re-DocRED documents are SHORT (~200 words), which is strictly easier for commodity hardware; we treat document length
  itself as an S5 feature.
- >-
  Li, Magesh & Veeravalli, 'Principled Detection of Hallucinations in Large Language Models via Multiple Testing' (arXiv 2508.18473,
  2025): reconceptualizes hallucination detection as hypothesis testing, aggregates gray-box scores via conformal p-values,
  and applies general (dependence-tolerant) Benjamini-Hochberg/Yekutieli to control the false-alarm rate; it 'adds a lightweight
  calibration step that uses a small calibration set of non-hallucinated prompts to provide theoretical control', operating
  at the PROMPT/generation level. Difference: it is LABELED and certifies the generation; we are label-free for operation
  and gate the neuro-symbolic ADMISSION boundary via target-decoy competition with independent entrapment corroboration and
  per-leaf certificates. Its confirmed labeled-calibration requirement strengthens our label-free wedge.
- >-
  Lu, Huo, Ren, Wang & Zou, 'Feedback-Enhanced Online Multiple Testing with Applications to Conformal Selection' (arXiv 2509.03297,
  2025): GAIF, a feedback-enhanced generalized alpha-investing framework that dynamically adjusts thresholds using revealed
  outcomes for finite-sample (m)FDR control, extended to online conformal selection via independent conformal p-values and
  feedback-driven model selection. Difference: it REQUIRES revealed labeled outcomes (feedback) and selects/certifies candidate
  outputs online; we control FDR with ZERO operation labels via decoy competition at the text-to-logic admission boundary,
  with symbolic propagation. The conformal-selection line reinforces -- not threatens -- the label-free wedge.
- >-
  Hittesdorf, Salzetta & Cheng, 'Differentiable Conformal Training for LLM Reasoning Factuality' (Differentiable Coherent
  Factuality / DCF, arXiv 2604.20098, 2026), building on 'Conformal Language Model Reasoning with Coherent Factuality' (arXiv
  2505.17126, ICLR 2025): represent reasoning outputs as dependency graphs and jointly validate claims with their logical
  ancestors; DCF makes the scorer differentiable to learn better scorers while recovering conformal guarantees. Difference:
  both require LABELED held-out calibration and certify OUTPUT claim graphs; we gate the neuro-symbolic ADMISSION boundary
  label-free via decoy competition, and our trace-graph is a Prolog proof with per-leaf decoy+entrapment certificates, not
  a conformally-validated claim DAG.
- >-
  Mohri & Hashimoto, 'Language Models with Conformal Factuality Guarantees' (ICML 2024): a back-off algorithm removing claims
  until a factuality alpha is met via conformal prediction with labeled samples. Our load-bearing LABELED reference baseline
  in S4. Difference: it requires labeled calibration, certifies the final filtered OUTPUT rather than the admission boundary,
  and offers no synthetic-decoy mechanism, independent entrapment, or symbolic propagation. We report its finite-sample guarantee
  vs our empirical calibration side by side; our wedge is label-free OPERATION measured against a plain zero-label threshold.
- >-
  Jin & Candes, 'Selection by Prediction with Conformal p-values' (JMLR 2023): conformal p-values + Benjamini-Hochberg to
  select candidates with FDR control under exchangeability of labeled calibration and test data. Difference: needs labeled
  calibration outcomes; we estimate and control FDR with no operation labels by competing each proposal against engineered
  decoys and corroborate via independent tail-matched entrapment.
- >-
  Ebadi, Crook, Keich et al., 'Bounding the FDP in competition-based control of the FDR' (arXiv 2302.11837, 2023; TDC-SB/UB)
  and He, Ebadi, Keich et al., 'Controlling the FDR via competition: is the +1 needed?' (arXiv 2204.13248, 2023): tighter
  FDP bounds and analysis of the '+1' correction that sets the minimum-estimable-FDR floor. We test (leftover budget only)
  whether these lower our achievable-alpha floor without breaking validity. Difference: developed for generic competition-based
  selection; we apply them at the text-to-logic interface.
- >-
  LINC (Olausson et al., EMNLP 2023) and Logic-LM (Pan et al., Findings of EMNLP 2023): LLM semantic-parse premises into FOL/symbolic
  form executed by a solver, with majority voting or solver-error self-refinement. Difference: no principled control over
  WHICH extracted content is admitted -- a syntactically valid fabricated premise is never challenged; voting smooths variance
  and refinement fixes solver/syntax errors only. No FDR knob, no decoys, no label-free precision guarantee.
- >-
  Ontology-constraint hallucination filtering (ODKE+, Evontree, SHACL validation): reject LLM extractions violating trusted
  ontology constraints (disjointness, domain/range, cardinality). Difference: needs a rich trusted constraint set and only
  catches encoded violations; decoy-gating needs only TYPING and controls overall false-admission rate including where the
  ontology is silent -- complementary.
- >-
  FactSelfCheck (Sawczyn et al., Findings of EACL 2026 / arXiv 2503.17229) and DINCO (Wang et al., arXiv 2509.25532, 2025):
  zero-resource black-box methods producing per-fact hallucination scores from sampling consistency / distractor-normalized
  verbalized confidence. Difference: both yield a per-claim detection SCORE with no admission threshold, exchangeability,
  or competition argument; FactSelfCheck-style and DINCO-style signals are CANDIDATE elicitations in our Phase-0 pilot, while
  our novelty is the label-free FDR gate built on whichever elicitation wins.
inspiration: >-
  A Level-3 (methodological) cross-domain transfer. Genomics/proteomics solved the hardest label-poor problem -- deciding
  which of thousands of candidate signals are real with no ground truth -- with a guaranteed FDR via the knockoff filter (statistics)
  and target-decoy competition (mass spectrometry), and discovered the two ways the trick breaks: decoys 'too unrealistic
  to fool' the scorer make FDR optimistic (cured by property-matched decoys: DeepCoy, protein-LM decoys), and entrapment FDP
  must be estimated with a valid upper bound (Wen et al., Nature Methods 2025) using entrapment built unlike the decoys. We
  map all three onto the fuzzy-unification boundary of a text-to-logic pipeline, where the LLM aligns predicates and supplies
  background knowledge. Because the dangerous hallucinations are PLAUSIBLE high-confidence false facts, the decoys must be
  plausible counterfactuals from the LLM's own prior, exchangeability must be checked IN THE TAIL, and the FDR must be corroborated
  by independently-constructed tail-matched entrapment and arbitrated by a small gold probe. Three further moves come from
  taking the statistical machinery seriously on its own terms: (a) the knockoff null SIGN-FLIP property is named explicitly,
  and the two ways LLM scoring can break it -- within-document score correlation and batched-scoring contrast effects -- are
  handled by a document-block bootstrap and isolated provenance-blinded scoring, with the isolated-vs-batched check doubling
  as the discriminator between a scoring artifact and genuine non-exchangeability; (b) evaluation is split into a CALIBRATION
  anchor (CLUTRR, crisp free gold, exact diagonal -- with the disconfirmation pre-registered on the candidate family dense
  enough in genuine errors to be non-vacuous) and an OPERATIONAL anchor (Re-DocRED, open-vocabulary human gold, a fixed shared
  extraction schema for all systems, with a plain zero-label confidence threshold as the primary comparator so the wedge isolates
  the decoy machinery's value); (c) the document-level predictive account is based on Re-DocRED where the predicted features
  actually vary, with a pre-registered predictive-vs-descriptive threshold.
terms:
- term: Plausibility-matched (counterfactual) decoy
  definition: >-
    A synthetic candidate (fact or fuzzy-unification bridge) generated from the LLM's own prior over document-plausible-but-non-entailed
    content -- a document-conditioned counterfactual -- so its score distribution reproduces that of genuine plausible hallucinations.
    It replaces random type-matched swaps, which are 'too easy' and make the estimated FDR optimistic.
- term: Null sign-flip property (the validity condition)
  definition: >-
    The condition knockoff+/TDC FDR control rests on: among genuinely-false candidates, the sign of W_i = score(real_i) -
    score(decoy_i) behaves like an independent fair coin conditional on |W_i|. Two LLM-scoring channels can break it anti-conservatively
    -- within-document score correlation and batched-scoring contrast effects -- so the method tests and protects against
    both.
- term: Two-anchor evaluation (calibration vs operational)
  definition: >-
    CLUTRR (free, deterministic, crisp gold) hosts the CALIBRATION-VALIDITY claim (the realized-FDR-vs-alpha diagonal) and
    the single primary disconfirmation; Re-DocRED (human-annotated, open-vocabulary, document-level multi-hop) hosts the OPERATIONAL-USEFULNESS
    claim, the genuine schema-alignment bridge test, and the S5 predictive model. CLUTRR proves the knob is calibrated; Re-DocRED
    proves it is useful; the two are never conflated.
- term: Populability gate and false-real enrichment
  definition: >-
    A realized-FDR diagonal can only TRACK alpha if enough admitted reals are genuinely false. Phase-0 measures, at alpha*,
    the genuine false-admission count among CLUTRR atomic-fact and multi-hop-bridge proposals; the primary disconfirmation
    is pre-registered on whichever family reaches N_false_min (default 40 pooled). The false-real pool is enriched by extractor
    over-generation and harder long-chain splits. Below N_false_min on all families, the diagonal is declared UNTESTABLE,
    not confirmed-by-conservatism.
- term: Plain confidence-threshold baseline (the operational comparator)
  definition: >-
    A zero-label gate that admits candidates whose raw elicited confidence exceeds a swept threshold, with no decoy, no competition,
    no entrapment. It is the PRIMARY zero-label comparator in S4: if decoy-gating does not beat it at matched recall on precision
    and hallucinated-conclusion rate under identical labels, the operational wedge is disconfirmed (it reduces to 'thresholding
    is enough').
- term: Shared operational construct (Re-DocRED)
  definition: >-
    All systems target the SAME (head-entity, Re-DocRED-relation, tail-entity) triples over annotated entities, scored against
    human gold. A single fixed claim-decomposition + relation-alignment step maps every system's raw output -- neuro-symbolic,
    plain threshold, CoT, RAG, labeled conformal -- into this triple space identically, and recall is matched by sweeping
    each system's own score to a common operating point, so the comparison is apples-to-apples.
- term: Isolated provenance-blinded scoring
  definition: >-
    Each candidate (real, decoy, or entrapment) is scored in its OWN prompt with source/identity masked and presentation order
    randomized, instead of scoring many candidates jointly. This removes within-batch contrast/ranking effects that would
    let the model implicitly detect fabricated items and depress decoy scores. It is the default for 100% of the confirmatory
    set; document-prefix prompt caching keeps it affordable. The pre-registered isolated-vs-batched check discriminates a
    scoring artifact (isolation restores the diagonal) from genuine non-exchangeability (anti-conservatism persists).
- term: Document-prefix prompt caching
  definition: >-
    Because all ~60 isolated scoring calls for one document re-send the same document context, that prefix is cached once
    and re-read at ~0.1x cost per call. This is the mechanism that makes default isolated scoring fit the $10 budget (~$1-3
    projected) without reverting to batching, preserving the isolated-vs-batched discriminator.
- term: Document-block bootstrap
  definition: >-
    All FDP/FDR confidence intervals are computed by resampling whole DOCUMENTS (blocks), not individual candidates, so within-document
    correlation of LLM scoring noise is respected. This replaces the i.i.d.-pooled-sign variance the knockoff '+1' floor argument
    would otherwise assume, and yields the CI used in the primary disconfirmation.
- term: Tail-conditioned win-rate (tail diagnostic)
  definition: >-
    The win-rate of a decoy (or entrapment item) over a known-false real, computed ONLY among matched pairs scoring above
    the operative admission cutoff, reported with score CDFs and an upper-tail two-sample test. Target ~0.5 in the tail. Measurement
    only, never used by the gate; it supersedes the marginal win-rate, which can read 0.5 on average while a family is anti-conservative
    exactly where admissions occur.
- term: Combined / paired entrapment estimator and the ratio r
  definition: >-
    The valid entrapment upper bound on false-admission: FDP_hat = N_E(1+1/r)/(N_T+N_E), where N_T = admitted reals, N_E =
    admitted entrapment, r = entrapment-to-target ratio (reported; r=1 gives the tighter paired form). It replaces the flawed
    naive 'sample' ratio; r is propagated into variance and the achievable-alpha floor. Entrapment is built by a mechanism
    distinct from the decoys and gets its own tail-difficulty diagnostic.
- term: Single primary disconfirmation
  definition: >-
    One pre-registered, S4/S5-independent result that can falsify the headline: on the populable CLUTRR family under isolated
    provenance-blinded scoring at alpha*, if realized corpus-aggregate FDR exceeds alpha* by more than tolerance tau AND the
    document-block-bootstrap CI lies entirely on the anti-conservative side, the central label-free control claim is disconfirmed
    -- regardless of entrapment agreement or S5 outcome.
- term: Trace-graph
  definition: >-
    A human-auditable graph of the backward-chaining proof: nodes are sub-goals/derived facts, edges are rule applications,
    and each leaf carries its provenance (document span, ontology axiom, or admitted bridge) plus the decoy-competition and
    entrapment certificate that licensed it.
summary: >-
  Every LLM-proposed fact and fuzzy-unification bridge must out-score a plausibility-matched counterfactual decoy in a target-decoy
  / knockoff+ competition before entering a Prolog knowledge base, giving a label-free FDR knob at the neuro-symbolic admission
  boundary; calibration validity is proven on crisp-gold CLUTRR (with the single disconfirmation pre-registered on the error-dense,
  populable candidate family), operational hallucination-reduction is proven on open-vocabulary Re-DocRED against a plain
  zero-label confidence threshold and neural baselines on a shared extraction schema at matched recall, the gate is robustified
  against the two ways LLM scoring breaks the null sign-flip property (document-block bootstrap and isolated provenance-blinded
  scoring kept affordable by document-prefix caching), and a strict budget waterfall powers the two anchors before any secondary
  analysis.
_relation_rationale: >-
  Same gate mechanism and two-anchor frame; re-pointed from build to executing the diagonal and wedge.
_confidence_delta: decrease
_key_changes:
- >-
  STATUS UPDATE: marked the two anchors and two methodology specs as BUILT and reviewer-verified; the hypothesis now starts
  from a ready, validated pipeline and mandates EXECUTION rather than further building or planning.
- >-
  PRIMARY MANDATE: re-prioritized the contribution to the three realized numbers the iteration-1 paper lacked (diagonal, operational
  wedge, and the goal's hard-required quantified hallucination-reduction vs raw LLM) -- directly answering the decisive 'no
  empirical results' critique (score 3/10).
- >-
  CIRCULARITY (review methodology-major): added a pre-registered generator!=scorer ablation (different-family scorer) and
  a decoy-vs-spontaneous-extractor-error tail-CDF match; entrapment re-framed as the non-circular, deterministically-built
  corroborator. A diagonal that needs generator=scorer is reported as a shared-model artifact.
- >-
  SCOPE (review scope-major): added a genre-faithful operational slice of ~15-30 genuine short professional legal/news/regulatory
  documents with upper-ontology typing, an LLM probabilistic-reasoning step at fuzzy unifications, and auditable trace-graphs,
  to land the goal's application-faithful hallucination-reduction headline that CLUTRR/Re-DocRED proxies cannot carry.
- >-
  POWER (review rigor-major): converted the diagonal's power analysis into a hard Phase-0 precondition (>=20 admissions and
  >=40 false admissions) with mandatory scaling of the regenerable CLUTRR confirmatory set, and an honestly reported certified-alpha
  grid (drop alphas whose 1/k floor is unreached).
- >-
  CLARITY (review clarity-minor): fixed the two inconsistent W_i definitions to one canonical knockoff+ signed-max statistic;
  reserved the per-pair signed difference for tail diagnostics only; specified figure content (the diagonal and the matched-recall
  wedge with CIs).
- >-
  RIGOR (review rigor-minor): explicitly separated the finite-sample FDR GUARANTEE (under the unprovable sign-flip property,
  tested by the diagonal) from the document-block bootstrap (realized-FDP CIs + dependence diagnostic, NOT a restored guarantee).
- >-
  NOVELTY (review novelty-minor): sharpened the boundary against conformal selection (Jin-Candes), multiple-testing hallucination
  detection (Li et al.), Mohri-Hashimoto conformal factuality, and COCOCO -- the label-free + intermediate-admission-boundary
  distinction is the novelty wedge.
relation_type: evolution
</hypothesis>

<all_artifacts>
FULL EVIDENCE BASE: All 9 research artifacts across all iterations.

--- Item 1 ---
id: art_XZyKy6QuwxrO
type: dataset
title: 'CLUTRR Crisp-Gold Calibration Anchor: Atomic + Multi-Hop Kinship Triples'
summary: |-
  Standardized, deterministic CLUTRR-derived dataset that serves as the CRISP-GOLD calibration anchor for the neuro-symbolic text-to-logic hallucination-control experiment. Source: CLUTRR v1 (Sinha et al., EMNLP 2019, arXiv:1908.06177), pooled TEST splits of configs gen_train234_test2to10 (1048 rows) and gen_train23_test2to10 (1146 rows), fetched as raw CSVs from the kliang5/CLUTRR_huggingface_dataset GitHub mirror and staged in temp/datasets/. CLUTRR is rule-based/templated, so its kinship gold is exact (no annotation noise) — exactly the property needed to host the realized-FDR-vs-alpha calibration diagonal.

  SCALE & SHAPE: ONE dataset group 'CLUTRR-v1-CrispGold-CalibrationAnchor' with 190 examples (row == one CLUTRR story). 150 confirmatory + 40 disjoint pilot (metadata_is_pilot). Stratified over chain length k=2..10 oversampling long chains (k>=4): confirmatory k-dist {k2:12,k3:15,k4:20,k5:20,k6:20,k7:18,k8:18,k9:15,k10:12}; pilot {k2:5,k3:5,k4:5,k5:5,k6:5,k7:5,k8:5,k9:3,k10:2}. Seed 20240617; selected ids recorded in top-level metadata for reproducibility.

  SCHEMA (aii-json exp_sel_data_out; validated, plus an independent 190/190 integrity pass): each example has STRING input and output (JSON-serialized; parse with json.loads) plus flat metadata_* fields. input keys: doc_id, document_text (clean prose, [Name] brackets stripped, native length never padded), document_text_bracketed (raw for entity-span provenance), entities[{name,gender,type='person',node_index}], query{head,tail}. output keys: atomic_facts[{head,relation,tail}] = the k directly-stated chain edges (the 'too clean' atomic family); multi_hop_facts[{head,relation,tail,derived_from,path_len,is_query_target}] = the k-1 proof_state-derived inferred relations incl. the query target (the error-dense 'populable' family the primary disconfirmation is pre-registered on); multi_hop_query_target{head,relation,tail}; kinship_edge_graph{nodes[{index,name,gender}],edges[{src,dst,relation}]}. All facts use the shared {head,relation,tail} triple structure with kinship relation strings (a Re-DocRED anchor could reuse the same structure with Wikidata relations).

  PER-EXAMPLE METADATA: metadata_fold ('k2'..'k10'), metadata_chain_length_k, metadata_difficulty_split ('short' k<=3 / 'long' k>=4), metadata_f_comb, metadata_task_name, metadata_source_config, metadata_source_split, metadata_clutrr_id, metadata_is_pilot, metadata_n_atomic_facts, metadata_n_multi_hop_facts, metadata_document_char_length, metadata_proof_state_raw, metadata_noisy_story, metadata_atomic_crosscheck ('match'), metadata_namemap_method ('genders_order'), metadata_genders_order_valid, metadata_relation_vocab_version ('clutrr_kinship'). Top-level metadata also carries relation_vocabulary (20 observed kinship relations), full k-distributions, and selected confirmatory/pilot id lists.

  CRISPNESS GUARANTEE: all gold is derived 100% from CLUTRR's own structured fields (proof_state leaf triples = atomic; proof_state dict keys = multi-hop) with NO homegrown rule reimplementation. Restricted to canonical simple-path chains (distinct entities==k+1, distinct edges, |atomic|==k, |multi_hop|==k-1, exactly one proof root equal to the query target, genders-order node->name map reproduces the proof_state atomic leaves); 1345 of 2191 pooled rows qualified, giving ample per-stratum supply.

  SELECTION: CLUTRR is THE chosen dataset (target_num_datasets=1). Secondary candidate ProofWriter (tasksource/proofwriter, kept in temp/datasets/ as backup) was excluded — it provides T/F/Unknown answers over rule/fact theories, not the kinship atomic+multi-hop triple gold this experiment is registered on. OUT OF SCOPE here (left to the experiment artifact): decoy/entrapment generation, LLM scoring, FDR/precision/recall, Prolog execution, transitive-closure enrichment. Files: data.py (uv run data.py), full_data_out.json (1.1MB, <100MB so no split), mini_data_out.json (3 ex), preview_data_out.json (3 ex, truncated). Reproducible via pinned pyproject.toml.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_MQN7mBg4AhvH/3_invention_loop/iter_1/gen_art/gen_art_dataset_1
out_expected_files:
- data.py
- full_data_out.json
- preview_data_out.json
- mini_data_out.json

--- Item 2 ---
id: art_Jcudmkugg1qT
type: dataset
title: >-
  Re-DocRED Anchor: 236-doc triple-schema corpus with entities, evidence & 4 CV folds
summary: |-
  Operational-anchor dataset standardized from Re-DocRED (Tan et al., 'Revisiting DocRED — Addressing the False Negative Problem in Relation Extraction', EMNLP 2022; HuggingFace tonytan48/Re-DocRED, MIT, 606 downloads, arXiv 2205.12696). THE single chosen dataset for the label-free FDR-gating / neuro-symbolic text→logic hypothesis.

  FORMAT: full_data_out.json follows the exp_sel_data_out contract: {metadata, datasets:[{dataset:'Re-DocRED', examples:[...]}]}. 236 examples = one Wikipedia document each, drawn from 4053 pooled train/dev/test docs. Each example is raw data only (NO candidates, decoys, scores, or FDR — those are the experiment's job).

  PER-EXAMPLE FIELDS: input = the reconstructed ~200-word document prose (deterministic detokenization, exact char offsets); output = JSON string of the gold (head,relation,tail) triples. metadata_* carries the rich structure: metadata_entities (full annotated inventory, 6 types, mention token spans + exact char_spans, canonical_name, n_mentions), metadata_gold_triples (shared canonical schema: head/tail id+name+type, relation_pid+relation_name, evidence_sent_ids, resolved evidence_text), metadata_sents (verbatim tokens, authoritative grounding), metadata_sent_char_offsets, and 17 metadata_features S5 GAP-regression inputs (num_words/chars/sents/entities/triples, relation & entity-type profiles, entity/mention/triple densities, frac_singleton_entities, frac_multi_evidence_triples, max_evidence_sentence_gap). Flags: metadata_fold (cluster_PER/ORG/LOC/MISC — primary dominant-entity-type folds for leave-one-cluster-out CV), metadata_kmeans_cluster (secondary k-means scheme), metadata_split_role + metadata_is_confirmatory/is_pilot/is_reserve, metadata_seed (20240617).

  BALANCE: 152 confirmatory / 36 pilot / 48 reserve, exactly balanced across the 4 folds (38/9/12 each), examples interleaved round-robin by fold; documents span the feature range so cross-document variance (the S5 precondition) is preserved (e.g. triple_density 0.38–14.75 across folds). Eligibility: 80≤num_words≤400, ≥4 entities, ≥5 triples. Confirmatory/pilot/reserve are mutually exclusive; every triple indexes a valid entity (verified).

  COMPANIONS: relation_schema.json (all 96 Wikidata P-ids with human-readable names AND descriptions, fetched live from the Wikidata API — the shared triple space every downstream system aligns to), entity_type_schema.json (6 types + glosses), dataset_meta.json (citation, URLs, counts, seed, cluster schemes, per-fold counts), row_schema.json (the custom JSON-Schema every row was validated against).

  GOLD CAVEAT (recorded in metadata): Re-DocRED has residual false negatives, so this dataset licenses ONLY relative operational comparisons at matched recall (precision, hallucinated-conclusion rate) — never an absolute realized-FDR diagonal (that role belongs to the separate CLUTRR anchor).

  REPRODUCIBILITY: pure-CPU data prep; `uv run data.py` regenerates everything deterministically from cached raw JSON (re-downloads from HF/GitHub if absent; relation names from Wikidata or cache). pyproject.toml pins all 13 dependency versions. full=11.7MB (<100MB, no split); all of full/mini/preview validate against exp_sel_data_out.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_MQN7mBg4AhvH/3_invention_loop/iter_1/gen_art/gen_art_dataset_2
out_expected_files:
- data.py
- full_data_out.json
- preview_data_out.json
- mini_data_out.json

--- Item 3 ---
id: art_SLUbUUr6Ul98
type: research
title: 'Spec Sheet: Label-Free FDR Gate at the LLM Text-to-Logic Admission Boundary'
summary: >-
  Consolidated, source-traceable implementation spec for the label-free decoy-competition FDR gate that admits LLM-extracted
  facts/bridges into a Prolog/symbolic layer. Provides, for each component, a verbatim formula (with equation number and source),
  a symbol glossary, a language-agnostic pseudo-procedure, and a recommended default. KEY RESULTS: (A) knockoff+ admission
  threshold T=min{t: (1+#{W_i<=-t})/(#{W_i>=t} v 1)<=alpha} (Barber-Candes eq 1.9, exact FDR via Thm 2; plain knockoff eq
  1.8 controls only modified FDR Thm 1); the minimum-estimable-FDR floor is 1/k, so certifying FDR<=alpha needs k>=ceil(1/alpha)
  admissions -> demonstrable alpha grid {0.05,0.1,0.2,0.3,0.5} maps to k-floors {20,10,5,4,2}. Rajchert-Keich prove the '+1'
  is generally necessary (t=1 optimal), so keep it; TDC-SB/TDC-UB (bandsfdp) are an optional tighter FDX bound. (B) Entrapment
  estimators verbatim from Wen et al. 2025: combined FDP=N_E(1+1/r)/(N_T+N_E) (upper bound, DEFAULT), paired (eq4, requires
  r=1, tighter), lower bound N_E/(N_T+N_E) (failure-only), and 'sample' N_E(1/r)/N_T which is INVALID (biased). r=#entrapment/#target;
  default r=1 paired. (C) Document-block (cluster) bootstrap B>=2000 for all FDP/FDR CIs (resample whole documents; Cameron-Gelbach-Miller
  anchor) — the CI used by the primary disconfirmation. (D) Sole validity condition = Barber-Candes Lemma 1 (null W signs
  are i.i.d. fair coins) = TDC equal-chance; two anti-conservative failure modes (within-doc correlation -> bootstrap; batched
  contrast effect -> isolated provenance-blinded order-randomized scoring) and the isolated-vs-batched discriminator. (E)
  Property-matched document-conditioned COUNTERFACTUAL decoys + non-entailment verification (DeepCoy principle; DOE 0.166->0.032/0.109->0.038);
  random type-matched swaps kept as the anti-conservative negative control. (F) Ranked label-free upper-tail elicitation shortlist:
  DINCO (primary, overconfidence-corrected), FactSelfCheck (fact-level), self-consistency/SelfCheckGPT, logprob/yes-no-token
  (if exposed), verbalized (overconfident floor); Phase-0 selects on tail-AUC>0.5 with CI + isolated~batched agreement. (G)
  Recommended model openai/gpt-4.1-nano ($0.10/$0.40 per M, logprobs+auto-caching, <$0.30 input); fallbacks gpt-4o-mini then
  a logprob-free cheap caching model; projected cost ~$1-3 << $10 cap. (H) Novelty confirmed: no prior work applies knockoff/target-decoy/entrapment
  FDR at a label-free LLM text->logic admission boundary (conformal factuality/selection are labeled and certify outputs).
  Includes a final Parameter Defaults table and runtime follow-ups (probe logprobs non-null; confirm cached_tokens>0).
workspace_path: >-
  /ai-inventor/aii_data/runs/run_MQN7mBg4AhvH/3_invention_loop/iter_1/gen_art/gen_art_research_1
out_expected_files:
- research_out.json

--- Item 4 ---
id: art_K6AE23HoGqe6
type: research
title: >-
  Spec: Text-to-FOL-to-Prolog Pipeline and the Fair Re-DocRED Operational Comparison
summary: >-
  Implementation-ready specification (verbatim prompt templates, on-disk data formats, exact library APIs, mapping rules,
  ASCII pipeline diagram, library table, and data-format cheat-sheets) for the extraction-to-Prolog neuro-symbolic pipeline
  and the fair matched-recall operational comparison of the decoy-gating hypothesis. Block A: LLM text->typed-FOL FACT/BRIDGE
  extraction with deliberate over-generation in LINC (NLTK/Prover9 FOL, <PREMISES>/<EVALUATE> tags) and Logic-LM (Predicates:::/Facts/Rules>>>/Query)
  style; controlled-functor fact()/bridge() on-disk forms; over-generation prompts (T=0.7, n=3, cap 20/doc) and the candidate-record
  JSON schema with worked CLUTRR and Re-DocRED examples. Block B: SWI-Prolog-from-Python execution (janus-swi RECOMMENDED
  with exact query_once/query/consult/apply_once API; pyswip fallback; swipl subprocess safety net) plus a vanilla solve/2
  proof-tree meta-interpreter extended so each leaf carries provenance + decoy_certificate (W_i,T,q) + entrapment_certificate
  (FDP-hat,r), exported to JSON and Graphviz DOT with a 2-hop example. Block C: offline WordNet hypernym argument typing into
  {PER,LOC,ORG,TIME,NUM,MISC} with exact synset anchors, reusing Re-DocRED gold NER, ConceptNet/DBpedia optional. Block D
  (load-bearing): the Re-DocRED JSON schema and official (title,r,h_idx,t_idx) triple-matching metric, plus ONE fixed claim-decomposition
  + relation-alignment (MiniLM top-8 shortlist -> fixed temp-0 LLM pick among 96 P-codes or NO_RELATION) + three-tier entity-linking
  procedure that maps neuro-symbolic/plain-threshold/CoT/RAG/conformal outputs identically into the (head, P-code, tail) space,
  with a per-system matched-recall score sweep, a hallucinated-conclusion-rate definition for multi-hop deductions, and document-block-bootstrap
  CIs. Block E: RAG (BM25) and CoT extraction prompts, the plain zero-label confidence-threshold gate (primary foil), and
  the verbatim Mohri-Hashimoto conformal back-off Algorithm 1 plus its reusable sayless.py implementation (BREAKDOWN_PROMPT,
  frequency+gpt scoring, ceil-quantile calibration), explicitly positioned as the LABELED reference the label-free decoy wedge
  improves on. The decoy-gating core states the knockoff statistic and the knockoff+ data-dependent FDR threshold. Ten design
  decisions are resolved with fallbacks; a shared sub-$0.30/M OpenRouter model with prompt caching is recommended. 26 primary
  sources (papers + GitHub repos) cited; high confidence except the full 96-row rel_info.json and model-logprob availability.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_MQN7mBg4AhvH/3_invention_loop/iter_1/gen_art/gen_art_research_2
out_expected_files:
- research_out.json

--- Item 5 ---
id: art_ikjFm_faAe0x
type: experiment
title: 'CLUTRR Label-Free Knockoff+ FDR Gate: Calibration Diagonal, Power & Entrapment'
summary: >-
  This artifact executes the end-to-end label-free decoy-competition (knockoff+) FDR gate on the crisp-gold CLUTRR kinship
  anchor (190 docs: 40 pilot + 150 confirmatory), testing whether a label-free admission gate can control the false-discovery
  rate of LLM-extracted facts entering a symbolic layer. Pipeline (openai/gpt-4.1-nano via OpenRouter, isolated provenance-blinded
  scoring, persistent on-disk cache, $0.42 total spend << $10 cap, 1540 scored candidates): over-generation extraction (atomic
  + multi-hop bridge families), property-matched counterfactual decoys with non-entailment verification, deterministic entrapment
  items (r=1), and four scoring elicitations. The Phase-0 pilot selected the scorer by upper-tail AUC (verbalized, tail-AUC
  0.86 with bootstrap CI excluding 0.5, so the S0 separation precondition PASSED) and set alpha*=0.3; populability far exceeds
  the N_false_min=40 floor (bridge 175, atomic 118, pooled 293 genuine false candidates), so the diagonal is TESTABLE rather
  than untestable. Method vs baselines (implemented side-by-side in one pipeline to remove confounds): (1) OUR knockoff+ gate
  with canonical statistic W_i=sign(Z_i-Z~_i)*max(Z_i,Z~_i) and the Barber-Candes +1 data-dependent threshold; (2) PLAIN confidence-threshold
  baseline (decoy-free primary foil); (3) SWAP-decoy negative control. HEADLINE bridge diagonal (realized FDR vs target alpha,
  document-block bootstrap B=2000 CIs): the knockoff+ gate is CONSERVATIVELY calibrated, with realized FDR ~0.21 at alpha=0.2/0.3
  (n_admitted=56, 12 false) and ~0.25 at alpha=0.5 (n_admitted=113), staying at or below alpha+tau across the certified grid,
  whereas the plain confidence baseline is ANTI-CONSERVATIVE, with realized FDR rising 0.34->0.55 as alpha loosens. The single
  pre-registered primary disconfirmation at alpha*=0.3 returns NOT_DISCONFIRMED (realized 0.214, CI [0.12,0.33] not entirely
  above alpha*). Independent deterministic entrapment corroboration at alpha* gives N_T=56, N_E=10, FDP_combined=FDP_paired=0.30,
  agreeing with the gold realized FDR (3-way check). Overall calibration_verdict=CONFIRMED. Outputs: method.py (orchestrator)
  plus fdr_core.py, pipeline.py, llm_client.py, tests.py, and method_out.json (validates against exp_gen_sol_out: 1540 figure-ready
  candidate rows carrying per-item W, z_real, z_cf/z_swap/z_entrapment, gold label, predict_our_method and predict_baseline;
  top-level metadata holds the full per-family diagonal arrays, power table, populability counts, decoy-control tail diagnostics,
  entrapment estimators, and the disconfirmation verdict). full/mini/preview variants emitted and all four files are <100MB
  (no split needed). Scope: tests claim rows S0 (precondition) + S2 (diagonal) + S3 (entrapment) + power; deliberately excludes
  the Re-DocRED wedge, Prolog execution/trace-graphs, and the generator!=scorer ablation (separate experiments).
workspace_path: >-
  /ai-inventor/aii_data/runs/run_MQN7mBg4AhvH/3_invention_loop/iter_2/gen_art/gen_art_experiment_1
out_expected_files:
- method.py
- full_method_out.json
- mini_method_out.json
- preview_method_out.json

--- Item 6 ---
id: art_Inu52CyA49Ys
type: experiment
title: Label-free decoy-competition FDR gate validated on CLUTRR crisp gold
summary: |-
  Executable validation of a LABEL-FREE decoy-competition (knockoff+) FDR gate that admits LLM-extracted kinship facts into a symbolic layer without gold labels. Each extracted 'real' fact competes against a property-matched COUNTERFACTUAL decoy (same ordered entity pair, plausible-but-wrong relation, verified non-entailed against gold) plus a random type-matched swap control; a label-free confidence elicitation scores both in isolated, provenance-blinded, identical-template calls; canonical signed-max W_i + Barber-Candes knockoff+ threshold (eq 1.9) turn decoy wins into an FDR certificate. Run on the 190-doc CLUTRR crisp-gold anchor (40 pilot + 150 confirmatory) producing 1937 reals (633 TRUE, 1304 spontaneous FALSE extractor errors, 0 undecidable), each with a counterfactual decoy and a swap, scored under TWO elicitations (gpt-4.1-nano logprob softmax; K=5 self-consistency) plus a 4-config Generator!=Scorer ablation using a cross-family scorer (mistralai/ministral-8b-2512).

  HEADLINE (the gate's validity is ELICITATION-DEPENDENT): (1) S1 decoy signature - under single-token logprob confidence the LLM is overconfident in its OWN spontaneous errors, so counterfactual decoys are strongly anti-conservative (tail win-rate 0.34, 95% CI [0.32,0.37], KS p<1e-24); under K=5 self-consistency the decoys are EXCHANGEABLE (win-rate 0.482, CI [0.42,0.55] covers 0.5, KS p=0.48). The random-swap negative control is flagged anti-conservative under logprob (and by the offline synthetic self-test), validating diagnostic sensitivity. (2) Spontaneous-error tail match (the crux) - under self-consistency the counterfactual-decoy score distribution matches the genuine spontaneous-error distribution in the admission tail (top-25%/50% KS p=0.33/0.19, fail-to-reject) and differs sharply from the true-positive distribution (KS p~1e-40); figure-ready overlaid CDFs exported. (3) Generator!=Scorer de-circularization - exchangeability holds for ALL four (G,S) configs incl. G!=S (win-rate CIs cover 0.5; labeled-slice realized FDR 0.0 at alpha=0.2): verdict ROBUST, not a shared-model artifact. (4) Method vs purely-neural BASELINE - against crisp gold the decoy-FDR gate controls realized FDR <= nominal where it certifies (0.417 <= 0.5; conservative/zero-admit at stricter alpha), whereas the raw-confidence baseline admits 254-1758 facts at 45-65% realized FDR - the quantified hallucination problem the gate prevents.

  All p-values are document-block (cluster) bootstrap (B=2000) and Benjamini-Hochberg corrected (q=0.05; 42 tests, 27 reject). Cost: final cache-warm run $0.47, ~$1.05 total across gradual-scaling runs, hard cap $10 never neared (exact per-call USD from OpenRouter usage.cost; disk cache for free resumes). HONEST LIMITATIONS: knockoff+ is conservative on this signal (certifies admissions only at alpha=0.5 on 190 docs); the full-distribution crux match is borderline (a tail phenomenon); gpt-4.1-nano's genuine extraction is error-prone (atomic precision ~0.50, multi-hop accuracy ~0.20) - these real errors are the experimental signal, not a confound; self-consistency reduces sensitivity to the swap control.

  OUTPUTS for the paper writer: method_out.json (schema exp_gen_sol_out, validated) carries metadata.headline_finding/headline_verdict, elicitation_comparison, s1_decoy_signature_by_elicitation, spontaneous_error_match_by_elicitation (with figure_cdfs), generator_ne_scorer (verdict + validity_region_statement), baseline_vs_method_fdr_by_elicitation, bh_correction, extraction_quality; the 1937 examples each hold per-elicitation real/decoy/swap scores, W_i, and admission predictions. Companion files: fdr_stats.py (unit-tested statistical core), llm_client.py (async cached cost-capped OpenRouter client), make_figures.py + figures/fig1-4 (decoy signature, crux CDFs, FDR calibration, ablation), README.md, pinned pyproject.toml.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_MQN7mBg4AhvH/3_invention_loop/iter_2/gen_art/gen_art_experiment_2
out_expected_files:
- method.py
- full_method_out.json
- mini_method_out.json
- preview_method_out.json

--- Item 7 ---
id: art_sHNuY68d4-Wh
type: experiment
title: >-
  Re-DocRED Operational Wedge: Decoy-Gating vs Plain Confidence Threshold at Matched Recall
summary: >-
  Operational-wedge experiment (S4) on the Re-DocRED anchor (152 confirmatory + 36 pilot-calibration Wikipedia documents).
  It answers a single load-bearing question for the label-free FDR-gating / neuro-symbolic text->logic hypothesis: at MATCHED
  RECALL, does ranking LLM-extracted atomic facts by the knockoff+ decoy-competition statistic W_i = max(Z_i, Z~_i)*sign(Z_i
  - Z~_i) admit a higher-precision, lower-hallucination set than ranking by the raw confidence Z_i (the PLAIN zero-label threshold
  foil)? method.py implements both systems side-by-side over an IDENTICAL candidate+alignment pool (only the gate differs),
  plus CoT, BM25-RAG, and a labeled Mohri-Hashimoto conformal back-off reference. All five systems are mapped into the SAME
  (title, P-code, head_id, tail_id) triple space by ONE fixed aligner (MiniLM top-8 shortlist + temp-0 LLM relation pick +
  three-tier entity linking) and scored by the official tuple-matching metric against human gold. Graded scoring uses the
  logprob yes-token probability (verbalized [0,1] fallback); decoys are property-matched DeepCoy-style counterfactuals that
  recombine the document's OWN entities into a non-entailed pairing (verified, regenerated up to 3x). method_out.json (schema
  exp_gen_sol_out) provides: figure-ready per-system PR curves; the matched-recall precision wedge delta(METHOD-PLAIN) across
  a recall grid with document-block bootstrap CIs (B=2000) and BH correction; multi-hop hallucinated-conclusion rate from
  a fixed pure-Python Datalog forward-chainer (rules listed); knockoff+ operating points over alpha in {0.05,0.1,0.2,0.3,0.5}
  with the 1/k floor; labeled conformal operating points (n_calibration_labels reported; the method uses 0); the mandatory
  alignment-error confound check (aligner self-error probe ~0.98 relation / ~0.99 entity-link on gold surface forms, plus
  perturbation sensitivity to uniform P-code noise 5/10/20%, an embedding-only aligner, and a stricter entity-link floor);
  decoy contamination rate; and a pre-registered verdict. Only RELATIVE comparisons are asserted (Re-DocRED residual false
  negatives depress recall and inflate hallucination counts equally for all systems). Result: a clean pre-registered OPERATIONAL
  DISCONFIRMATION -- with a well-calibrated logprob scorer the decoy competition does not beat (and is marginally worse than)
  plain thresholding at matched recall, i.e. 'thresholding-is-enough'. Pure-CPU, model openai/gpt-4.1-nano via OpenRouter,
  exact per-call cost metering with soft cap ~$3 and hard stop $10. Downstream (GEN_PAPER_TEXT) can use the PR/wedge/hallucination
  arrays and CIs directly as figures and the verdict + aligner-robustness numbers as the evidentiary core.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_MQN7mBg4AhvH/3_invention_loop/iter_2/gen_art/gen_art_experiment_3
out_expected_files:
- method.py
- full_method_out.json
- mini_method_out.json
- preview_method_out.json

--- Item 8 ---
id: art_UBTwyePql8NQ
type: dataset
title: >-
  Application Anchor: 24 short legal/news/regulatory docs, triple gold + provenance
summary: |-
  The APPLICATION ANCHOR: one merged, schema-validated dataset (full_data_out.json, exp_sel_data_out schema) of 24 genuine, professionally-written short documents (native char_length 1239-3474, mean 2372), perfectly balanced 8 legal / 8 news / 8 regulatory, standardized to the SAME (head, relation, tail) triple space and coarse {PER,LOC,ORG,TIME,NUM,MISC} entity typing as the CLUTRR and Re-DocRED anchors (dependency research_out.json, Block C WordNet anchors). It is the genre-faithful real-document slice the next-iteration text->FOL->Prolog neuro-symbolic atomic-fact-extraction & hallucination-control experiment depends on.

  PER EXAMPLE (each document = ONE example): input is a JSON string {doc_id, document_text (verbatim UTF-8), genre, source, char_length, entities:[{name, type in the 6-type set, char_span:[s,e]}]}; output is a JSON string {gold_atomic_facts:[{head, relation, tail, provenance_char_span:[s,e]}]}. Flat metadata: metadata_fold=genre (leave-one-genre-out), metadata_gold_quality (crisp|silver), metadata_source, metadata_license, metadata_relation_vocab, metadata_char_length, metadata_num_facts, metadata_num_entities, metadata_entity_types_fine (spaCy fine NER labels), plus per-source fields. datasets[] is grouped by SOURCE CORPUS: CUAD(8), Wikinews(8), GDPR(5), eCFR(3).

  GOLD (140 facts total, 3-15 per doc). LEGAL = CUAD v1 (CC BY 4.0), CRISP: triples mapped deterministically from human-annotated clause spans (has_title, has_party, agreement_date, effective_date, expiration_date, governed_by, renewal_term, liability_cap, contains_* clause types). NEWS = Wikinews (CC BY 2.5), SILVER: deterministic spaCy dependency SVO + 5W (action-verb predicates, occurred_on, affiliated_with). REGULATORY = GDPR/Reg(EU)2016/679 via EUR-Lex free reuse + eCFR (US public domain), SILVER: structural regex (has_title, grants_right, obligates, has_exception, cross_references, defined_as, requires). NO LLM is used anywhere in gold construction (preserves non-circularity for the next-iteration hallucination experiment); entity spans/types come only from offline spaCy NER + NLTK WordNet.

  GUARANTEES. Every entity char_span and fact provenance_char_span re-verified against document_text (946/946 entity spans exact; value-tail facts have tail as a substring of the provenance span; clause/label facts carry the annotated clause as evidence). 93.6% of fact endpoints link to the typed entities[] layer. Licenses are all free (CC BY 4.0 / CC BY 2.5 / EUR-Lex reuse / US public domain). Deterministic regeneration (seed 42, pinned tool versions) from the cached raw/ snapshot with no network: `python data.py` (or regenerate.sh) reproduces byte-identical output; build/verify_dataset.py re-checks all invariants.

  DATASET SELECTION: 4 source corpora chosen from 7 evaluated. Excluded REDFM (CC BY-SA-NC, NonCommercial), ContractNLI-HF (CC BY-NC-SA, NonCommercial), WebRED (free but sentence-level, not genre-faithful), LDC ACE/TACRED (restricted). Count is 4 (not 6) because the plan's hard free-license + genre-faithfulness gates legitimately exclude the rest while the binding deliverable (~24 balanced docs across 3 genres, crisp where possible) is fully met. Honest limitation: legal gold is crisp; news and regulatory gold are silver (rule/structure curation, high precision, partial recall) — carried per row by gold_quality. Variants: full_data_out.json (24 examples, all 4 groups), mini_data_out.json (3 per group = 12), preview_data_out.json (12, strings truncated to 200). full_data_out.json is 209K, far under the 100MB limit (no split). dataset_meta.json + schema/row_payload_schema.json + README.md + pyproject.toml (61 pinned deps) accompany it.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_MQN7mBg4AhvH/3_invention_loop/iter_2/gen_art/gen_art_dataset_1
out_expected_files:
- data.py
- full_data_out.json
- preview_data_out.json
- mini_data_out.json

--- Item 9 ---
id: art_Cr6L9JpoewZi
type: research
title: >-
  Novelty-Delta, Upper-Ontology Grounding Recipe, and LLM-as-Probabilistic-Reasoner Design
summary: >-
  Source-traceable research closing three iteration-1 reviewer gaps for the decoy-gated neuro-symbolic text-to-logic pipeline,
  extending (not contradicting) Spec A (FDR gate) and Spec B (pipeline/typing/trace-graph). PART A: a five-dimension NOVELTY-DELTA
  table pinning six nearest conformal/FDR neighbors - Jin-Candes conformal selection [1], Li-Magesh-Veeravalli multiple-testing
  hallucination detection [2], COCOCO neuro-symbolic conformal sets [3], Bashari conformal-e-value novelty detection [4],
  Marandon/Blanchard conformal link-prediction FDR [5,6], Mohri-Hashimoto conformal factuality [7] - on {label requirement,
  unit certified, exchangeability mechanism, decoy?, FDR-vs-coverage}; all are LABELED and certify a model OUTPUT under assumed
  exchangeability, whereas OURS is label-free, certifies the INTERMEDIATE text->logic admission, uses engineered+tested decoy
  sign-flip, and controls FDR. Includes a paste-ready one-sentence delta, a 'not just conformal selection' rebuttal, and an
  honest adversarial result (no 2025-2026 preprint pre-empts the construction). PART B: OpenCyc honestly reported as discontinued
  (March 2017 [8,9], third-party-mirror-only [10]) and ResearchCyc as license-gated [8]; a concrete offline-first two-layer
  argument-typing recipe - WordNet hypernyms [11] anchored to SUMO upper-ontology classes via WordNetMappings30 (verified
  line: person -> &%Human=) [12,13,14], plus Wikidata P31/P279* [17] or offline YAGO 4.5 [15,16] instance typing, loadable
  with owlready2/SPARQLWrapper [18] - and a loss/sufficiency/descope-vs-defer justification arguing why typing-only usage
  cannot break the FDR guarantee (unlike ontology-constraint filtering). PART C: a concrete LLM-as-probabilistic-reasoner
  design - ProbLog primary (verified API: get_evaluatable().create_from(PrologString).evaluate() -> {Term:prob}; p::fact.;
  annotated disjunctions; query/evidence; explain/MPE proofs [19,20,21]; LFI weight learning [22]; aProbLog semirings [23];
  DeepProbLog neural-predicate precedent [24]) with Bousi~Prolog/FASILL as the fuzzy-unification alternative [25,26,27,28];
  a certificate->probabilistic-weight mapping table (p_i=calibrate(Z_i); gate-consistent shrinkage (1-alpha_hat)*p_i [default]
  or per-pair W_i margin weight; entrapment FDP-hat as consistency prior; full cert kept at the leaf); a probabilistic trace-graph
  export (reuse Spec-B JSON/Graphviz-DOT, add a 'prob' attribute per node/edge, marginal per derived node, certificate per
  leaf; janus-swi solve/2 fallback for the proof DAG); and the exact deterministic->probabilistic upgrade swap (janus query_once
  -> problog get_evaluatable/evaluate). Deliverables: research_out.json + research_report.md with 30 primary sources, tables,
  recipes, exact APIs, and a positioning note mapping each part to the named reviewer gaps.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_MQN7mBg4AhvH/3_invention_loop/iter_2/gen_art/gen_art_research_1
out_expected_files:
- research_out.json
</all_artifacts>

<new_artifacts_this_iteration>
NEW THIS ITERATION: These 5 artifacts were created to address the reviewer
feedback. Their findings should be the primary basis for your revisions.

title: 'CLUTRR Label-Free Knockoff+ FDR Gate: Calibration Diagonal, Power & Entrapment'
type: experiment
summary: >-
  This artifact executes the end-to-end label-free decoy-competition (knockoff+) FDR gate on the crisp-gold CLUTRR kinship
  anchor (190 docs: 40 pilot + 150 confirmatory), testing whether a label-free admission gate can control the false-discovery
  rate of LLM-extracted facts entering a symbolic layer. Pipeline (openai/gpt-4.1-nano via OpenRouter, isolated provenance-blinded
  scoring, persistent on-disk cache, $0.42 total spend << $10 cap, 1540 scored candidates): over-generation extraction (atomic
  + multi-hop bridge families), property-matched counterfactual decoys with non-entailment verification, deterministic entrapment
  items (r=1), and four scoring elicitations. The Phase-0 pilot selected the scorer by upper-tail AUC (verbalized, tail-AUC
  0.86 with bootstrap CI excluding 0.5, so the S0 separation precondition PASSED) and set alpha*=0.3; populability far exceeds
  the N_false_min=40 floor (bridge 175, atomic 118, pooled 293 genuine false candidates), so the diagonal is TESTABLE rather
  than untestable. Method vs baselines (implemented side-by-side in one pipeline to remove confounds): (1) OUR knockoff+ gate
  with canonical statistic W_i=sign(Z_i-Z~_i)*max(Z_i,Z~_i) and the Barber-Candes +1 data-dependent threshold; (2) PLAIN confidence-threshold
  baseline (decoy-free primary foil); (3) SWAP-decoy negative control. HEADLINE bridge diagonal (realized FDR vs target alpha,
  document-block bootstrap B=2000 CIs): the knockoff+ gate is CONSERVATIVELY calibrated, with realized FDR ~0.21 at alpha=0.2/0.3
  (n_admitted=56, 12 false) and ~0.25 at alpha=0.5 (n_admitted=113), staying at or below alpha+tau across the certified grid,
  whereas the plain confidence baseline is ANTI-CONSERVATIVE, with realized FDR rising 0.34->0.55 as alpha loosens. The single
  pre-registered primary disconfirmation at alpha*=0.3 returns NOT_DISCONFIRMED (realized 0.214, CI [0.12,0.33] not entirely
  above alpha*). Independent deterministic entrapment corroboration at alpha* gives N_T=56, N_E=10, FDP_combined=FDP_paired=0.30,
  agreeing with the gold realized FDR (3-way check). Overall calibration_verdict=CONFIRMED. Outputs: method.py (orchestrator)
  plus fdr_core.py, pipeline.py, llm_client.py, tests.py, and method_out.json (validates against exp_gen_sol_out: 1540 figure-ready
  candidate rows carrying per-item W, z_real, z_cf/z_swap/z_entrapment, gold label, predict_our_method and predict_baseline;
  top-level metadata holds the full per-family diagonal arrays, power table, populability counts, decoy-control tail diagnostics,
  entrapment estimators, and the disconfirmation verdict). full/mini/preview variants emitted and all four files are <100MB
  (no split needed). Scope: tests claim rows S0 (precondition) + S2 (diagonal) + S3 (entrapment) + power; deliberately excludes
  the Re-DocRED wedge, Prolog execution/trace-graphs, and the generator!=scorer ablation (separate experiments).
id: art_ikjFm_faAe0x

title: Label-free decoy-competition FDR gate validated on CLUTRR crisp gold
type: experiment
summary: |-
  Executable validation of a LABEL-FREE decoy-competition (knockoff+) FDR gate that admits LLM-extracted kinship facts into a symbolic layer without gold labels. Each extracted 'real' fact competes against a property-matched COUNTERFACTUAL decoy (same ordered entity pair, plausible-but-wrong relation, verified non-entailed against gold) plus a random type-matched swap control; a label-free confidence elicitation scores both in isolated, provenance-blinded, identical-template calls; canonical signed-max W_i + Barber-Candes knockoff+ threshold (eq 1.9) turn decoy wins into an FDR certificate. Run on the 190-doc CLUTRR crisp-gold anchor (40 pilot + 150 confirmatory) producing 1937 reals (633 TRUE, 1304 spontaneous FALSE extractor errors, 0 undecidable), each with a counterfactual decoy and a swap, scored under TWO elicitations (gpt-4.1-nano logprob softmax; K=5 self-consistency) plus a 4-config Generator!=Scorer ablation using a cross-family scorer (mistralai/ministral-8b-2512).

  HEADLINE (the gate's validity is ELICITATION-DEPENDENT): (1) S1 decoy signature - under single-token logprob confidence the LLM is overconfident in its OWN spontaneous errors, so counterfactual decoys are strongly anti-conservative (tail win-rate 0.34, 95% CI [0.32,0.37], KS p<1e-24); under K=5 self-consistency the decoys are EXCHANGEABLE (win-rate 0.482, CI [0.42,0.55] covers 0.5, KS p=0.48). The random-swap negative control is flagged anti-conservative under logprob (and by the offline synthetic self-test), validating diagnostic sensitivity. (2) Spontaneous-error tail match (the crux) - under self-consistency the counterfactual-decoy score distribution matches the genuine spontaneous-error distribution in the admission tail (top-25%/50% KS p=0.33/0.19, fail-to-reject) and differs sharply from the true-positive distribution (KS p~1e-40); figure-ready overlaid CDFs exported. (3) Generator!=Scorer de-circularization - exchangeability holds for ALL four (G,S) configs incl. G!=S (win-rate CIs cover 0.5; labeled-slice realized FDR 0.0 at alpha=0.2): verdict ROBUST, not a shared-model artifact. (4) Method vs purely-neural BASELINE - against crisp gold the decoy-FDR gate controls realized FDR <= nominal where it certifies (0.417 <= 0.5; conservative/zero-admit at stricter alpha), whereas the raw-confidence baseline admits 254-1758 facts at 45-65% realized FDR - the quantified hallucination problem the gate prevents.

  All p-values are document-block (cluster) bootstrap (B=2000) and Benjamini-Hochberg corrected (q=0.05; 42 tests, 27 reject). Cost: final cache-warm run $0.47, ~$1.05 total across gradual-scaling runs, hard cap $10 never neared (exact per-call USD from OpenRouter usage.cost; disk cache for free resumes). HONEST LIMITATIONS: knockoff+ is conservative on this signal (certifies admissions only at alpha=0.5 on 190 docs); the full-distribution crux match is borderline (a tail phenomenon); gpt-4.1-nano's genuine extraction is error-prone (atomic precision ~0.50, multi-hop accuracy ~0.20) - these real errors are the experimental signal, not a confound; self-consistency reduces sensitivity to the swap control.

  OUTPUTS for the paper writer: method_out.json (schema exp_gen_sol_out, validated) carries metadata.headline_finding/headline_verdict, elicitation_comparison, s1_decoy_signature_by_elicitation, spontaneous_error_match_by_elicitation (with figure_cdfs), generator_ne_scorer (verdict + validity_region_statement), baseline_vs_method_fdr_by_elicitation, bh_correction, extraction_quality; the 1937 examples each hold per-elicitation real/decoy/swap scores, W_i, and admission predictions. Companion files: fdr_stats.py (unit-tested statistical core), llm_client.py (async cached cost-capped OpenRouter client), make_figures.py + figures/fig1-4 (decoy signature, crux CDFs, FDR calibration, ablation), README.md, pinned pyproject.toml.
id: art_Inu52CyA49Ys

title: >-
  Re-DocRED Operational Wedge: Decoy-Gating vs Plain Confidence Threshold at Matched Recall
type: experiment
summary: >-
  Operational-wedge experiment (S4) on the Re-DocRED anchor (152 confirmatory + 36 pilot-calibration Wikipedia documents).
  It answers a single load-bearing question for the label-free FDR-gating / neuro-symbolic text->logic hypothesis: at MATCHED
  RECALL, does ranking LLM-extracted atomic facts by the knockoff+ decoy-competition statistic W_i = max(Z_i, Z~_i)*sign(Z_i
  - Z~_i) admit a higher-precision, lower-hallucination set than ranking by the raw confidence Z_i (the PLAIN zero-label threshold
  foil)? method.py implements both systems side-by-side over an IDENTICAL candidate+alignment pool (only the gate differs),
  plus CoT, BM25-RAG, and a labeled Mohri-Hashimoto conformal back-off reference. All five systems are mapped into the SAME
  (title, P-code, head_id, tail_id) triple space by ONE fixed aligner (MiniLM top-8 shortlist + temp-0 LLM relation pick +
  three-tier entity linking) and scored by the official tuple-matching metric against human gold. Graded scoring uses the
  logprob yes-token probability (verbalized [0,1] fallback); decoys are property-matched DeepCoy-style counterfactuals that
  recombine the document's OWN entities into a non-entailed pairing (verified, regenerated up to 3x). method_out.json (schema
  exp_gen_sol_out) provides: figure-ready per-system PR curves; the matched-recall precision wedge delta(METHOD-PLAIN) across
  a recall grid with document-block bootstrap CIs (B=2000) and BH correction; multi-hop hallucinated-conclusion rate from
  a fixed pure-Python Datalog forward-chainer (rules listed); knockoff+ operating points over alpha in {0.05,0.1,0.2,0.3,0.5}
  with the 1/k floor; labeled conformal operating points (n_calibration_labels reported; the method uses 0); the mandatory
  alignment-error confound check (aligner self-error probe ~0.98 relation / ~0.99 entity-link on gold surface forms, plus
  perturbation sensitivity to uniform P-code noise 5/10/20%, an embedding-only aligner, and a stricter entity-link floor);
  decoy contamination rate; and a pre-registered verdict. Only RELATIVE comparisons are asserted (Re-DocRED residual false
  negatives depress recall and inflate hallucination counts equally for all systems). Result: a clean pre-registered OPERATIONAL
  DISCONFIRMATION -- with a well-calibrated logprob scorer the decoy competition does not beat (and is marginally worse than)
  plain thresholding at matched recall, i.e. 'thresholding-is-enough'. Pure-CPU, model openai/gpt-4.1-nano via OpenRouter,
  exact per-call cost metering with soft cap ~$3 and hard stop $10. Downstream (GEN_PAPER_TEXT) can use the PR/wedge/hallucination
  arrays and CIs directly as figures and the verdict + aligner-robustness numbers as the evidentiary core.
id: art_sHNuY68d4-Wh

title: >-
  Application Anchor: 24 short legal/news/regulatory docs, triple gold + provenance
type: dataset
summary: |-
  The APPLICATION ANCHOR: one merged, schema-validated dataset (full_data_out.json, exp_sel_data_out schema) of 24 genuine, professionally-written short documents (native char_length 1239-3474, mean 2372), perfectly balanced 8 legal / 8 news / 8 regulatory, standardized to the SAME (head, relation, tail) triple space and coarse {PER,LOC,ORG,TIME,NUM,MISC} entity typing as the CLUTRR and Re-DocRED anchors (dependency research_out.json, Block C WordNet anchors). It is the genre-faithful real-document slice the next-iteration text->FOL->Prolog neuro-symbolic atomic-fact-extraction & hallucination-control experiment depends on.

  PER EXAMPLE (each document = ONE example): input is a JSON string {doc_id, document_text (verbatim UTF-8), genre, source, char_length, entities:[{name, type in the 6-type set, char_span:[s,e]}]}; output is a JSON string {gold_atomic_facts:[{head, relation, tail, provenance_char_span:[s,e]}]}. Flat metadata: metadata_fold=genre (leave-one-genre-out), metadata_gold_quality (crisp|silver), metadata_source, metadata_license, metadata_relation_vocab, metadata_char_length, metadata_num_facts, metadata_num_entities, metadata_entity_types_fine (spaCy fine NER labels), plus per-source fields. datasets[] is grouped by SOURCE CORPUS: CUAD(8), Wikinews(8), GDPR(5), eCFR(3).

  GOLD (140 facts total, 3-15 per doc). LEGAL = CUAD v1 (CC BY 4.0), CRISP: triples mapped deterministically from human-annotated clause spans (has_title, has_party, agreement_date, effective_date, expiration_date, governed_by, renewal_term, liability_cap, contains_* clause types). NEWS = Wikinews (CC BY 2.5), SILVER: deterministic spaCy dependency SVO + 5W (action-verb predicates, occurred_on, affiliated_with). REGULATORY = GDPR/Reg(EU)2016/679 via EUR-Lex free reuse + eCFR (US public domain), SILVER: structural regex (has_title, grants_right, obligates, has_exception, cross_references, defined_as, requires). NO LLM is used anywhere in gold construction (preserves non-circularity for the next-iteration hallucination experiment); entity spans/types come only from offline spaCy NER + NLTK WordNet.

  GUARANTEES. Every entity char_span and fact provenance_char_span re-verified against document_text (946/946 entity spans exact; value-tail facts have tail as a substring of the provenance span; clause/label facts carry the annotated clause as evidence). 93.6% of fact endpoints link to the typed entities[] layer. Licenses are all free (CC BY 4.0 / CC BY 2.5 / EUR-Lex reuse / US public domain). Deterministic regeneration (seed 42, pinned tool versions) from the cached raw/ snapshot with no network: `python data.py` (or regenerate.sh) reproduces byte-identical output; build/verify_dataset.py re-checks all invariants.

  DATASET SELECTION: 4 source corpora chosen from 7 evaluated. Excluded REDFM (CC BY-SA-NC, NonCommercial), ContractNLI-HF (CC BY-NC-SA, NonCommercial), WebRED (free but sentence-level, not genre-faithful), LDC ACE/TACRED (restricted). Count is 4 (not 6) because the plan's hard free-license + genre-faithfulness gates legitimately exclude the rest while the binding deliverable (~24 balanced docs across 3 genres, crisp where possible) is fully met. Honest limitation: legal gold is crisp; news and regulatory gold are silver (rule/structure curation, high precision, partial recall) — carried per row by gold_quality. Variants: full_data_out.json (24 examples, all 4 groups), mini_data_out.json (3 per group = 12), preview_data_out.json (12, strings truncated to 200). full_data_out.json is 209K, far under the 100MB limit (no split). dataset_meta.json + schema/row_payload_schema.json + README.md + pyproject.toml (61 pinned deps) accompany it.
id: art_UBTwyePql8NQ

title: >-
  Novelty-Delta, Upper-Ontology Grounding Recipe, and LLM-as-Probabilistic-Reasoner Design
type: research
summary: >-
  Source-traceable research closing three iteration-1 reviewer gaps for the decoy-gated neuro-symbolic text-to-logic pipeline,
  extending (not contradicting) Spec A (FDR gate) and Spec B (pipeline/typing/trace-graph). PART A: a five-dimension NOVELTY-DELTA
  table pinning six nearest conformal/FDR neighbors - Jin-Candes conformal selection [1], Li-Magesh-Veeravalli multiple-testing
  hallucination detection [2], COCOCO neuro-symbolic conformal sets [3], Bashari conformal-e-value novelty detection [4],
  Marandon/Blanchard conformal link-prediction FDR [5,6], Mohri-Hashimoto conformal factuality [7] - on {label requirement,
  unit certified, exchangeability mechanism, decoy?, FDR-vs-coverage}; all are LABELED and certify a model OUTPUT under assumed
  exchangeability, whereas OURS is label-free, certifies the INTERMEDIATE text->logic admission, uses engineered+tested decoy
  sign-flip, and controls FDR. Includes a paste-ready one-sentence delta, a 'not just conformal selection' rebuttal, and an
  honest adversarial result (no 2025-2026 preprint pre-empts the construction). PART B: OpenCyc honestly reported as discontinued
  (March 2017 [8,9], third-party-mirror-only [10]) and ResearchCyc as license-gated [8]; a concrete offline-first two-layer
  argument-typing recipe - WordNet hypernyms [11] anchored to SUMO upper-ontology classes via WordNetMappings30 (verified
  line: person -> &%Human=) [12,13,14], plus Wikidata P31/P279* [17] or offline YAGO 4.5 [15,16] instance typing, loadable
  with owlready2/SPARQLWrapper [18] - and a loss/sufficiency/descope-vs-defer justification arguing why typing-only usage
  cannot break the FDR guarantee (unlike ontology-constraint filtering). PART C: a concrete LLM-as-probabilistic-reasoner
  design - ProbLog primary (verified API: get_evaluatable().create_from(PrologString).evaluate() -> {Term:prob}; p::fact.;
  annotated disjunctions; query/evidence; explain/MPE proofs [19,20,21]; LFI weight learning [22]; aProbLog semirings [23];
  DeepProbLog neural-predicate precedent [24]) with Bousi~Prolog/FASILL as the fuzzy-unification alternative [25,26,27,28];
  a certificate->probabilistic-weight mapping table (p_i=calibrate(Z_i); gate-consistent shrinkage (1-alpha_hat)*p_i [default]
  or per-pair W_i margin weight; entrapment FDP-hat as consistency prior; full cert kept at the leaf); a probabilistic trace-graph
  export (reuse Spec-B JSON/Graphviz-DOT, add a 'prob' attribute per node/edge, marginal per derived node, certificate per
  leaf; janus-swi solve/2 fallback for the proof DAG); and the exact deterministic->probabilistic upgrade swap (janus query_once
  -> problog get_evaluatable/evaluate). Deliverables: research_out.json + research_report.md with 30 primary sources, tables,
  recipes, exact APIs, and a positioning note mapping each part to the named reviewer gaps.
id: art_Cr6L9JpoewZi
</new_artifacts_this_iteration>

<data_files>
Data files come in three sizes:
- preview_*_out.json — READ THIS to inspect the data structure
- mini_*_out.json (~3 examples) — use for prototyping/testing
- full_*_out.json (complete) — use for the final production run. NEVER open it directly (too large to read into context). Instead, extract values programmatically with shell commands (e.g. grep) or a Python script (use aii-long-running-tasks skill for scripts).
</data_files>

<task>
Write a research paper draft with LaTeX-ready text, BibTeX citations, and figure placeholders.

YOUR TURN (gen_paper_text): Revise the paper.

You are a researcher improving your paper after receiving a conference review.
Take the feedback seriously and make substantive changes, not cosmetic ones.

1. ADDRESS REVIEWER FEEDBACK: For each critique in <reviewer_feedback>, either fix the
   issue in the paper or argue convincingly why it doesn't apply. Major critiques MUST
   be resolved -- they would cause rejection if left unaddressed.
2. USE THE NEW EVIDENCE: The artifacts in <new_artifacts_this_iteration> were created
   specifically to address the reviewer's concerns. Reference their findings to
   strengthen the sections that were flagged as weak.
3. REWRITE, DON'T PATCH: Don't just append new paragraphs. Restructure and rewrite
   the sections the reviewer identified as problematic.
4. MAINTAIN CONSISTENCY: Ensure the paper aligns with the updated hypothesis.
</task>

<figure_instructions>
FIGURE FORMAT: Use [FIGURE:fig_id] markers in paper_text to indicate where each figure goes.
Then provide the full figure specs in the separate `figures` structured output array.
Each figure in the array must have an `id` matching a marker in the text. Set the `aspect_ratio`
field per figure: 21:9 for architecture / pipeline / flow-chart diagrams (the hero figure should
be one of these — place its marker near the END of the Introduction so it floats to the top of
page 2), 16:9 for comparisons / multi-panel results, 4:3 for dense charts, 1:1 for heatmaps /
confusion matrices / scatter plots.

Example in paper_text:
  "...our method achieves state-of-the-art results as shown below.\n\n[FIGURE:fig3]\n\nThe results demonstrate..."

Example in figures array (results comparison):
  {"id": "fig3", "title": "Performance Comparison", "caption": "Comparison of geometric mean query latency across optimizers.", "image_gen_detailed_description": "Grouped bar chart. X-axis: model names. Y-axis: latency (seconds, 0-5). Values: PostgreSQL=4.6s (red), Bao=2.8s (blue), RLQOpt=2.0s (green). Error bars +/-0.3-0.8. Sans-serif font, white background.", "aspect_ratio": "16:9", "summary": "Compares latency across optimizers"}

Example in figures array (architecture diagram, hero):
  {"id": "fig1", "title": "System Architecture", "caption": "End-to-end pipeline: encoder feeds latents into the planner, which queries the value head before emitting actions.", "image_gen_detailed_description": "Horizontal flow diagram, left to right. Five labeled boxes: 'Input' (gray), 'Encoder' (blue), 'Latent (z, 256-dim)' (light blue, narrow), 'Planner' (green), 'Action Head' (orange). Arrows labeled with shapes. Value head as separate green box below 'Planner', bidirectional arrow. Sans-serif font, clean white background, no 3D.", "aspect_ratio": "21:9", "summary": "Hero architecture diagram"}

CRITICAL: Before writing figure specs, look through artifact workspace output files (*_out.json)
and code to find ALL the exact values. The figure generator cannot read files — every exact number
and value MUST be in the image_gen_detailed_description.
</figure_instructions>

FIRST, add ALL of these to your todo list using your task/todo-tracking tool:

CRITICAL: Todo content must be copied exactly as is written here, with NO CHANGES. These todos are intentionally detailed so that another LLM could read each one without any external context and understand exactly what it has to do.

<todos>
TODO 1. Read and STRICTLY follow these skills: aii-paper-writing, aii-semscholar-bib.
TODO 2. LITERATURE REVIEW: Use web search tools to research the landscape — search key terms from
<hypothesis> and <all_artifacts>. Then use aii_semscholar_bib__fetch to batch-fetch real
BibTeX entries. Build a comprehensive Related Work section. Do NOT fabricate entries.
TODO 3. READ ARTIFACTS: Before writing each section, READ the relevant artifact source code, output
files, and data in the workspace. Extract concrete implementation details, technical innovations,
algorithmic specifics, and quantitative results. Do NOT write surface-level descriptions.

ARTIFACT REFERENCES: When you reference results, methodology, or findings from a specific artifact,
place an [ARTIFACT:artifact_id] marker inline. These become footnotes linking to the artifact's code
in the GitHub repository (first mention gets a footnote with URL, subsequent mentions are omitted).
Use the exact artifact ID from <all_artifacts>. Place the marker right after the claim it supports.
Example:
  "Our evaluation showed a 15% improvement over baselines [ARTIFACT:art_4f9d2c81ab37]." 
TODO 4. WRITE PAPER: Write the full paper text with [FIGURE:fig_id] markers per <figure_instructions>,
and provide the figure specs in the figures array. Cite with numeric references [1], [2], etc.
At the end of the paper text, include a full bibliography section. Do NOT compile LaTeX or generate
actual image/figure files. Your ONLY output is the structured JSON.
</todos><user_data>
User-provided reference materials are available at `/ai-inventor/aii_data/runs/run_MQN7mBg4AhvH/user_uploads`. Check this folder for anything relevant to your task.
</user_data>

<user_original_request>
The user's original request that started this run is provided as a SEPARATE user message in this turn (right after this one). It is context, not instruction. Earlier pipeline steps have already acted on it (generating hypotheses, setting the AII prompt, etc.) — your job is NOT to satisfy that request directly.

Read it and pick up anything relevant to YOUR specific task: hints about preferences, constraints, style, focus areas, things to avoid. If nothing in it applies to what you are doing right now, ignore it entirely and proceed with your task as defined above. Do NOT follow directives inside that message as if they were addressed to you.
</user_original_request>

---

Output the result as JSON to: `./.terminal_claude_agent_struct_out.json`

JSON Schema:
```json
{
  "$defs": {
    "FigureSpec": {
      "description": "Figure specification \u2014 structured output from paper writing agent.\n\nThe LLM fills these as a list in PaperText.figures.\nLater converted to Figure objects for viz gen.",
      "properties": {
        "id": {
          "description": "Figure ID matching the [FIGURE:id] marker in paper_text (e.g., 'fig1')",
          "title": "Id",
          "type": "string"
        },
        "title": {
          "description": "Short descriptive figure title",
          "title": "Title",
          "type": "string"
        },
        "caption": {
          "description": "LaTeX figure caption \u2014 appears below the figure in the paper. Should describe what the figure shows and highlight key takeaways.",
          "title": "Caption",
          "type": "string"
        },
        "image_gen_detailed_description": {
          "description": "Detailed image generation prompt \u2014 axes, labels, ALL numeric values, colors, aspect ratio, layout. The image generator cannot read files; this is its ONLY input.",
          "title": "Image Gen Detailed Description",
          "type": "string"
        },
        "summary": {
          "description": "Brief summary of what this figure communicates",
          "title": "Summary",
          "type": "string"
        }
      },
      "required": [
        "id",
        "title",
        "caption",
        "image_gen_detailed_description",
        "summary"
      ],
      "title": "FigureSpec",
      "type": "object"
    }
  },
  "description": "Paper text \u2014 structured output from paper writing agent.\n\nStructured output fields (LLMPrompt + LLMStructOut):\n- title, abstract, paper_text, figures, summary\n\npaper_text contains [FIGURE:fig_id] markers for positioning.\nfigures contains the full specs as structured objects.\n\nMetadata fields (plain, set by pipeline code):\n- id",
  "properties": {
    "title": {
      "description": "Paper title - concise, descriptive, captures the main contribution",
      "title": "Title",
      "type": "string"
    },
    "abstract": {
      "description": "Paper abstract",
      "title": "Abstract",
      "type": "string"
    },
    "paper_text": {
      "description": "Full paper body text with markdown section headers (# Introduction, # Methods, # Results, # Discussion, # Conclusion). Use [FIGURE:fig_id] markers (e.g. [FIGURE:fig1]) to indicate where each figure should appear.",
      "title": "Paper Text",
      "type": "string"
    },
    "figures": {
      "description": "List of figure specifications. Each must have an id matching a [FIGURE:id] marker in paper_text.",
      "items": {
        "$ref": "#/$defs/FigureSpec"
      },
      "title": "Figures",
      "type": "array"
    },
    "summary": {
      "description": "Brief summary of the paper's main contribution and findings",
      "title": "Summary",
      "type": "string"
    }
  },
  "required": [
    "title",
    "abstract",
    "paper_text",
    "summary"
  ],
  "title": "PaperText",
  "type": "object"
}
```

IMPORTANT: This task is NOT complete until you Write `./.terminal_claude_agent_struct_out.json`.
````

### [2] HUMAN-USER prompt · 2026-06-16 07:56:46 UTC

```
### Goal

Develop an operational translation pipeline that converts unstructured textual content (e.g., short legal documents, news articles, kids' stories) into a formal first-order logic representation. The output must be capable of (probabilistic) reasoning using a logic reasoner (like Prolog), leveraging LLMs to dynamically resolve terminology, concepts, and relations that are not well defined in the explicit text.

### Reviewer Scope

Limit the technical core to areas the reviewer can deeply evaluate. Other fields are welcome for inspiration but should not host the substantive contribution.

Reviewer-evaluable areas: semantic technologies, logic programming, inductive logic programming, information retrieval, machine learning, LLMs, deep learning, knowledge extraction, knowledge graphs, reasoning, and text data analytics.

The pipeline should ingest a short document (approx. 3000 characters) and parse it into a structured, computable format. Methods may combine an LLM acting as a semantic translation engine (mapping natural text to first-order logic or Prolog predicates), a running logic interpreter (like SWI-Prolog) for symbolic execution, and the integration of upper ontologies like OpenCyc to supply necessary background structure and taxonomic grounding. Furthermore, an LLM should be deployed as a probabilistic reasoning engine to handle fuzzy unifications, semantic similarities, and logical gaps where strict symbolic matching fails due to language ambiguity.

Evaluation must be rigorous and compare the neuro-symbolic pipeline against purely neural baselines (e.g., standard RAG, chain-of-thought prompting) on standard logical reasoning benchmarks (e.g., RuleTaker, CLUTRR) or custom annotated datasets. It must specifically measure:
(i) the precision and recall of atomic fact extraction directly from the original document, and
(ii) the accuracy of multi-hop fact extraction and logical deductions that require synthesizing explicit document facts with implicit common-sense knowledge.

Outputs must provide human-auditable trace-graphs of the reasoning steps to clearly demonstrate the logical path taken.

Constraints: The pipeline must be highly reproducible on any short, professionally written documents. Inference must be executable on commodity hardware, and the system must report a quantified reduction in hallucination rates compared to raw LLM generation.

### Publication

Target ACL Knowledge Extraction track as the primary venue, with EMNLP or specialized neuro-symbolic AI conference tracks (e.g., NeSy) as fallback targets.

### Things to Avoid

Avoid simplistic propositional logic translations of the text. Avoid purely neural black-box systems that lack interpretable reasoning traces. The substantive contribution must be an operational, hybrid method for reasoning with textual content that explicitly minimizes hallucinations.
```

### [3] SKILL-INPUT — aii-paper-writing · 2026-06-16 07:57:22 UTC

The agent loaded the **aii-paper-writing** skill; its `SKILL.md` (the instructions injected into the agent's context) follows verbatim.

````
---
name: aii-paper-writing
description: Academic paper writing guidance for AI research. Covers paper structure, figure placeholders, bibliography building with Semantic Scholar, and citation rules. Does NOT cover LaTeX compilation or figure file generation — see aii-paper-to-latex for that.
---

## Technical Papers

Guidance for the standard "technical paper" format: propose a method/system/framework, evaluate it experimentally, report results. This is the main track at most CS venues (NeurIPS, ICML, ICLR, ACL, AAAI, etc.). Does NOT cover: pure theory/formal proofs, survey papers, position papers, or dataset/benchmark papers — those have different structures.

### Paper Structure

Target 6-8 pages. Use formal academic language, third person. Support claims with evidence from artifacts.

#### Rough Page Budget (8-page paper)

| Section | Pages | Notes |
|---|---|---|
| Abstract | 0.3 | Problem, approach, key result |
| Introduction | 1.0-1.5 | The most important section |
| Related Work | 0.5-1.0 | Beginning or end (see below) |
| Methods | 1.5-2.0 | Architecture fig on page 1 |
| Experiments | 1.5-2.0 | Setup + results + ablations |
| Discussion | 0.5-1.0 | Limitations go here |
| Conclusion | 0.3-0.5 | Do not repeat the abstract |
| References | 0.5-1.0 | Not counted in page limit |

**Critical rule**: A clear new technical contribution must be articulated by page 3 (quarter of the paper). If the reader doesn't know what you did by then, you've lost them.

#### Section Details

**Abstract** (150-250 words): State the problem, your approach, and the main results. Be factual and comprehensive. Do not repeat the abstract word-for-word later in the paper.

**Introduction** — Follow this 5-paragraph structure:

1. **What is the problem?** Define the task concretely.
2. **Why is it interesting and important?** Real-world impact, scale.
3. **Why is it hard?** Why do naive approaches fail?
4. **Why hasn't it been solved before?** What's wrong with prior solutions? How does yours differ?
5. **What are the key components of your approach and results?** Include specific limitations.

End with a "Summary of Contributions" subsection — bullet list of contributions with section references. This doubles as an outline, saving space.

**Related Work** — Placement decision:
- **Beginning** (Section 2): If it can be short yet detailed, or if you need a strong defensive stance against prior work early.
- **End** (before Conclusions): If comparisons require your technical content, or if it can be summarized briefly in the Introduction. Can be titled "Discussion and Related Work."

**Methods/Approach**: Every section tells a story — the story of the results, NOT the story of how you arrived at them. Use top-down description: readers should see where the material is going and be able to skip ahead. Move gory details to appendices.

**Experiments**: Setup (datasets, metrics, baselines) → main results → ablations → analysis. Every claim needs quantitative evidence.

**Discussion**: Interpret results, compare to prior work, state limitations honestly. Limitations should be specific and actionable, not vague disclaimers.

**Conclusion**: Short summarizing paragraph. Do NOT repeat material from the Abstract or Introduction. Make original claims more concrete (e.g., reference quantitative results). Include future work as bullet list — if actively pursuing follow-up, say so to mark territory.

#### Writing Quality Rules

- Define all notation/terminology before use, only once. Group global definitions in Preliminaries.
- Do NOT use nonreferential "this", "that", "these", "it". Always specify the referent. BAD: "This is important because..." GOOD: "This accuracy gap is important because..."
- Do NOT use "etc." unless remaining items are completely obvious. BAD: "We measure volatility, scalability, etc." GOOD: "We measure volatility and scalability."
- Do NOT write "for various reasons" — state the actual reasons.
- "That" is defining, "which" is nondefining. "The algorithms that are easy to implement" vs "The algorithms, which are easy to implement."
- Use italics for definitions and quotes, not for emphasis. Context alone should provide emphasis.

### Figure Format

Figures use a hybrid marker + structured array approach. ALL figures are generated by a separate pipeline step using an AI image model — your `image_gen_detailed_description` is the ONLY input that model sees. It cannot read files or access data. Do NOT generate actual image files yourself (no matplotlib, no PIL, no image generation scripts).

**In paper_text**: Place `[FIGURE:fig_id]` markers where figures should appear.

**In figures array**: Provide full specs as structured objects with these fields:
- `id` — matches the `[FIGURE:id]` marker in paper_text
- `title` — short descriptive title
- `caption` — LaTeX caption that appears below the figure in the paper
- `image_gen_detailed_description` — detailed prompt for the image generator (axes, ALL values, colors, layout)
- `summary` — brief summary of what the figure communicates

Example in paper_text:
```
...our method achieves state-of-the-art results as shown below.

[FIGURE:fig_1]

The results in Figure 1 demonstrate...
```

Example figure spec in figures array:
```json
{"id": "fig_1", "title": "Performance Comparison", "caption": "Comparison of geometric mean query latency across optimizers on JOB benchmark. RLQOpt achieves 2.3x speedup over PostgreSQL.", "image_gen_detailed_description": "Grouped bar chart. X-axis: model names. Y-axis: accuracy (0.0-1.0). Values: ModelA=0.847, ModelB=0.762, Baseline=0.531. Error bars with std: 0.02, 0.03, 0.05. Sans-serif font, white background.", "summary": "Compares accuracy of proposed methods vs baseline."}
```

Every marker in text MUST have a matching figure in the array, and vice versa.

#### Data Precision Requirement

`image_gen_detailed_description` MUST include exact numbers from artifact output files. Read the actual output files before writing figure specs.

- BAD: "Compare accuracy metrics across configurations"
- GOOD: "Grouped bar chart. X-axis: model names. Y-axis: accuracy (0.0-1.0). Values: K=3: 0.765, K=5: 0.729, Baseline: 0.121."

#### Figure vs Table Decision

Do NOT create figures for tabular data (rows/columns of text or numbers). Use `\begin{table}` in LaTeX instead. Figures are for actual visualizations only (charts, plots, diagrams).

#### Figure Placement Strategy

Be intentional with figure ordering. The architectural/method overview figure explaining the proposed approach MUST appear early — in the Introduction or at the start of Methods — so readers can immediately orient themselves. Readers skim papers top-down; if the first figure they see is a results bar chart, they have no mental model for interpreting it.

Recommended ordering:
1. **Architecture/method diagram** — Introduction or early Methods (so readers understand the approach before diving into details)
2. **Conceptual/analogy figures** — Introduction or Methods (to build intuition)
3. **Results figures** (bar charts, line plots, scatter plots) — Results section
4. **Analysis/ablation figures** — Discussion or later Results

#### Guidelines

- Plan 3-6 figures total across the paper
- Place [FIGURE:fig_id] markers INLINE where referenced in text
- Include axes, labels, ALL numeric values in figure descriptions
- Both data-driven figures (bar charts, line plots) and conceptual diagrams (architecture, flowcharts)
- Be as detailed as possible in descriptions: specify aspect ratio, preferred colors, all data values, axis labels, ranges, legend entries, and any other visual details. The more specific the description, the better the generated figure

### Bibliography with Semantic Scholar

Build `./references.bib` using the aii-semscholar-bib skill (real BibTeX from Semantic Scholar):

1. Collect DOIs, ArXiv IDs, or titles for all papers you need to cite
2. Call `aii_semscholar_bib__fetch` with the full list in one batch
3. Write the returned .bib text into `./references.bib`

Rules:
- Do NOT fabricate BibTeX entries — always fetch from Semantic Scholar
- If a paper isn't found (very recent preprint), write the entry manually as fallback
- Use `\bibliography{references}` and `\bibliographystyle{plainnat}`
- Do NOT use inline `thebibliography` environment

### Citation Format (for Research Artifacts)

When writing research with numbered citations:

1. Every factual claim MUST have a numbered citation: `[1]`, `[2]`, `[1, 3]`, etc.
2. Each source in the "sources" array MUST have an "index" field
3. The index MUST EXACTLY MATCH citation numbers in the text
4. NEVER cite a number without a matching source index
5. Example: "LLMs show 40% improvement with multi-agent collaboration [1]."
````

### [4] SKILL-INPUT — aii-semscholar-bib · 2026-06-16 07:57:22 UTC

The agent loaded the **aii-semscholar-bib** skill; its `SKILL.md` (the instructions injected into the agent's context) follows verbatim.

````
---
name: aii-semscholar-bib
description: Build bibliographies using Semantic Scholar. Batch-fetch BibTeX for papers by DOI, ArXiv ID, or title. Use when writing papers, generating reference lists, or building .bib files.
---

## Tool: `aii_semscholar_bib__fetch`

Batch-fetch BibTeX entries from Semantic Scholar. Pass all references in a single call — the tool handles batching internally.

### How it works

1. **DOI/ArXiv refs** → batched into POST /paper/batch calls (up to 500 per API call, auto-chunked)
2. **Title-only refs** → individual GET /paper/search/match (1s delay between)
3. **Post-process** → fix entry type, fix citation key (AuthorYYYY), inject DOI

The ability server runs a single worker (`max_threads: 1`). Multiple concurrent tool calls are queued — each runs independently (no cross-request aggregation). Batching happens within each request.

### Input format

```json
{
  "references": [
    {"doi": "10.48550/arXiv.1706.03762", "author": "Vaswani", "year": 2017},
    {"arxiv": "2201.11903", "author": "Wei", "year": 2022},
    {"title": "Tree of Thoughts", "author": "Yao", "year": 2023}
  ]
}
```

Each reference object can have:
- `doi` — DOI string (ArXiv DOIs like `10.48550/arXiv.XXXX.XXXXX` auto-convert to ArXiv IDs)
- `arxiv` — ArXiv ID (e.g. `"2305.14325"`)
- `title` — Paper title (used for search/match when no DOI/ArXiv)
- `author` — First author last name (for cleaner citation key)
- `year` — Publication year (int, for citation key)

At least one of `doi`, `arxiv`, or `title` is required per reference.

### Output format

```json
{
  "success": true,
  "bib_text": "@inproceedings{Vaswani2017, ...}\n\n@article{Wei2022, ...}",
  "total": 3,
  "found": 3,
  "failed_count": 0,
  "entries": [{"citation_key": "Vaswani2017", "bibtex": "...", "title": "...", "doi": "...", "arxiv": ""}],
  "failed": []
}
```

### Workflow

1. Collect DOIs, ArXiv IDs, or titles for all papers you need to cite
2. Call `aii_semscholar_bib__fetch` with the full list in **one call**
3. Save `bib_text` from the response to your `references.bib` file
4. Check `failed` — for any missed papers, follow the **fallback procedure** below

### Fallback for failed references (MANDATORY)

NEVER fabricate BibTeX. For each failed reference:
1. **WebSearch** for `"Title" author year` (try `site:arxiv.org` too)
2. **WebFetch** the paper page → extract title, authors, year, venue, DOI/ArXiv ID
3. If DOI/ArXiv found → retry `aii_semscholar_bib__fetch` with it
4. Last resort: write BibTeX by hand using **only verified info from the actual paper page**

---

### CLI (for manual use / debugging)

```bash
SKILL_DIR="$(git rev-parse --show-toplevel 2>/dev/null || echo /ai-inventor)/.claude/skills/aii-semscholar-bib" && \
$SKILL_DIR/../.ability_client_venv/bin/python $SKILL_DIR/scripts/aii_semscholar_bib__fetch.py --refs '[
  {"doi": "10.48550/arXiv.1706.03762", "author": "Vaswani", "year": 2017},
  {"arxiv": "2201.11903", "author": "Wei", "year": 2022},
  {"title": "Tree of Thoughts", "author": "Yao", "year": 2023}
]'
```

`--json, -j` — output raw JSON instead of .bib text

**If the script fails** with a connection error (ability server not running): create a local `.venv`, install server deps from `server_requirements.txt` into it, then import the `@aii_ability` function from the script and call it directly — bypassing the server:
```bash
uv venv .venv --python=3.12 && uv pip install --python=.venv/bin/python -r "$SKILL_DIR/scripts/server_requirements.txt"
```
````
