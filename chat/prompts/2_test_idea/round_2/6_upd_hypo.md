# upd_hypo — test_idea

> Phase: `invention_loop` · round 2 · `upd_hypo`
> Run: `run_u75jRHUss0zo` — Gold-Free Faithfulness Metrics for NL-to-FOL Translation
>
> Full, verbatim record of every prompt the AI Inventor pipeline gave this agent — system-user, human-user and skill-input — in the order they landed. Nothing truncated.

## Task: `upd_hypo` (terminal_claude_agent)

### [1] SYSTEM-USER prompt · 2026-09-24 01:02:04 UTC

````
<ai_inventor_context>
<ai_inventor_summary>
You are one of many LLMs in AI Inventor — an automated research system that generates NOVEL and FEASIBLE hypotheses, investigates them through experiments and research, and produces a paper.

Your output feeds other LLMs downstream. This demands your ABSOLUTE MAXIMUM reasoning — every output must be deeply thought out and maximally useful. Surface-level responses waste downstream computation.
</ai_inventor_summary>

<your_role>
YOU ARE: A hypothesis reviser (Step 3.6: UPD_HYPO in the invention loop)

You received the current hypothesis, all artifacts, and the paper draft.
Revise the hypothesis based on what the evidence supports.

Honest revision → focused research. Inflated confidence → wasted iteration.
</your_role>
</ai_inventor_context>

You are deciding where a research run points next, using the evidence it
gathered this iteration. Your revised hypothesis IS the next iteration's
hypothesis — nothing else steers the run — so this is a steering decision
first and a piece of honest reflection second.

SCOPE: Your ONLY output is the revised hypothesis text. You do NOT run code,
produce artifacts, fix bugs, or otherwise act on the evidence yourself — the
next iteration of the invention loop will spawn fresh artifacts based on your
revised hypothesis. Reflect on the evidence and rewrite the hypothesis;
nothing else.

PRINCIPLES:
- Ground every revision in specific artifacts and results. A number that was
  projected, assumed or left as a placeholder is not a result.
- CLASSIFY EVERY ARTIFACT SEPARATELY, BEFORE CHOOSING A MOVE. One artifact
  is one bet. A round is normally MIXED, and judging the round as a whole is
  how one real positive gets thrown out with the nulls beside it. The round
  summary is then READ OFF the best of those verdicts, and the move follows
  from the summary and the remaining budget by a fixed rule — not by free
  judgement, because free judgement is where past runs went wrong.
- LATCH ONTO A GENUINE POSITIVE. One executed, non-obvious, baseline-proof
  result at a size the ask cares about is the run's whole output. Hold it,
  and spend the next round on its mechanism, its boundary, its confounds and
  its replication. Do not go looking for a different question while it lives.
- WEAK IS NOT NULL. A small real effect, a positive that lost to a baseline
  by a margin, a signal seen on one body of evidence — these are LEADS. The
  answer to a lead is to make it bigger and cleaner, not to abandon it. Widen
  off a lead only after deepening it has come back empty.
- A round where NOTHING is real is the signal to go WIDER, not smaller. The
  question the user asked is still open; the answer you tried is the only
  thing that was refuted, and every next bet should be a different answer to
  the ask.
- Never shrink the claim until the effect you happened to observe becomes
  the claim. A finding nobody needed is worse than an honest negative.
- A broken test is fixed ONCE, with the claim unchanged. A bet that breaks
  twice is dropped, and its budget goes to a new candidate.
- The run is looking for a POSITIVE, NON-OBVIOUS result. A clean negative is
  a LAST RESORT, right only when no iteration and no candidate remain.
- Increase specificity as evidence accumulates; do not inflate confidence
  without strong evidence.
- Revise hypothesis text only — never attempt to address feedback by running
  code, proposing fixes, or producing artifacts; the next loop iteration
  handles all artifact generation.

<workspace>
Your workspace: `/ai-inventor/aii_data/runs/run_u75jRHUss0zo/3_invention_loop/iter_2/upd_hypo/upd_hypo`

CRITICAL: Every file you create, write, or save MUST be inside this workspace directory (subdirectories OK). You MUST NOT write files anywhere outside this path — external paths are READ-ONLY. Use absolute paths for all file operations.

EVERY file write MUST start with `/ai-inventor/aii_data/runs/run_u75jRHUss0zo/3_invention_loop/iter_2/upd_hypo/upd_hypo/`:
GOOD: `/ai-inventor/aii_data/runs/run_u75jRHUss0zo/3_invention_loop/iter_2/upd_hypo/upd_hypo/file.py`, `/ai-inventor/aii_data/runs/run_u75jRHUss0zo/3_invention_loop/iter_2/upd_hypo/upd_hypo/results/out.json`
BAD: `/tmp/file.py`, `~/output.json`, `./file.py`, any path outside the workspace
</workspace>
<disposable_outputs>
YOUR WORKING DIRECTORY IS A DELIVERABLE. When this module ends it must read
like a GitHub repository someone else can fork, resume and run — and the bulk
it holds must be either worth keeping or restorable. This run shares a storage
volume with the database; a run that fills it stops every other run on the box.

So before you finish, produce TWO files:

1. `.aii/manifest.yaml` — one entry per heavy path, each with EXACTLY ONE decision.
   The `.aii/` directory ALREADY EXISTS in your cwd: write the file into
   it. Do not create, replace or `touch` `.aii` itself — a plain file by
   that name makes the manifest unwritable for the rest of the module.

```yaml
entries:
  - path: results/
    keep: six GPU-hours of sweep output, not reproducible inside this run
  - path: hf_cache/
    delete: redownloadable
    source: "huggingface-cli download meta-llama/Llama-3-8B"
  - path: checkpoints/
    delete: regenerable
    source: "uv run train.py --epochs 3 --seed 0"
```

   - `keep:` takes a ONE-LINE reason. Use it for the expensive and the
     irreproducible: trained weights, long-running results, datasets you
     collected yourself.
   - `delete:` takes `redownloadable` (and a `source:` naming the repo id, URL
     or command) or `regenerable` (and a `source:` that is the command which
     rebuilds it). These are deleted AFTER the round ends, never mid-step.
   - Every path is RELATIVE TO YOUR CWD and must resolve INSIDE it. Absolute
     paths, `..`, and anything resolving outside are rejected.
   - Globs and whole directories are fine. A whole `hf_cache/` is ONE entry —
     do not list files individually.

2. `README.md` — written as if your cwd were a GitHub repository: what you
   did, the layout with a line per important file/directory, how to run it,
   and a **"Restoring removed files"** section giving the install/download
   command for EVERY `delete` entry. An `install.sh` or `restore.sh` beside it
   is welcome.

A CHECKER RUNS WHEN YOU SUBMIT. If anything heavy has no decision it fails
your submission and hands you the uncovered list, grouped by directory with
sizes, and you fix the manifest and submit again.

WHAT NEEDS NO DECISION — do not write entries for these:
- text and code files, at ANY size (source, JSON, CSV, YAML, logs, markdown);
- anything under the auto-keep floor (10 MB), whatever it holds.
Only large binaries and cache directories (`hf_cache/`, `.venv/`,
`node_modules/`, `checkpoints/`, `wandb/`, `__pycache__/`, …) need one.

NEVER mark your results, figures, papers, code, logs or anything a later step
reads as `delete`. If a later step needs it, it is a `keep`.

WHAT A `keep` BUYS YOU. Anything you do not mark `delete` stays exactly where
you wrote it, on this run's storage volume, at the path it already has — it is
not moved, renamed or copied. A later round reads it there, by that absolute
workspace path, so a checkpoint you keep is a checkpoint the next round can
load instead of retraining. It is also the ONLY copy: the publish step pushes
your cwd to GitHub but skips every file of 100 MB or
more, so trained weights and large binary artifacts never leave the volume.
Write the workspace path of each kept artifact into your results and your
`README.md`, so the paper can cite it by path rather than by a link that
was never pushed.
</disposable_outputs>

<current_hypothesis>
The hypothesis as it stands. Revise it based on the evidence below.

kind: hypothesis
title: Peer agreement plus text checks vs judges
hypothesis: |-
  kind: hypothesis (iteration 2 of 5; move = DEEPEN on the two iteration-1 leads)

  CORRECTED RECORD OF ITERATION 1 (it replaces the draft's claims; every number was executed).
  (i) Under the pre-registered rule, NO candidate passed. The disguised cheap judge (gemini-2.5-flash-lite, nonce-disguised, AUROC 0.777) is the incumbent. On the 389 common, label-consistent track-L items (160 errors, 151 sentences; review audit paired_boot.json), c_score is 0.842 vs the judge's 0.785, Δ +0.057 [-0.022, 0.137]; FOL-Triage fused is 0.767, Δ -0.020 [-0.111, 0.074]. c_score also fails the rewrite gate (RENAME false alarms 96%, flip 77%).
  (ii) The ranking depends on the labels. Re-scoring with dataset E's adjudicated screen labels (screen_adjudicated_labels.json; review audit rescore_adjudicated.json), tier A+B, n=304 with 170 errors: fused (fitted on track H only, never on these labels) 0.872, L2-bow 0.817, c_score 0.776, judge 0.771, rt_nli 0.750, SC-5 0.699. All tiers (n=504): fused 0.868, c_score 0.829, judge 0.815. Label noise runs mostly one way: vocabulary-aligned 'CORRECT' is often unfaithful. Solver-CORRECT to panel-ERROR is 58 (exp D) / 62 (exp C), against 1 and 1 the other way. So the 'VOCAB = CORRECT' convention is the largest label risk, not ADD+DROP artefacts.
  (iii) Two shared-instrument confounds point in opposite directions. c_score shares align() with the solver labeller, although its vocab-clean control holds (0.852 vs SC 0.714; partial Spearman 0.51). L2-bow shares lexical sensitivity with the panel, since both penalise unanchored predicates. Neither label regime alone can rank these metrics.
  (iv) Closed in iteration 1; one sentence each in the paper, no further budget. L1 lint on LLM outputs: AUROC 0.508, TPR 2% (it works on human errors, 0.655, and as a gold audit). L2-role: 0.557. The user's pilot structural metrics: 0.50-0.53, a clean negative. Round-trip re-formalise-and-z3: 0.513.
  (v) Frontier judge (gemini-3.1-pro), same items: +0.077 [0.006, 0.154] over the cheap judge on 200 original-text L items (p=.015), and +0.115 on H. The gain vanishes under disguise. It costs $0.0029 per call, above the $0.002 gate.
  (vi) Judges are not rewrite-invariant. They flip on 29-49% of meaning-preserving rewrites (contrapositive false alarms: cheap 0.67, nano 0.95).
  (vii) Consensus is cross-family (6 fresh peers 0.872 vs 2 Logic-LM peers 0.753) and beats SC-5 by +0.140. That result CONFIRMS SAC3 (Zhang et al. 2023); it is not new.
  (viii) Exact-equivalence consensus degrades with length: its complexity interaction is -0.94 per SD of words, vs about 0 for SC.
  (ix) Candidate B (B1 template-verbalise + bidirectional NLI; B2 solver-built worlds judged from text) was PLANNED BUT NEVER EXECUTED. gen_art_experiment_2 is empty, and exp D's round-trip rows are an LLM-verbaliser baseline, not B1.
  (x) Dataset E's panel is STRICT: it accepts 0.613 of expert-corrected formulas, has 0.727 majority accuracy on real errors, and rejects 0.822 of MALLS gold vs 36-46% for experts. Tiers: A 1,044 / B 2,157 / C 3,891 / none 276 / UNPARSEABLE 1,086. In L25, tier-A-only is NOT testable (40 CORRECT / 98 ERROR).

  CLAIM (the lead, made bigger and cleaner). COMPLEMENTARY GOLD-FREE FUSION, called PEER+TEXT. Two cheap, judge-free signals see disjoint parts of the error mass. Fused with fixed weights, they beat the disguised cheap LLM judge AND the best cross-fitted combination of all requested baselines. They do so under EVERY label regime, on held-out data. The advantage is largest on long, heavily conditioned sentences, where the judge degrades, and the fused metric stays invariant to meaning-preserving rewrites that flip the judge.
  Signal 1, STRUCTURE-FROM-PEERS: graded, name-free cross-family consensus. It sees structural, scope, quantifier and polarity errors that a candidate's family makes and others do not: the polarity blind spot is 5%, and recall on polarity errors 0.95.
  Signal 2, LEXICON-AND-ROLES-FROM-TEXT: L2 text accounting plus the L3 text-only role questionnaire, answered exactly by z3 on the formula side. It sees errors that ALL systems share, and meaning-changing renames, where consensus is blind: 38% of errors are endorsed by the peer medoid (COVERAGE 41%, STRUCT 57%).
  A cheap judge reads both kinds of error but loses them on long inputs and under rewrites.
  One-sentence finding if it holds: 'For NL->FOL there is no need for a large judge. Agreement among cheap translators, checked by a solver clause by clause, plus solver-exact text accounting, beats an LLM judge and every standard baseline combination. It stays rewrite-invariant, and it holds on long conditioned sentences regardless of how the labels were adjudicated.'

  MECHANISM PREDICTIONS (pre-registered; informative whichever way they fall).
  P1 CROSSOVER. Per-type recall at matched false-alarm rate: peers > text on QUANT/SCOPE/BIND/argument-SWAP/NEG, and text > peers on MEANING_RENAME and on peer-endorsed (medoid-equivalent) errors.
  P2 DISJOINTNESS. Among true errors, Spearman(peer score, text score) < 0.4. At least 50% of the fusion's AUROC gain over the better single signal comes from peer-endorsed errors.
  P3 LENGTH. Exact-equivalence consensus loses AUROC with words (interaction < 0), graded consensus loses at most half as much, and the judge's correctness falls with length (iteration 1: -0.48 per SD, p<.001). The fused-minus-judge Δ is therefore larger in L25/L20/EXC than in CTRL.
  P4 INVARIANCE. PEER+TEXT stays ≤10% false alarms on EVERY rewrite family, including RENAME, on one shared rewrite set. The judges stay at ≥25% on at least one family.

  COMPONENT FIXES. Each defect is fixed once; a component that breaks again is dropped.
  F1 NAME-FREE ALIGNMENT, for the RENAME 96% false alarms and the align() confound. Candidate-to-peer predicate and constant maps are found from structure, not names. Signature per symbol: arity, z3 monotonicity (DOWN/UP), quantifier-block position and argument-sharing graph, plus an optional text anchor (the L2 stem/WordNet span). The search is an assignment, accepted only if clause entailment verifies under it. This makes consensus invariant to renaming by construction and decouples it from the labeller's name-similarity aligner. Over-alignment risk (masking predicate substitution) is measured by per-type recall of SWAP and MEANING_RENAME.
  F2 GRADED CLAUSE CONSENSUS, for length saturation.
    - Decompose every formula into claim units: top-level conjuncts after normalisation, each universal rule as (restrictor set, consequent), and existential claims.
    - support = the mean over the candidate's units of the fraction of peers p for which p entails the unit.
    - coverage = the fraction of peer-majority units (units supported by ≥50% of peers) that the candidate entails.
    - g_score = 1 - F1(support, coverage).
    - The same z3 calls give the error type and location. An unsupported unit is ADD. An uncovered majority unit is DROP (the dropped-condition signal the user cares about most). A candidate that entails the negation of a majority unit is NEG. A unit that matches only after a quantifier flip is QUANT. The medoid-repair operator readout (81% exact operator match vs 46% chance in iteration 1) is kept for the error code.
    - Peers are leave-one-FAMILY-out. Gold-as-system and ccg2lambda rows are never peers. Timeouts are UNKNOWN units, and their number is reported.
  F3 FUSION CALIBRATION, for the false-alarm rate on CORRECT items (0.19 vs a 0.10 target). The logistic is over [g_score, exact c_score, L2-bow, L3-z3]. It is fitted ONLY on the screen (track L+H), on items where the solver label and the adjudicated screen label AGREE, so that neither shared-instrument confound drives the weights. The threshold is set on screen CORRECT items from LLM systems only. Weights and threshold are frozen in prereg before any held-out label is read.
  F4 CANDIDATE B2, executed once (it was never tested, not refuted). z3 builds small worlds that separate the candidate from its typed single-edit mutants. Each world is verbalised by template, and a cheap text-only reader answers TRUE/FALSE/UNDETERMINED from the sentence. It is capped at $2 and screened as a standalone metric and as a 5th fusion feature. If it fails to run again, it is dropped for good.

  LABEL REGIMES. The claim counts only if it survives all of them; labels are never judged by the metric.
  R_AB: dataset E tiers A+B, excluding CONTESTED and reading_choice (the card's primary pool).
  R_A: tier A only, solver vs audited/repaired reference. It is testable in L20 and EXC; sign-only elsewhere.
  R_ADJ: a NEW calibrated, reference-aware adjudicator.
    - A frontier family that is neither a generator nor a metric judge (Anthropic Sonnet-class) sees the sentence, the candidate and the reference.
    - It adjudicates a stratified sample of ≤1,200 E rows: every solver-vs-panel disagreement, and tier-B and L25 rows over-sampled.
    - It also adjudicates the ~70 screen disagreement items.
    - Gate: balanced accuracy ≥0.85 on the 96 expert track-H pairs + 77 gate items, separately ≥0.80 on faithful and on unfaithful items. If it fails the gate, R_ADJ is dropped and reported.
  R_COMP: a new COMPOSED-LONG stratum whose references are trusted by construction.
    - About 250 sentences of ≥25 words with ≥3 conditions and unless/except/provided-that templates, composed from short references already verified (TRUSTED_AGREED/GOLD_PANEL_OK, FOLIO-refined ∩ DSAVlab agreed). Both weak and strong exception readings are accepted.
    - Candidates come from the same 10 generator slots (real outputs, not perturbations).
    - VOCAB_GRAN rows go to R_ADJ. It is a separate stratum, never pooled with real sentences. It exists because in L25 tier A is untestable and the panel rejects 85% of references.
  The disagreement between regimes is itself reported: how much each metric's AUROC moves between R_AB and R_ADJ, and in which direction.

  SCREEN vs CONFIRMATION (strict).
  SCREEN: track L/H (753 + 302 items) with both label sets. It is used for all fitting, thresholds and fix selection.
  CONFIRMATION: dataset E (700 sentences, 8,507 rows; L25 176C/697E, L20 229/592, EXC 222/384, CTRL 237/149 in A+B), plus R_COMP. It is scored ONCE with frozen weights. If confirmation fails, PEER+TEXT is dead. There will be no subgroup hunting on E.

  BASELINES, run on E with the same item ids (all requested ones):
  - parse rate, with unparseable outputs as errors and in the denominator;
  - the pilot structural metrics;
  - round-trip NLI (API and local verbaliser) and embedding similarity;
  - cheap judge, original and disguised, on all decided rows (about $0.3);
  - frontier judge, original and disguised, on a stratified 300-row subsample (about $1);
  - SC-5 on a stratified 1,500-row subsample;
  - exact c_score;
  - each FOL-Triage layer;
  - S4 = the cross-fitted combination of all cheap baselines INCLUDING the judge, with fold ids by sentence.

  SUCCESS CRITERIA.
  CONFIRM, all three required:
  (a) PEER+TEXT minus judge_cheap_disg, paired sentence-clustered bootstrap: 95% CI > 0 on pooled E under R_AB AND R_ADJ, and the sign is positive under R_A (pooled L20+EXC tier A).
  (b) The nested cross-fitted ΔAUROC of [S4 + PEER+TEXT] over S4 has a CI > 0 under R_AB and R_ADJ.
  (c) In the L25+L20+EXC long stratum and in R_COMP, the Δ vs the judge is positive with CI > 0 in at least one of them. PEER+TEXT is at least 0.95 of the frontier judge's AUROC on the frontier subsample, at ≤10% of its cost.
  PARTIAL: (a) holds in one regime only, or holds pooled but not in the long strata. It is reported as regime-dependent, with the regime-shift table as the finding.
  DISCONFIRM: the CI includes 0 or is negative in every regime. The judge is then the incumbent for the user, and the crossover table (P1) still says which error mass each cheap signal owns.
  The mechanism claims P1-P4 are scored separately, and each is reported CONFIRMED or REFUTED.
  Power: pooled E has about 860 CORRECT and 1,800 ERROR rows over about 600 sentences, so the paired ΔAUROC MDE is about 0.04 pooled and about 0.07 per testable stratum. Strata below 50/50 are declared untestable before scoring.

  THE USER'S OTHER REQUIREMENTS, delivered in the same pass:
  - item-level AUROC/AUPRC and precision at the frozen threshold;
  - system-level Kendall τ with CI over the 13 E system×variant rows (iteration 1 gave Spearman 0.87 over 9 systems, descriptive);
  - per-error-type sensitivity on real errors typed by minimal repair, plus a typed-perturbation suite of tier-A-verified references with the 12 operators at matched positions;
  - error-type identification accuracy: the g_score unit codes and medoid operators vs the adjudicated repair operators, against the judge's 0-27%;
  - one SHARED rewrite set (exp D's invariance_items.json extended with RENAME), run for every metric;
  - coverage with every failure in the denominator;
  - $ and seconds per item;
  - complexity curves over words, quantifiers, depth, conditions and exceptions;
  - contamination: original vs disguised for every LLM component, with the minimum detectable DiD stated;
  - gold-error and correct-but-not-equivalent rates under R_AB vs R_ADJ (iteration-1 R_AB values: correct-but-not-equivalent 0.16-0.26 per stratum and 0.06-0.43 per system; panel gold-error rate 0.82).
  Deliverables: reusable functions, each with a precise docstring: name_free_align, graded_consensus(text, fol, peers) -> {g_score, support, coverage, unit_codes}, content_accounting, role_questionnaire + l3_compare, peer_text_score(text, fol, peers), world_probe (B2); plus the released labelling tools equivalent_modulo_vocab, minimal_typed_repair and the R_ADJ adjudication prompt.
  Error-type census (formerly C2): it is kept as a DESCRIPTIVE by-product on E under R_ADJ (prediction: polarity ≤20% and coverage ≥40% of repaired errors).
  The synthetic-to-real decomposition (formerly C3): it is reported only descriptively, from the typed-perturbation suite, with no separate budget.
motivation: >-
  The user needs to score (text, FOL) pairs with no gold, and has warned that detecting synthetic perturbations is not the
  target. Two in-step facts reshape the design. (1) Real errors are not where perturbation suites look. After vocabulary alignment,
  polarity-type single edits are about 10% of repairable real errors, while a uniform typed suite (our iteration-2 suite:
  3 of 10 operators) spends 30% of its mass on them. Nearly half of real errors are multi-edit restructurings. Coverage (a
  missing condition, an added property) dominates the rest. (2) Real errors split by what is needed to SEE them. About a quarter
  are visible from the formula alone, as shapes almost no English sentence has (∃x(A→B), glued independent claims, a restrictor
  inside ↔, free variables). Those can be flagged with near-zero false alarms, no text, no LLM and no gold, and the check
  cannot be contaminated. The rest need the text, and a bag-of-words check is too weak for them, so role-level accounting
  or a text-only questionnaire is required. This gives the user three things. First, a cheap, deterministic L1 layer that
  flags a known share of errors with a known false-alarm rate, and that also audits gold: it found an error in the curated
  corrected gold. Second, a principled place to spend small-LLM money (L3), only where L1/L2 are blind. Third, a validation
  recipe (census-reweighted typed perturbations) that says when a cheap synthetic test suite can stand in for real labelled
  errors. That matters because gold is rare and partly wrong (about 36-39% of original FOLIO/MALLS gold, per 2606.02837).
  The long, heavily conditioned stratum the user cares about is now labelable. MALLS-train holds 1,501 sentences of at least
  25 words with 3 or more conditions, and 986 exception-bearing sentences of at least 15 words, which replaces the infeasible
  SARA Prolog. That is where the pilot shows both the biggest risk (L1 false alarms rise at 20 words or more) and the biggest
  opportunity: in the pilot census the COMPOUND share of errors rises from 7/27 (26%) under 12 words to 14/24 (58%) at 20
  words or more, exactly the mass that single-invariant checks and typed perturbations miss.
assumptions:
- >-
  Corrected gold anchors real-error labels well enough once it is itself audited. The pilot shows that the curated gold contains
  residual errors: L1 flagged the corrected vaccine formula ∃x(A→B). Automatic vocabulary alignment over-accepts meaning-changing
  renames: 21/99 is an upper bound, and bag-of-words L2 fires on 4 of those 21. So every VOCAB/GRAN and COMPOUND pair, plus
  a 20% sample of the rest, goes to a 3-family adjudication panel on disguised items. The panel's own accuracy is measured
  first on typed perturbations, split by DOWN and UP position. Curator AMBIGUITY flags define a separate 'reading choice'
  label class that is never pooled with errors.
- >-
  Formula smells mined from annotator errors transfer to LLM errors, at least partly. This is the main risk to C1(a). It is
  tested directly: L1 false alarms are measured per family on verified-correct LLM outputs (equivalent to corrected gold modulo
  alignment, or panel-confirmed), and L1 precision on real LLM errors. If a smell exceeds 3% false alarms for any family it
  is dropped, and that is reported, not tuned.
- >-
  A small LLM that reads only the sentence can fill a fixed role schema (condition vs assertion, force, negation, claim grouping,
  argument order) with ≥ 85% per-field accuracy. This is measured on the gold-derived schema answers of verified items before
  L3 is fused. Because L3 never sees a formula, it cannot copy a memorised gold formula. Contamination is still checked by
  comparing original items with disguised items (entities and predicates renamed).
- >-
  Enough labelled long items exist. MALLS-train gives 1,501 items with at least 25 words and 3 conditions, and 4,539 with
  at least 20 words and 3 conditions (probes/complexity_counts.out.txt). Its GPT-4 gold is noisy, so a stratified 600 are
  relabelled by the panel. FOLIO-refined (19 such premises) and ProverQA-hard (0 long conditioned sentences among 8,948) cannot
  fill this stratum. A stratum is tested only if it holds at least 50 errors AND at least 50 correct outputs.
- >-
  The z3 fragment covers the data. 8 of 302 curated corrected formulas fail our parser, and 334 of 27,284 MALLS-train formulas
  fail. Every unparseable output is counted in the denominator as a coverage failure. Timeouts are labelled UNKNOWN and never
  merged with proofs.
investigation_approach: >-
  COMPONENT MAP (layer: target error types; pilot reach on real human errors; calibration status). L1 lint: GLUE/UNGLUE, RESTR,
  BIND/free variable, ∃→ and ↔-restrictor structure, well-formedness; 47% of structural/polarity-type, 28% of compound, 12%
  of coverage errors; 1.7% false alarms on gold, still to be calibrated per LLM family. L2 accounting: ADD/DROP coverage,
  constants, predicate substitution; bag-of-words form 32% of coverage errors at 8.5% false alarms (paired AUROC 0.58); role-aware
  form not yet probed. L2 polarity/slot rules: NEG/REV/QUANT/SWAP; iteration-2 anchor 0.86-0.88 on synthetic REV/∀→∃, but
  polarity-type is only 10% of real repaired errors. L3 questionnaire: conditions vs assertions, claim grouping, force and
  order, aimed at COMPOUND and coverage; not yet probed, gated on ≥ 85% per-field accuracy. ARTIFACT PLAN (each executor has
  ≤ $10 of OpenRouter spend, tracked after every call; costs are estimated before each sweep). STEP 0, PRE-REGISTRATION: freeze
  the smell list, the L2 rules, the L3 schema, the thresholds, the splits, the strata and the analyses before any LLM-output
  label is seen. Go/no-go gate per component: ≤ 10% false alarms on verified-correct outputs in every length stratum, otherwise
  the component is dropped and the drop is reported. STEP 1, META-EVALUATION SET (dataset artifact, ≈ $8). (a) HUMAN TRACK:
  the curated FOLIO-validation conclusions and MALLS-test subset (302 items; 99 non-equivalent original→corrected pairs),
  plus a natural SPECIFICITY set: sentences shared between yfxiao/folio-refined and the DSAVlab-corrected FOLIO, i.e. two
  independent 'correct' annotations, whose non-equivalent pairs must classify as VOCAB/GRAN/CONVENTION or as a residual gold
  error confirmed by the panel. (b) LLM TRACK: about 1,500 sentences stratified by complexity (FOLIO-refined sentences, MALLS-test,
  and a stratified 600 from MALLS-train, oversampling those with at least 20 words, 3 or more conditions or exception markers).
  Candidates come from at least 8 distinct model families on OpenRouter, from small to frontier, each zero- and few-shot,
  plus ccg2lambda (kenken6696/folio_by_ccg2lambda) and the Logic-LM released FOLIO outputs. (c) SEMI-SYNTHETIC COMPOSED items:
  2-4 verified short gold rules nested under 'unless / provided that / except where' templates, with gold derived under both
  weak and strong exception readings. They form a separate stratum and are never pooled with real-error AUROC. (d) TYPED PERTURBATIONS
  of verified gold with the same 12 operators as the census, at matched DOWN/UP positions. (e) MEANING-PRESERVING REWRITES:
  STRICT (renaming, reordering, De Morgan, prenex, contrapositive) and CONVENTION (⊕/∨, weak/strong exception, →/↔ for 'means',
  added sortal restrictor, lexical negation). STEP 2, LABELS AND THEIR BIAS: z3 equivalence to corrected gold → equivalence
  modulo vocabulary (aligner, merge/split and arity-reification bridges) → minimal typed repair (depth ≤ 2, fingerprint-prefiltered,
  z3-verified; code in probes/repair_census.py) → panel adjudication of VOCAB/GRAN/COMPOUND plus a 20% sample. Report precision
  and recall of the automatic vocabulary classifier against the panel, the gold-error rate (including residual errors in corrected
  gold, L1-assisted), the correct-but-not-equivalent rate, the reading-choice rate, and every AUROC under naive, vocabulary-corrected
  and adjudicated labels. STEP 3, CENSUS (C2): minimal-typed-repair classes for human and LLM errors, per family and per complexity
  stratum, with bootstrap CIs. Include a χ² test against the uniform mix of standard perturbation suites and against each
  other. Specificity control: the same classifier on panel-confirmed correct-but-non-equivalent pairs; report error-vs-correct
  contrasts, not raw shares. STEP 4, REUSABLE FUNCTIONS (experiment artifact), each with a precise docstring: fol_lint(fol)
  → smell codes; content_accounting(text, fol); role_accounting(text, fol) (UD roles with generic-subject repair, DOWN-anchor
  polarity, slot order); formula_role_profile(fol) (solver-exact schema answers); role_questionnaire(text) (small LLM, text
  only; cost of about $0.0003 per item); fol_triage(text, fol) → {p_error, fired_layer, codes, coverage_status}; equivalent_modulo_vocab(a,
  b) and minimal_typed_repair(cand, ref), which are the labelling tools released with the dataset. STEP 5, BASELINES: parse
  rate; the pilot's structural metrics (joint-load conflicts, arity consistency, undefined predicates, rerun Jaccard); round-trip
  (a cheap LLM verbalises, then NLI and embedding similarity to the source, plus re-formalise-and-z3-equivalence); a cheap
  LLM judge on all items and a strong judge on a 300-item stratified subsample; K=5 sampling self-consistency modulo vocabulary;
  and a DECOMPOSED judge that sees the formula and is asked the L3 questions, which isolates what solver-exact answering adds.
  STEP 6, ANALYSES (evaluation artifact). Item level: AUROC, AUPRC and precision at the pre-registered threshold. Incremental
  value: nested logistic models with bootstrap ΔAUROC over the best baseline combination, plus partial correlations. System
  level: Kendall τ over families (prompt variants averaged) with a CI, reported descriptively, and over all variants. Per-error-type
  sensitivity by census class. Invariance: false alarms per rewrite family. Coverage, with every failure in the denominator.
  Cost in $ and seconds per item. Complexity: AUROC and false alarms against length, quantifier count, nesting depth, number
  of conditions and number of exceptions. A competing-effects test asks whether the cascade's slope is less negative than
  the judge's. Contamination: judge and round-trip accuracy on original vs disguised items. C3 decomposition: for each non-degenerate
  metric, MIX, WITHIN-TYPE and NOISE terms with paired bootstrap CIs; no τ-across-metrics test. Power: with about 300 errors
  and 300 correct outputs per pooled comparison, the AUROC SE is about 0.02 and the minimum detectable paired ΔAUROC is about
  0.05. Per stratum (≥ 50/50), the MDE is about 0.10; strata below that are declared untestable in advance.
success_criteria: >-
  C1 CONFIRM: (a) L1 precision ≥ 0.8 on real LLM errors, with false alarms ≤ 3% on verified-correct outputs of every model
  family for sentences under 20 words, and a reported, length-conditional false-alarm rate at 20 words or more. (b) The fused
  cascade's ΔAUROC over the best baseline combination has a 95% CI > 0 on adjudicated labels. (c) The cascade reaches AUROC
  ≥ 0.9 × the strong judge's at ≤ 5% of its cost, or beats it in the top complexity stratum. C1 PARTIAL: L1+L2 alone give
  a pre-filter with precision ≥ 0.8 that covers ≥ 25% of real LLM errors (the pilot on human errors shows 27% for L1 at 1.7%
  false alarms), but no ΔAUROC over the judge. This ships as a free first pass, with the remaining error mass stated. C1 DISCONFIRM:
  L1 precision < 0.6 on LLM outputs (the smells do not transfer from annotators to LLMs), AND the ΔAUROC CI includes 0 in
  every stratum. This is reported as a clear negative for structure-only gold-free checks, and the per-layer oracle-vs-deployable
  gap shows whether the checks or the text instruments failed. C2 CONFIRM: on LLM outputs, polarity-type operators ≤ 20% of
  repaired errors (CI upper bound < 0.25), coverage operators ≥ 40%, and the mix differs from uniform (χ² p < 0.01). The classifier
  labels ≥ 80% of panel-confirmed correct-but-non-equivalent pairs as non-errors (specificity control). Human-vs-LLM mix differences
  are reported either way. C2 DISCONFIRM: polarity-type ≥ 35% on LLM outputs, meaning LLMs err differently from annotators.
  This reverses the design priority back toward polarity anchors, and is reported as such. C3 CONFIRM (MIX-dominant): for
  ≥ 2/3 of non-degenerate non-LLM metrics, census-reweighted synthetic sensitivity is within ±0.10 of real sensitivity on
  clean labels. The result, 'typed perturbations are a valid proxy once reweighted by a real-error census', is actionable.
  C3 ALTERNATIVE: the reweighted prediction misses by more than 0.10. Per-operator WITHIN-TYPE ratios are then reported as
  the finding, e.g. that real DROPs remove the least salient condition. In every outcome the label-noise term is reported
  separately, so no gap is attributed to metrics that noise alone explains.
related_works:
- >-
  Fixing FOLIO and MALLS (arXiv 2606.02837; HF DSAVlab-UNIUD). It re-annotates the gold: about 39%/36% wrong; 10.5%/32% syntactic/semantic
  on FOLIO and 3%/39% on MALLS; 7 ambiguity categories with per-item flags. We use its original→corrected pairs as real errors
  with known fixes and add what it lacks: a minimal-typed-repair census after alignment, a detectability split (text-free
  vs text-needing), and an audit showing residual errors in the corrected gold.
- >-
  Thatikonda et al. 2024 (arXiv 2409.16461). It categorises real LLM NL→FOL errors, builds perturbations from them and trains
  a verifier/corrector with gold-based supervision. Ours is gold-free at test time, classifies by minimal typed repair modulo
  vocabulary rather than by annotator categories, and measures how far synthetic sensitivity predicts real sensitivity (C3).
- >-
  Mutation testing: Just et al. FSE 2014 ('Are mutants a valid substitute for real faults?'); Papadakis et al. ICSE 2018 (weaker
  once suite size is controlled); Brown et al. FSE 2017 ('wild-caught mutants' mined from real bug fixes). They establish
  the synthetic-vs-real question and operator mining for code. We do not claim that phenomenon. We claim the first MIX / WITHIN-TYPE
  / NOISE decomposition for formal-translation metrics, and a census-reweighting recipe validated on real NL→FOL errors.
- >-
  Summarization factuality: Goyal & Durrett NAACL 2021 (synthetic error data do not match real model errors), FRANK (Pagnoni
  et al. NAACL 2021: typology census, then per-type metric sensitivity), Tang et al. ACL 2023 (error types shift across summarizers).
  Same census-then-sensitivity logic, for text-to-text. In FOL the 'answer key' side can be computed EXACTLY by a solver (L3),
  and a whole error class is visible with no text at all (L1). Neither is possible for summaries.
- >-
  QA-based factuality metrics (QAGS, Wang et al. ACL 2020; QuestEval, Scialom et al. EMNLP 2021). They ask the same questions
  of source and output with QA models. L3 borrows the idea but uses a FIXED, census-derived role schema, a text-only small
  LLM on one side and a solver-exact answerer on the other, so the formula side has zero model error.
- >-
  Static-analysis bug patterns and fix mining (FindBugs; Getafix, Bader et al. OOPSLA 2019) and vacuity detection in model
  checking (Kupferman & Vardi). L1 is a lint for logic translations: smells chosen from real annotator corrections, including
  solver-checked vacuity and triviality. The new element is its validation as a faithfulness flag with a measured false-alarm
  rate, and its use to audit gold.
- >-
  CLOVER (Ryu et al. ICLR 2025), roundtrip verification (arXiv 2604.25031), sampling-based symbolic consensus (arXiv 2410.20936;
  Grammars of Formal Uncertainty, NeurIPS 2025). These are gold-free checks via distinguishing interpretations, back-translation
  or agreement. They are baselines here, and part of the C3 decomposition.
- >-
  Brunello et al. AAAI 2026 (arXiv 2511.11816, same group as 2606.02837) and FOL closeness-metric sensitivity (arXiv 2501.08613).
  They run perturbation studies of GOLD-based metrics. C3 asks whether such perturbation sensitivity predicts real-error sensitivity,
  for gold-free metrics.
- >-
  The Signal-Coverage Matrix (arXiv 2606.28013, Lean 4) crosses type-checking with gold-free semantic judges (an Opus judge
  and GTED) on real outputs. Closest in spirit for real-error evaluation, but for Lean statements, without a repair census
  or a text-free layer, and with the judges calibrated against each other rather than against adjudicated labels.
- >-
  SyGNS (Yanaka et al. 2021) and Udep2Mono (Chen & Gao 2021). SyGNS is gold-based polarity comparison, which is our oracle
  polarity. Udep2Mono is the text-side polarity marker. We showed in iteration 2 that Udep2Mono conflicts with FOL restrictor
  conventions, and we repaired that; polarity now serves as one L2 rule.
inspiration: >-
  Three imports, each chosen because it directly fixes a measured failure. (1) SOFTWARE STATIC ANALYSIS: linters flag code
  that is almost never intended, without knowing the spec. Bug patterns are mined from real fixes (FindBugs, Getafix, wild-caught
  mutants). Applied to logic, some formulas are almost never what English means, so they can be flagged without reading the
  text. The pilot: 27% of real errors, 1.7% false alarms. (2) CLINICAL SCREENING CASCADES: a cheap, high-specificity test
  runs first, and costlier tests run only where the cheap one is blind, each with its false-positive rate fixed on known negatives.
  That fixes the compounding false alarms of iteration 1 and spends LLM money only on the error mass L1/L2 cannot see. (3)
  SUMMARIZATION FACTUALITY and MUTATION-TESTING methodology: census real errors first, then weight synthetic tests by that
  census (FRANK; Just et al.). In FOL this becomes testable exactly, because the minimal repair between a candidate and a
  reference can be SEARCHED and PROVED with a solver instead of annotated by hand.
terms:
- term: FOL-Triage
  definition: >-
    The proposed gold-free metric: L1 formula lint (no text), L2 text accounting (no LLM), L3 text-only role questionnaire
    (small LLM) compared with solver-exact formula answers. The three are fused into P(unfaithful), with the firing layer
    and an error code.
- term: Formula smell (lint rule)
  definition: >-
    A deterministic formula-only pattern that almost no English sentence means, e.g. ∃x(A→B), ∀x(A∧B), a restrictor inside
    ↔, glued independent claims, a free variable, an arity clash, a vacuous predicate, or a valid/unsatisfiable formula.
- term: Minimal typed repair
  definition: >-
    The smallest set of typed edits (NEG, REV, QUANT, RESTR, CONN, MOVE, DROP, ADD, SWAP, BIND, SCOPE, UNGLUE) that makes
    a candidate provably equivalent (z3) to the corrected gold after vocabulary alignment. More than 2 edits, or no repair
    found, is COMPOUND. It defines the error type of a real error.
- term: Vocabulary alignment
  definition: >-
    Renaming candidate predicates and constants onto reference ones (same arity, token/character similarity), plus merge/split
    and arity-reification bridges. Equivalence after alignment means VOCAB/GRAN, i.e. not an error. It is an upper bound,
    because meaning-changing renames also align, so it is adjudicated.
- term: Reading choice
  definition: >-
    A correction on a sentence the curators flagged ambiguous, where the gold picks one legitimate reading. It is a separate
    label class, not an error.
- term: Transfer decomposition (MIX / WITHIN-TYPE / NOISE)
  definition: >-
    A metric's synthetic-minus-real sensitivity is split into three parts. MIX: per-type synthetic sensitivity reweighted
    by the real census. WITHIN-TYPE: the same operator, synthetic vs real. NOISE: naive vs adjudicated labels.
- term: Solver-exact answerer
  definition: >-
    z3 queries that read role facts off a formula exactly: per-predicate monotonicity (DOWN = condition, UP = asserted), quantifier
    force per claim block, connectivity components (independent claims) and argument slots.
- term: Correct-but-not-equivalent
  definition: >-
    A faithful candidate that is not logically equivalent to gold because of vocabulary, granularity or a legitimate convention.
    It is estimated by alignment plus panel adjudication.
summary: >-
  FOL-Triage is a three-layer gold-free faithfulness check for NL→FOL: a text-free formula lint, LLM-free text accounting
  and a text-only small-LLM role questionnaire answered exactly by a solver on the formula side. In-step, the lint alone flagged
  27% of real annotator errors at 1.7% false alarms, and found an error in curated gold. The hypothesis also covers a minimal-typed-repair
  census of real errors (coverage dominates; polarity is about 10%; 46% compound) and a MIX/WITHIN-TYPE/NOISE decomposition
  of why synthetic perturbation tests overstate metric quality.
alternates:
- title: Text judges truth in solver-built worlds
  hypothesis: >-
    z3 builds small models that separate the candidate from its own typed single-edit mutants (the census operators). Each
    model is verbalised by template, and a small NLI model judges whether that situation is consistent with the text. The
    mismatch rate predicts real errors, including COMPOUND ones, with no gold and no large LLM.
  why_it_could_win: >-
    46% of real errors are compound restructurings that no role field isolates. A truth-value judgement on concrete situations
    sees any behavioural difference through one mechanism. It beats FOL-Triage if the small NLI model judges templated worlds
    with at least about 85% accuracy on long conditioned sentences.
- title: Agreement across systems by repair distance
  hypothesis: >-
    For each sentence, several diverse systems' outputs are aligned modulo vocabulary. A candidate's minimal-typed-repair
    distance to the cross-system medoid (0 = equivalent, 1-2 = typed edit, 3+ = compound) is its error score, and the repair
    operators give the error type.
  why_it_could_win: >-
    It needs no text-side instrument at all, which removes the weakest link (L2 bag-of-words AUROC was 0.59). It wins if errors
    are idiosyncratic across model families. It loses where families share a blind spot or a reading choice, which the census
    measures.
- title: Template verbalisation plus bidirectional entailment
  hypothesis: >-
    A deterministic, non-repairing FOL→English template verbaliser, plus a small NLI model checking entailment in both directions
    against the source, predicts faithfulness. Missing content fails text→formula entailment, and added content fails formula→text
    entailment.
  why_it_could_win: >-
    Coverage operators are 57% of repairable real errors, and bag-of-words accounting is weak on them. If NLI handles templated
    logical English, it captures coverage in context, which bag-of-words matching cannot, without any alignment step.
- title: A disguised cheap judge is enough
  hypothesis: >-
    A cheap LLM judge, shown the sentence and the formula with every predicate and constant renamed to neutral tokens (so
    memorised gold cannot help), matches the strong judge. Neither the lint nor the questionnaire adds signal over it.
  why_it_could_win: >-
    If current small LLMs already recognise ∃x(A→B)-style shapes and dropped conditions, structure adds nothing and the cheapest
    reliable metric is the judge. C1(b)'s ΔAUROC test decides between them directly.
_relation_rationale: >-
  FOL-Triage becomes one half of a peer+text fusion; consensus lead is the other half, tested label-robustly
_confidence_delta: decreased
_key_changes:
- >-
  Verdict corrected (reviewer MUST-FIX): no candidate passed the pre-registered rule. On 389 common label-consistent items,
  c_score vs judge is +0.057 [-0.022, 0.137] and fused vs judge is -0.020 [-0.111, 0.074]. The disguised cheap judge (0.777)
  is the incumbent.
- >-
  The ranking is label-dependent (MUST-FIX). On adjudicated screen labels (tier A+B, n=304), fused is 0.872 vs judge 0.771
  and c_score 0.776. The solver-to-panel transitions are 58 CORRECT->ERROR vs 1 the other way. So 'VOCAB = CORRECT' is flagged
  as the biggest label risk, replacing the claim that ADD+DROP errors are 'likely CORRECT'.
- >-
  Move = DEEPEN on the two leads (FOL-Triage text layers; cross-family consensus), merged into one complementary PEER+TEXT
  fusion. The mechanism is explicit: peers see family-specific structure errors (polarity blind spot 5%), and text sees shared
  errors and renames (38% of errors are peer-endorsed).
- >-
  New pre-registered mechanism tests P1-P4: per-type crossover at matched FA, disjointness of the two signals among errors,
  the length slope (exact consensus -0.94/SD words vs graded consensus vs judge), and rewrite invariance on ONE shared rewrite
  set.
- >-
  Fix F1: name-free structural alignment (arity, monotonicity, block, argument graph, optional text anchor), verified by entailment.
  It targets c_score's RENAME 96% false alarms and removes the shared-align() confound with the labeller.
- >-
  Fix F2: graded clause-level consensus (support/coverage entailment F1 against peers). It targets the saturation of exact
  equivalence on long sentences and yields ADD/DROP/NEG/QUANT codes with location, which is the user's error-type ask.
- >-
  Fix F3: fusion weights fitted only on screen items where the solver and adjudicated labels agree; threshold set on LLM-system
  CORRECT items (the iteration-1 FA was 0.19 vs 0.10). Frozen before E labels are read.
- >-
  Label robustness is now part of the claim. Regimes: R_AB (panel), R_A (tier A), R_ADJ (a new reference-aware frontier adjudicator
  from a family that is neither generator nor judge, gated at balanced acc ≥0.85 on the 96 expert pairs + 77 gate items),
  and R_COMP (a composed-long stratum with references trusted by construction, because L25 tier A is untestable).
- >-
  Dataset E is used as CONFIRMATION only (frozen weights, scored once). The screen (track L/H) is used for all fitting. There
  is no subgroup hunting if confirmation fails.
- >-
  Every requested baseline is re-run on E with the same ids, including S4 = all cheap baselines + judge (nested ΔAUROC). The
  frontier judge is included, because iteration 1 showed +0.077 [0.006, 0.154] on original text that vanished under disguise,
  at a cost above the gate.
- >-
  Candidate B (B1/B2) was planned but never executed (exp 2 is empty). B2 (solver worlds judged by a text-only reader) gets
  one capped ($2) execution as a standalone metric and a fusion feature; it is dropped if it breaks again.
- >-
  Closed with no further budget: L1 lint on LLM outputs (0.508, but kept as a free gold-audit tool), L2-role (0.557), the
  user's pilot structural metrics (0.50-0.53, a negative result), and round-trip re-formalisation (0.513).
- >-
  Reframed as confirming prior work, not novel: consensus beating self-consistency (+0.140) confirms SAC3. The new contribution
  is the solver-graded, name-free clause consensus with typed localisation, and its complementarity with solver-exact text
  checks under label-robust validation.
- >-
  Descriptive by-products with no separate budget: the census (formerly C2) and the synthetic-to-real decomposition (formerly
  C3). The typed-perturbation suite is kept for the user's per-type sensitivity requirement.
_evidence_state: lead
_move: deepen
_move_rationale: >-
  Leads, no genuine positive: consensus and text layers each beat the judge under only one label regime. Fuse them, fix alignment
  and length saturation, and confirm on held-out E under all regimes.
_coverage: full
_coverage_statement: >-
  Iteration 2 answers the core ask: a gold-free (text, FOL) metric that predicts faithfulness and names the error type. It
  is tested against every requested baseline, including the judge, on held-out real LLM outputs, with rewrite invariance,
  coverage, cost and the long heavily-conditioned stratum.
_candidates_considered: 11
relation_type: embedding
</current_hypothesis>

<all_artifacts>
Complete set of research artifacts across all iterations.

--- Item 1 ---
id: art_d0njuqy2Csj-
type: experiment
title: Screening a three-layer logic-translation checker
summary: >-
  FOL-Triage wide screen (iter-1 exp A), all under this workspace. Frozen shared screen: screen_items.json (track L = 753
  Logic-LM FOLIO-dev outputs of gpt-3.5/gpt-4/davinci-003 vs DSAVlab corrected gold, 112/202 conclusions + 271 agreed premises;
  track H = 302 curated original->corrected), href_items.json, invariance_set.json, screen_meta.json; item_id=sha1(system|norm(text)|fol)[:16]
  for joining with sibling experiments. Labels (iter-3 repair census, xor precedence fixed): L CORRECT 278 / ERROR 199 / UNCERTAIN
  204 / UNPARSEABLE 60; 59% of ERRORs are pure ADD+DROP vocabulary artefacts (needs panel adjudication). Released functions
  in src/fol_triage.py: fol_lint (L1), content_accounting (L2-bow), role_accounting (L2-role), formula_role_profile + role_questionnaire
  (gemini-2.5-flash-lite, text only) + l3_compare (L3); fused logistic fitted on track H with sentence-leak guard, frozen
  in prereg.json before track-L labels. PRIMARY (L ERROR vs CORRECT, n=477, 199 pos): fused AUROC 0.759 [0.695,0.825]; L2-bow
  0.737; L3 0.756; L2-role 0.557; L1 0.508 (lint does not transfer to LLM outputs; 0.655 on track H); fused-L2bow +0.022 CI
  [-0.019,0.061] not significant; decomposed judge (LLM reads formula instead of z3) lowers L3 AUROC by 0.059 (sig.); nonce-disguise
  shows no contamination (0.765 vs 0.770). Gates: AUROC/coverage 0.92/cost $0.0002 pass; rewrite-FA FAILS (0.275; originals
  flagged at same rate, fused FA on L CORRECT 0.19 vs 0.10 calibrated on H; flip rate <=0.06). Long/conditioned strata UNTESTABLE
  on this screen. L3 gate on HREF: role .91, claims .86, missing .92, extra .92 gated; force .69 excluded. Robustness rows:
  qwen3-30b and local Qwen2.5-1.5B (OpenRouter outage fallback). Headline AUROCs re-derived independently (results/audit_rederive.json,
  placebos ~0.5). Judge/round-trip/self-consistency baselines are NOT here (experiments C/D; join on item_id in iteration
  2). Outputs: method_out.json (exp_gen_sol_out; predict_fol_triage + per-layer predict_* per item), results/metrics.json,
  results/per_item.jsonl, README.md. Spend $0.29.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_u75jRHUss0zo/3_invention_loop/iter_1/gen_art/gen_art_experiment_1
out_expected_files:
- method.py
- full_method_out.json
- mini_method_out.json
- preview_method_out.json

--- Item 2 ---
id: art_i3cVDxBp-USk
type: experiment
title: Do other models' translations agree? Consensus metric for NL-to-logic
summary: >-
  Experiment 3 screens candidate C, a text-free, gold-free consensus metric for NL->FOL faithfulness, on the shared frozen
  screen (label hash 0e43cbdd...). c_score = 1 - eq_frac: the share of OTHER systems' translations of the same sentence that
  are NOT z3-equivalent to the candidate modulo vocabulary alignment. The pool has 6 fresh OpenRouter families (llama-3.3-70b,
  qwen3-235b, deepseek-v3.1, mistral-small-3.2, gemini-2.5-flash-lite, gpt-4.1-mini) plus the 3 released Logic-LM systems,
  leave-one-out. Also scored: medoid repair depth and operators, and semantic entropy over z3 classes. Baselines: K=5 self-consistency
  (gpt-4.1-nano T=0.7 on all items; true same-model gpt-3.5-turbo SC for gpt-3.5 candidates), predicate-set stability, and
  FOL length. PRIMARY (track L, 297 CORRECT vs 249 ERROR, sentence-clustered bootstrap 2000): c_score AUROC 0.866 [0.821,
  0.906]; peers-only 0.872; non-OpenAI peers 0.863; other Logic-LM systems only 0.753; cluster entropy 0.773; medoid depth
  0.722; sc5_cheap 0.725 [0.669, 0.781] (n=546, now complete). Paired Δ c_score - sc5_cheap = +0.140 [0.085, 0.197]; c_score
  - sc5_same = +0.140 [0.057, 0.227] (n=167). Cross-fitted [c_score, sc5] vs [sc5] = +0.147. Vocab-clean subset (shared-aligner
  confound control): c_score 0.852 vs SC 0.714. At the medoid threshold: recall 0.62, false alarms 0.14. Shared blind spot:
  38% of errors are endorsed by the consensus (POLARITY 5%, COVERAGE 41%, STRUCT 57%). Repair operators match the labeller's
  81% of the time (chance 46%). RENAME rewrites cause 96% false alarms (the aligner does not survive synonym or constant renaming);
  z3-equivalent rewrites flip 0% by construction. Long/conditioned stratum n=5, descriptive only. Cost: $1.52 total; the peer
  pool costs $0.0015 per sentence. This re-run completed the SC_cheap arm that the shared-key limit had cut to 231/307 units,
  and restored WordNet for RENAME.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_u75jRHUss0zo/3_invention_loop/iter_1/gen_art/gen_art_experiment_3
out_expected_files:
- method.py
- full_method_out.json
- mini_method_out.json
- preview_method_out.json

--- Item 3 ---
id: art_elDZY26Pu6GD
type: experiment
title: Cheap LLM judge and baseline scores for logic translations
summary: >-
  Experiment D (baseline/null arm) on the SHARED FROZEN SCREEN: data/screen_items.json, 1,090 items. Track L = 796 Logic-LM
  FOLIO-dev outputs labelled vs corrected gold or agreed premises: 294 CORRECT / 230 ERROR / 216 UNCERTAIN / 56 UNPARSEABLE.
  Track H = 294 curated original-vs-corrected items. Label-vector sha1 122d01df... FINAL judges are the planned API models,
  under prereg.json: judge_cheap = gemini-2.5-flash-lite (JSON 0-100, rubric A), judge_cheap2 = gpt-4.1-nano (P(YES)), judge_strong
  = gemini-3.1-pro-preview (frontier; 200L+96H subset). Open-weight local judges (Qwen3-8B, Llama-3.1-8B, Qwen3-14B-nf4; run
  during a key outage) are kept as judge_local_* rows. API spend $2.02. Track L AUROC [95% CI]: judge_cheap_disg 0.777 [0.720,
  0.827] = THE BAR; judge_cheap_orig 0.749; gpt-4.1-nano 0.750/0.714; frontier orig 0.802 on the subset, which is +0.077 [0.006,
  0.154] over the cheap judge on the same items (DeLong p=.015), with the gap vanishing under disguise; rt_nli_min 0.710 (API
  verbaliser) / 0.740 (local verbaliser); rt_embed_cos 0.633; rt_reformalise_eq 0.513 (near chance). User's pilot structural
  metrics are 0.50-0.53 (a negative result); cross-system rerun Jaccard 0.720. The cross-fitted S4 combination of all cheap
  baselines has OOF AUROC 0.817 [0.762, 0.867], which is +0.039 [-0.010, 0.087] over the judge (not significant). best_baseline_oof
  per item and data/folds.json are provided for nested deltas in iteration 2. Contamination: no evidence. Every DiD CI includes
  0; the frontier judge loses ~0.07 under disguise on both tracks (lost lexical meaning); the recall probe matches the corrected
  gold 15.9% vs the erroneous original 4.4%. Invariance: the judges false-alarm on contrapositive (cheap 0.67, nano 0.97),
  De Morgan and rename rewrites. Judge correctness falls with sentence length (p=1.6e-5); long sentences are untestable on
  track L. Label noise: 56% of L ERRORs are subst_only; results/judge_label_disagreements.csv is there for dataset-E adjudication.
  All headline numbers were re-derived independently, with placebos, in results/audit_headlines.json. Outputs: method_out.json
  / full_method_out.json (workspace root; also results/method_out.json) (predict_* = oriented scores), results/analysis.json,
  results/summary.md.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_u75jRHUss0zo/3_invention_loop/iter_1/gen_art/gen_art_experiment_4
out_expected_files:
- method.py
- full_method_out.json
- mini_method_out.json
- preview_method_out.json

--- Item 4 ---
id: art_U4Hsqt4Ay9Tg
type: dataset
title: Held-out logic translation test set, panel-checked
summary: >-
  Held-out NL->FOL faithfulness meta-evaluation set (run_u75jRHUss0zo, iter 1, dataset E). full_data_out.json (exp_sel_data_out,
  27.7 MB) has 4 groups. (1) heldout_candidates: 8,507 rows = real FOL candidates for 700 screen-disjoint sentences. Strata:
  MALLS-train L25=300 (>=25 words, >=3 conditions; includes a pre-registered 100-sentence top-up), L20=150, EXC=100 (unless/except/without),
  and FOLIO-train CTRL=150. Generators: 10 LLM slots over 9 families, few-shot at temperature 0; zero-shot Llama-70B/Qwen3;
  GPT-5.1 on 200 sentences; ccg2lambda; the MALLS GPT-4 gold as a system. input=JSON{text,candidate_fol,reference_fol,system,prompt_variant};
  output=CORRECT/ERROR/CONTESTED/UNRESOLVED/UNPARSEABLE. Labels combine the shared z3 solver labeller with a blind, nonce-disguised,
  family-disjoint panel (Haiku-4.5/GLM-4.6/Kimi-K2; Haiku adjudicates only GLM/Kimi disagreements). The combination rule gives
  tier A (solver), B (panel-decided VOCAB_GRAN/COMPOUND) and C (no trusted reference). Metadata per row: sentence_id (bootstrap
  cluster), item_id, strata {words,n_quant,depth,n_conditions,exception_type,source_stratum,l25_topup_batch}, auto_label,
  repair_ops, panel_votes, error_ops, label_tier, reference_status, correct_not_equivalent, reading_choice, disguised_text/fol.
  Tier A+B testable: L25 176 CORRECT/697 ERROR; L20, EXC and CTRL are also testable. (2) heldout_sentences: 700 rows with
  reference status (GOLD_PANEL_OK 95, PANEL_REPAIRED 145, NO_TRUSTED_REFERENCE 295, TRUSTED_AGREED 36, DISPUTED 112). (3)
  panel_calibration: 77 synthetic gate items plus 96 expert track-H real-error pairs with panel votes. (4) screen_audit: 1,173
  Logic-LM track-L and curated track-H rows keyed by the screen's item_id; also in screen_adjudicated_labels.json. Caveats:
  the panel is STRICT. Its majority accuracy on real errors is 0.727, and it accepts only 0.61 of expert-corrected formulas.
  It rejected 82% of MALLS gold, so ERROR is over-called: confirm on tier A too. HELD-OUT: iteration 2 must not tune thresholds
  on it. Primary analysis = tiers A+B excluding CONTESTED and reading_choice, bootstrapped by sentence_id. See dataset_card.md.
  Cost $9.83.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_u75jRHUss0zo/3_invention_loop/iter_1/gen_art/gen_art_dataset_1
out_expected_files:
- data.py
- full_data_out.json
- preview_data_out.json
- mini_data_out.json

--- Item 5 ---
id: art_TaxJRnPcJMuZ
type: experiment
in_dependencies:
- id: art_U4Hsqt4Ay9Tg
  label: confirmation data
title: Peer agreement plus text checks, held-out test
summary: >-
  Held-out confirmation of PEER+TEXT (NL->FOL faithfulness without gold) on dataset E (8,507 candidate rows, 700 sentences),
  frozen on the iteration-1 screen (prereg sha256 b9f28b1b, git a6896ce) and scored once. PEER = graded cross-family consensus
  (claim units, peer aligned into candidate vocabulary, finite-model refuter + z3 entailment; support/coverage/g_score, unit
  error codes); TEXT = iteration-1 L2-bow + L3 (text-only questionnaire vs z3 role profile); fused by a screen-fitted logistic.
  RESULTS (R_AB tiers A+B, 1822 ERR/864 COR): PEER+TEXT AUROC .790 [.75,.82] (stratified .753; long pool .768; tier-A L20+EXC
  .818) vs iteration-1 c_score_align .782, NF-anchored c_score .743, TEXT .693, local Qwen3-8B disguised judge .712. Delta
  vs local judge +.078 [.043,.112] pooled, +.115 long pool, +.075 stratified; CTRL -.031 n.s. The pre-registered flash-lite
  judge bar is UNTESTABLE (shared OpenRouter key hit $0 at 18:00 UTC; the replacement key was also exhausted, polled 19:10-22:13
  UTC; 20 rows); the local judge is a labelled secondary bar. Fusion does NOT beat c_score_align alone (stratified +.011 n.s.;
  tier A c_score_align .860 > .818), and that aligner is shared with the solver labeller (confound open). Name-free alignment
  'failed' the screen gate only through a threshold-tie artefact; post hoc NF-anchored passes (RENAME FA .074, ROLE_PERMUTE
  recall .77) and its fusion gives .759 on E. P1 INCONCLUSIVE (PEER>TEXT on ADD/DROP errors, TEXT>PEER on peer-endorsed),
  P2 REFUTED, P3 INCONCLUSIVE (gap vs judge grows with length, diff-in-delta +.146 CI>0), P4 REFUTED (fused RENAME FA .385).
  Unit-code typing at chance (.37 vs .38). Disguise improves the judge (no contamination benefit). Within-stratum placebo
  .59 (composition), global .50. FILES: results/per_item_E.jsonl (row_key=item_id|prompt_variant, fold_E=sha1('E_folds_v1|'+sid)%5,
  every score) for the iteration-3 join; results/analysis.json, tables.md, p_tests.json, deviations.json, prereg.json; src/peer_text.py
  reusable functions; method_out.json (exp_gen_sol_out, predict_* for all metrics). Audits: tests/audit_rederive.py re-derives
  pooled AUROCs and headline delta to 1e-9; tests/placebo_headline.py (shuffled labels fail); prefilter audit 0 conflicts;
  judge prompt identity 30/30. OpenRouter spend $0.155.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_u75jRHUss0zo/3_invention_loop/iter_2/gen_art/gen_art_experiment_5
out_expected_files:
- method.py
- full_method_out.json
- mini_method_out.json
- preview_method_out.json

--- Item 6 ---
id: art_zcwCQgTqk6DN
type: dataset
title: Long logic sentences and FOL error suite
summary: >-
  Two held-out NL->FOL faithfulness tables (full_data_out.json, aii exp_sel_data_out, every row re-verified against its sources
  by data.py and z3-re-verified by src/verify.py, 0 failures). (1) PERTURB (group perturb_suite, COMPLETE): 4,234 typed mutants
  (metadata_fold PERTURB, output ERROR, error_ops=[op]) plus 868 meaning-preserving controls (PERTURB_CONTROL, output CORRECT).
  They cover 300 bases: 36 TRUSTED_AGREED + 95 GOLD_PANEL_OK + 69 PANEL_REPAIRED dataset-E references, and 100 R_COMP weak
  readings. Operators are NEG, REV, QUANT, RESTR, CONN, MOVE, DROP, ADD (ADD_FOREIGN / ADD_INTERNAL), SWAP, BIND and MEANING_RENAME,
  at DOWN/UP positions (metadata_position_polarity, polarity_method, matched_pair_id; 1,354 complete pairs). QUANT/REV/RESTR
  are UP-only; SCOPE and UNGLUE have 0 rows. Each mutant is z3 non-equivalent to every accepted reading. Controls are RENAME_SYN
  / RENAME_NONCE, REORDER and CONTRAPOSITIVE/DEMORGAN, each z3-equivalent. (2) R_COMP (group rcomp_sentences): 250 main +
  100 reserve templated sentences, each with >=25 words, >=3 conditions and one unless/except/provided-that/only-if clause
  (9 templates). Weak and strong references come from the template (T8 also stores a not-accepted converse), are unit-tested
  and z3-checked, and are built from a 652-entry atom lexicon mined from verified FOLIO/MALLS references. Provenance fields:
  template_id, lexicon_ids, source_rule_ids. CAVEAT: the shared OpenRouter key hit its daily limit 5 minutes in ($0.41 spent);
  the 21:38 UTC replacement key was also already exhausted. Pending: the Sonnet lexicon and reference audits, fluency, generator
  candidates (rcomp_candidates), solver labels, adjudication and the testability declaration. ./run_all.sh completes them
  resumably under the pre-registered prereg_rcomp.json. Until then R_COMP must not be used for metric claims. PERTURB is ready
  for per-operator sensitivity and invariance analysis. Rows carry item_id (E's recipe) and disguised_text/fol. adjudicator_check_out.json
  holds 60 known-label QA items. See dataset_card.md.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_u75jRHUss0zo/3_invention_loop/iter_2/gen_art/gen_art_dataset_3
out_expected_files:
- data.py
- full_data_out.json
- preview_data_out.json
- mini_data_out.json

--- Item 7 ---
id: art_HepAw8c6Eu7-
type: evaluation
in_dependencies:
- id: art_d0njuqy2Csj-
  label: scores
- id: art_i3cVDxBp-USk
  label: scores
- id: art_elDZY26Pu6GD
  label: scores+folds
- id: art_U4Hsqt4Ay9Tg
  label: adjudicated labels
title: Re-checking earlier logic-metric results across label sets
summary: >-
  Zero-LLM-spend, CPU-only re-analysis of the iteration-1 artifacts (exp A FOL-Triage, exp C consensus c_score, exp D judges/baselines,
  dataset E screen adjudication), joined on item_id. eval.py (+src/) writes eval_out.json (exp_eval_sol_out, validated; ~5.9k
  flat metrics_agg keys + structured metadata incl. VERDICT; 1,380 per-item examples with oriented scores, per-regime labels,
  PT OOF), tables/*.csv (each with a '# source:' line), figures/fig_regime_shift and fig_forest_common (json/png/pdf), and
  audit/ scripts. KEY FINDINGS. (1) Re-derivation gate: 57/57 reviewer audit numbers reproduce (n=389/160 err/151 sents; c_score
  .842, fused .767, judge_disg .785; tier A+B n=304 fused .872, bow .817, c_score .776, judge .771). (2) Same-item, same-label
  common sets for 13 regimes (testable: R_SOLVER_CONS n=373/155 err, own-label A/C/D, R_ADJ_AB 298/165, R_ADJ_ALL 498/271,
  CONTESTED->C/E, L_UNPARSEABLE_AS_ERROR 413/195; R_ADJ_A and all track-H regimes are untestable, reported sign-only). (3)
  The iteration-1 rule FAILS for fused_H and c_score in every regime (rewrite FA 0.275 / 0.96). fused_H minus judge is -0.013
  under solver labels but +0.096 [.020,.171] under A+B; c_score minus judge is +0.067 [-.012,.148] under solver labels and
  +0.006 under A+B. (4) Label-only shift solver->A+B on the same 161 items: bow +0.102 and fused +0.080 (CI>0) go up; c_score
  -0.106 goes down. Rank Kendall tau is 0.60. On the 58 flipped items, bow/fused flag 81-83% vs c_score 34% (instrument-sharing
  confirmed). (5) SCREEN PREVIEW: PT (cross-fitted c_score+bow_uncarried+l3) minus judge_cheap_disg is +0.089 [.010,.165]
  solver, +0.104 [.039,.175] A+B, +0.090 [.038,.142] all tiers, +0.118 unparseable-as-error. Nested S4+PT over refit S4 is
  +0.04-0.06 (CI>0). Screen bar that iteration-2 confirmation must beat = these deltas. (6) P1: the structural clause is untestable
  (all QUANT/SCOPE/BIND/SWAP/NEG cells have <15 errors); text beats peers on peer-endorsed errors (CI>0). P2a CONFIRMED only
  for all tiers. P2b depends on the comparator: vs c_score the gain comes from endorsed errors; vs bow it comes from non-endorsed
  errors. (7) At matched FA 0.10 the ORIGINAL cheap judge has higher recall than the disguised one (+0.11/+0.20). Contamination
  DiD CIs include 0 but MDE = 0.12-0.21, so a 0.05 effect is undetectable. Frontier minus cheap under A+B is +0.166. (8) Invariance
  comparisons across A/C/D used different rewrite sets. (9) Candidate B was planned but gen_art_experiment_2 is an empty .aii/
  dir: it never ran. (10) Exp C's -0.94/SD length interaction reproduces exactly. Exp A's L2-bow = n_unanch+uncarried (0.737)
  vs bow_uncarried (0.711). Panel expert-pair acceptance is .613 (unambiguous). Independent re-derivation (different code
  path) matches all headline numbers. On permuted labels the cross-fitted PT is biased below 0.5; the observed deltas exceed
  all 20 null deltas (null max .047 solver / .087 A+B).
workspace_path: >-
  /ai-inventor/aii_data/runs/run_u75jRHUss0zo/3_invention_loop/iter_2/gen_art/gen_art_evaluation_1
out_expected_files:
- eval.py
- full_eval_out.json
- mini_eval_out.json
- preview_eval_out.json
</all_artifacts>

<previous_round_strands>
How you classified the PREVIOUS round's artifacts, one per bet. Use it for the
BROKEN-FIXED-ONCE rule: a bet that was "broken" then and is "broken" again now is
not a defect any more — drop it and give its slot to a new candidate. A "lead" that
you already deepened once and that came back "null" is the one case where widening
off a lead is allowed.

--- Strand 1 ---
artifact: art_d0njuqy2Csj-
state: lead
why: >-
  Fused 0.759 < judge on solver labels (paired Δ -0.020, n.s.) but 0.872 vs 0.771 on adjudicated A+B labels; L3 solver-exact
  +0.059 over LLM reading; L1 0.508 null

--- Strand 2 ---
artifact: art_i3cVDxBp-USk
state: lead
why: >-
  c_score 0.866 own labels, +0.14 over SC (SAC3-known); vs judge on common items +0.057 [-0.022, 0.137]; 0.776 ≈ judge on
  panel labels; RENAME FA 96%; length slope -0.94

--- Strand 3 ---
artifact: art_elDZY26Pu6GD
state: lead
why: >-
  Judge bar 0.777; frontier judge +0.077 [0.006, 0.154] on original text only; judges flip 29-49% on equivalent rewrites;
  S4 0.817 n.s.; pilot structural metrics 0.50-0.53 null

--- Strand 4 ---
artifact: art_U4Hsqt4Ay9Tg
state: lead
why: >-
  8,507 rows, L25/L20/EXC testable A+B; its adjudicated screen labels reverse the ranking. Panel strict (accepts 0.613 of
  expert-correct; rejects 0.822 of MALLS gold); L25 tier-A untestable
</previous_round_strands>

<new_artifacts_this_iteration>
These 3 artifacts were created THIS iteration.

id: art_TaxJRnPcJMuZ
type: experiment
in_dependencies:
- id: art_U4Hsqt4Ay9Tg
  label: confirmation data
title: Peer agreement plus text checks, held-out test
summary: >-
  Held-out confirmation of PEER+TEXT (NL->FOL faithfulness without gold) on dataset E (8,507 candidate rows, 700 sentences),
  frozen on the iteration-1 screen (prereg sha256 b9f28b1b, git a6896ce) and scored once. PEER = graded cross-family consensus
  (claim units, peer aligned into candidate vocabulary, finite-model refuter + z3 entailment; support/coverage/g_score, unit
  error codes); TEXT = iteration-1 L2-bow + L3 (text-only questionnaire vs z3 role profile); fused by a screen-fitted logistic.
  RESULTS (R_AB tiers A+B, 1822 ERR/864 COR): PEER+TEXT AUROC .790 [.75,.82] (stratified .753; long pool .768; tier-A L20+EXC
  .818) vs iteration-1 c_score_align .782, NF-anchored c_score .743, TEXT .693, local Qwen3-8B disguised judge .712. Delta
  vs local judge +.078 [.043,.112] pooled, +.115 long pool, +.075 stratified; CTRL -.031 n.s. The pre-registered flash-lite
  judge bar is UNTESTABLE (shared OpenRouter key hit $0 at 18:00 UTC; the replacement key was also exhausted, polled 19:10-22:13
  UTC; 20 rows); the local judge is a labelled secondary bar. Fusion does NOT beat c_score_align alone (stratified +.011 n.s.;
  tier A c_score_align .860 > .818), and that aligner is shared with the solver labeller (confound open). Name-free alignment
  'failed' the screen gate only through a threshold-tie artefact; post hoc NF-anchored passes (RENAME FA .074, ROLE_PERMUTE
  recall .77) and its fusion gives .759 on E. P1 INCONCLUSIVE (PEER>TEXT on ADD/DROP errors, TEXT>PEER on peer-endorsed),
  P2 REFUTED, P3 INCONCLUSIVE (gap vs judge grows with length, diff-in-delta +.146 CI>0), P4 REFUTED (fused RENAME FA .385).
  Unit-code typing at chance (.37 vs .38). Disguise improves the judge (no contamination benefit). Within-stratum placebo
  .59 (composition), global .50. FILES: results/per_item_E.jsonl (row_key=item_id|prompt_variant, fold_E=sha1('E_folds_v1|'+sid)%5,
  every score) for the iteration-3 join; results/analysis.json, tables.md, p_tests.json, deviations.json, prereg.json; src/peer_text.py
  reusable functions; method_out.json (exp_gen_sol_out, predict_* for all metrics). Audits: tests/audit_rederive.py re-derives
  pooled AUROCs and headline delta to 1e-9; tests/placebo_headline.py (shuffled labels fail); prefilter audit 0 conflicts;
  judge prompt identity 30/30. OpenRouter spend $0.155.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_u75jRHUss0zo/3_invention_loop/iter_2/gen_art/gen_art_experiment_5
out_expected_files:
- method.py
- full_method_out.json
- mini_method_out.json
- preview_method_out.json

id: art_zcwCQgTqk6DN
type: dataset
title: Long logic sentences and FOL error suite
summary: >-
  Two held-out NL->FOL faithfulness tables (full_data_out.json, aii exp_sel_data_out, every row re-verified against its sources
  by data.py and z3-re-verified by src/verify.py, 0 failures). (1) PERTURB (group perturb_suite, COMPLETE): 4,234 typed mutants
  (metadata_fold PERTURB, output ERROR, error_ops=[op]) plus 868 meaning-preserving controls (PERTURB_CONTROL, output CORRECT).
  They cover 300 bases: 36 TRUSTED_AGREED + 95 GOLD_PANEL_OK + 69 PANEL_REPAIRED dataset-E references, and 100 R_COMP weak
  readings. Operators are NEG, REV, QUANT, RESTR, CONN, MOVE, DROP, ADD (ADD_FOREIGN / ADD_INTERNAL), SWAP, BIND and MEANING_RENAME,
  at DOWN/UP positions (metadata_position_polarity, polarity_method, matched_pair_id; 1,354 complete pairs). QUANT/REV/RESTR
  are UP-only; SCOPE and UNGLUE have 0 rows. Each mutant is z3 non-equivalent to every accepted reading. Controls are RENAME_SYN
  / RENAME_NONCE, REORDER and CONTRAPOSITIVE/DEMORGAN, each z3-equivalent. (2) R_COMP (group rcomp_sentences): 250 main +
  100 reserve templated sentences, each with >=25 words, >=3 conditions and one unless/except/provided-that/only-if clause
  (9 templates). Weak and strong references come from the template (T8 also stores a not-accepted converse), are unit-tested
  and z3-checked, and are built from a 652-entry atom lexicon mined from verified FOLIO/MALLS references. Provenance fields:
  template_id, lexicon_ids, source_rule_ids. CAVEAT: the shared OpenRouter key hit its daily limit 5 minutes in ($0.41 spent);
  the 21:38 UTC replacement key was also already exhausted. Pending: the Sonnet lexicon and reference audits, fluency, generator
  candidates (rcomp_candidates), solver labels, adjudication and the testability declaration. ./run_all.sh completes them
  resumably under the pre-registered prereg_rcomp.json. Until then R_COMP must not be used for metric claims. PERTURB is ready
  for per-operator sensitivity and invariance analysis. Rows carry item_id (E's recipe) and disguised_text/fol. adjudicator_check_out.json
  holds 60 known-label QA items. See dataset_card.md.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_u75jRHUss0zo/3_invention_loop/iter_2/gen_art/gen_art_dataset_3
out_expected_files:
- data.py
- full_data_out.json
- preview_data_out.json
- mini_data_out.json

id: art_HepAw8c6Eu7-
type: evaluation
in_dependencies:
- id: art_d0njuqy2Csj-
  label: scores
- id: art_i3cVDxBp-USk
  label: scores
- id: art_elDZY26Pu6GD
  label: scores+folds
- id: art_U4Hsqt4Ay9Tg
  label: adjudicated labels
title: Re-checking earlier logic-metric results across label sets
summary: >-
  Zero-LLM-spend, CPU-only re-analysis of the iteration-1 artifacts (exp A FOL-Triage, exp C consensus c_score, exp D judges/baselines,
  dataset E screen adjudication), joined on item_id. eval.py (+src/) writes eval_out.json (exp_eval_sol_out, validated; ~5.9k
  flat metrics_agg keys + structured metadata incl. VERDICT; 1,380 per-item examples with oriented scores, per-regime labels,
  PT OOF), tables/*.csv (each with a '# source:' line), figures/fig_regime_shift and fig_forest_common (json/png/pdf), and
  audit/ scripts. KEY FINDINGS. (1) Re-derivation gate: 57/57 reviewer audit numbers reproduce (n=389/160 err/151 sents; c_score
  .842, fused .767, judge_disg .785; tier A+B n=304 fused .872, bow .817, c_score .776, judge .771). (2) Same-item, same-label
  common sets for 13 regimes (testable: R_SOLVER_CONS n=373/155 err, own-label A/C/D, R_ADJ_AB 298/165, R_ADJ_ALL 498/271,
  CONTESTED->C/E, L_UNPARSEABLE_AS_ERROR 413/195; R_ADJ_A and all track-H regimes are untestable, reported sign-only). (3)
  The iteration-1 rule FAILS for fused_H and c_score in every regime (rewrite FA 0.275 / 0.96). fused_H minus judge is -0.013
  under solver labels but +0.096 [.020,.171] under A+B; c_score minus judge is +0.067 [-.012,.148] under solver labels and
  +0.006 under A+B. (4) Label-only shift solver->A+B on the same 161 items: bow +0.102 and fused +0.080 (CI>0) go up; c_score
  -0.106 goes down. Rank Kendall tau is 0.60. On the 58 flipped items, bow/fused flag 81-83% vs c_score 34% (instrument-sharing
  confirmed). (5) SCREEN PREVIEW: PT (cross-fitted c_score+bow_uncarried+l3) minus judge_cheap_disg is +0.089 [.010,.165]
  solver, +0.104 [.039,.175] A+B, +0.090 [.038,.142] all tiers, +0.118 unparseable-as-error. Nested S4+PT over refit S4 is
  +0.04-0.06 (CI>0). Screen bar that iteration-2 confirmation must beat = these deltas. (6) P1: the structural clause is untestable
  (all QUANT/SCOPE/BIND/SWAP/NEG cells have <15 errors); text beats peers on peer-endorsed errors (CI>0). P2a CONFIRMED only
  for all tiers. P2b depends on the comparator: vs c_score the gain comes from endorsed errors; vs bow it comes from non-endorsed
  errors. (7) At matched FA 0.10 the ORIGINAL cheap judge has higher recall than the disguised one (+0.11/+0.20). Contamination
  DiD CIs include 0 but MDE = 0.12-0.21, so a 0.05 effect is undetectable. Frontier minus cheap under A+B is +0.166. (8) Invariance
  comparisons across A/C/D used different rewrite sets. (9) Candidate B was planned but gen_art_experiment_2 is an empty .aii/
  dir: it never ran. (10) Exp C's -0.94/SD length interaction reproduces exactly. Exp A's L2-bow = n_unanch+uncarried (0.737)
  vs bow_uncarried (0.711). Panel expert-pair acceptance is .613 (unambiguous). Independent re-derivation (different code
  path) matches all headline numbers. On permuted labels the cross-fitted PT is biased below 0.5; the observed deltas exceed
  all 20 null deltas (null max .047 solver / .087 A+B).
workspace_path: >-
  /ai-inventor/aii_data/runs/run_u75jRHUss0zo/3_invention_loop/iter_2/gen_art/gen_art_evaluation_1
out_expected_files:
- eval.py
- full_eval_out.json
- mini_eval_out.json
- preview_eval_out.json
</new_artifacts_this_iteration>

<current_paper>
The paper draft from this iteration — represents the current state of the research story.

# Gold-Free Faithfulness Metrics for NL-to-FOL Translation

## Framing

Translating natural language into first-order logic (NL-FOL) is a prerequisite for neurosymbolic reasoning pipelines [10], yet evaluating whether a candidate formula faithfully captures a sentence's meaning remains an open problem. Gold FOL annotations are expensive, non-unique, and unreliable: Brunello et al. [3] found that approximately 42% of entries in both FOLIO [1] and MALLS [2] contain incorrect formalisations. Existing metrics either require a gold formula (exact match, prover-checked equivalence) or only verify that the output parses [5, 6]. The user's own pilot study used structural consistency checks (arity agreement, predicate-set overlap across reruns, joint satisfiability) that measure stability but not whether a formula says what its sentence says.

This run investigates gold-free metrics that predict faithfulness to the text given only a sentence and a candidate formula, with no reference formula, no ontology, and no domain knowledge. The evaluation is a meta-evaluation: we build a labelled set of (sentence, formula) pairs from public benchmarks whose gold has been audited, and measure each metric's ability to discriminate correct translations from errors.

## Iteration 1

### 1.1 Strategy

The iteration screens four candidate metric families head-to-head on a frozen evaluation set, with a disguised cheap LLM judge as the bar to beat.

**Candidates.** (A) FOL-Triage, a three-layer cascade: L1 (formula lint: deterministic formula smells), L2 (text accounting: bag-of-words and role-aware coverage), and L3 (role questionnaire: a small LLM reads the text and z3 reads the formula; their structured answers are compared). (B) Round-trip verification: verbalise the formula back to natural language and compare to the original via NLI or embedding similarity [7]. (C) Cross-system consensus: collect translations of the same sentence from multiple independent systems, measure z3-equivalence between the candidate and the peer pool, and score disagreement [8]. (D) Disguised cheap judge and baselines: an LLM judge, structural pilot metrics, and round-trip features evaluated on nonce-disguised sentences to control for memorisation.

**Evaluation set.** The frozen screen uses Logic-LM [10] released outputs on FOLIO validation: three LLM systems (GPT-3.5-turbo, GPT-4, text-davinci-003) producing 796 items. Track L contains LLM outputs labelled by z3 equivalence to corrected gold [4]; track H contains the 294 original human gold formulas, of which 57 are errors according to the corrected labels. The parallel run (run_qY2a2IS-WLIs) measured 43.9% of solver-non-equivalent candidates as faithful by a three-family panel; iteration 2 will re-score with those adjudicated labels.

**Decision rule.** A candidate must achieve AUROC ≥ 0.65 on track L (ERROR vs CORRECT), with coverage ≥ 90%, rewrite false-alarm rate ≤ 10% per rewrite family, and cost ≤ $0.002 per item. It advances only if its AUROC exceeds the disguised cheap judge's, with a paired bootstrap CI excluding zero.

**Held-out dataset (Artifact E).** A separate 700-sentence, 8,507-row held-out set was constructed from FOLIO training premises, MALLS training long/conditional/exception strata, and FOLIO curated conclusions, each translated by 9 LLM families plus ccg2lambda plus GPT-4 gold. Labels were assigned by z3 equivalence to audited gold, with contested cases adjudicated by a three-member panel (Claude Haiku-4.5, GLM-4.6, Kimi-K2). This set is reserved for iteration 2 confirmation. [ARTIFACT:art_U4Hsqt4Ay9Tg]

The dataset contains 1,750 CORRECT, 5,005 ERROR, 1,086 UNPARSEABLE, 276 UNRESOLVED, and 390 CONTESTED items. The panel calibration subset (173 items) shows that the panel agrees with expert-corrected labels on both faithful and unfaithful items. A screen audit of 1,173 items from the Logic-LM screen confirms the label assignment. The dataset cost $9.83 in API calls.

### 1.2 Experiment A: FOL-Triage

[ARTIFACT:art_d0njuqy2Csj-]

FOL-Triage was evaluated on the frozen screen with Gemini 2.5 Flash Lite as the primary LLM for L3. Total API spend was $0.29.

#### Headline AUROCs (track L, ERROR vs CORRECT, n = 477, 199 errors)

| Metric | AUROC | 95% CI | AUPRC |
|-|-|-|-|
| L1 (any smell) | 0.508 | [0.499, 0.519] | 0.425 |
| L2 bag-of-words | 0.737 | [0.677, 0.801] | 0.690 |
| L2 role-aware | 0.557 | [0.527, 0.594] | 0.476 |
| L3 score | 0.756 | [0.701, 0.809] | 0.657 |
| Fused (fitted on H, no leak) | 0.759 | [0.695, 0.825] | 0.740 |
| Fused (all H) | 0.827 | [0.778, 0.874] | 0.771 |
| Fused (cross-fit L) | 0.864 | [0.824, 0.902] | 0.789 |
| Decomposed judge (LLM reads formula) | 0.716 | [0.645, 0.789] | 0.717 |
| L3 with local Qwen2.5-1.5B | 0.708 | [0.637, 0.774] | 0.603 |

The primary no-leak fused score is 0.759. The fused-all-H and cross-fit-L numbers (0.827, 0.864) are shown for completeness but are not valid held-out estimates: the former uses the full track H for fitting, and the latter is a within-L cross-fit that overstates generalisation.

**Track H (human gold errors, n = 258, 57 errors).** Fused out-of-fold AUROC is 0.777 [0.698, 0.847]. L1 alone reaches 0.655, compared to 0.508 on track L. The lint rules fire on human annotation errors but not on LLM outputs, because the two populations produce different formula smells.

#### L1 lint: a negative result on LLM outputs

L1 flags formulas with deterministic smells (existential implication, free variables, arity clashes, vacuity, trivial formulas, dangling predicates). On track L, the true positive rate is 2.0% at a false positive rate of 0.4%, giving AUROC 0.508. This is a negative result: L1 lint does not transfer from human annotation errors (where it is effective, AUROC 0.655) to LLM outputs. The reason is that LLM-generated formulas rarely contain the syntactic pathologies L1 detects; their errors are semantic (wrong predicates, missing conditions, scope mistakes).

All nine individual smell rules have false-alarm rates below 3% on every system:

| Smell | gpt-3.5 FA | gpt-4 FA | davinci-003 FA |
|-|-|-|-|
| EX_IMP | 0.0 | 0.0 | 0.0 |
| ALL_AND | 0.0 | 0.0 | 0.0 |
| IFF_RESTR | 0.0 | 0.009 | 0.0 |
| GLUE | 0.0 | 0.0 | 0.0 |
| FREE | 0.0 | 0.0 | 0.0 |
| VACUOUS | 0.0 | 0.0 | 0.0 |
| TRIVIAL | 0.0 | 0.0 | 0.0 |
| ARITY | 0.0 | 0.0 | 0.0 |
| DANGLING | 0.0 | 0.0 | 0.0 |

Only the FREE smell fires on any track-L errors (4 items).

#### L2 role-aware check: below bag-of-words

The role-aware UD-based check (L2-role) achieves AUROC 0.557, which is 0.18 below the simpler bag-of-words check (L2-bow, 0.737). The role-aware layer adds no discriminative power over word overlap.

#### Decomposed judge ablation

Replacing z3 with an LLM that reads the formula directly (the decomposed judge) drops L3 AUROC from 0.756 to 0.697 (ΔAUROC = −0.059). The LLM gets only 57.6% of binary argument slots correct on track L and 36.4% on track H. The z3 answerer is significantly more accurate for structured formula reading.

#### Per-type sensitivity (track L, at binary threshold)

| Error type | n | L1 | L2-bow | L2-role | L3 | Fused | Cascade |
|-|-|-|-|-|-|-|-|
| NEG | 5 | 0.0 | 0.2 | 1.0 | 0.2 | 0.4 | 1.0 |
| QUANT | 2 | 0.0 | 0.0 | 0.5 | 0.0 | 0.5 | 0.5 |
| CONN | 4 | 0.0 | 0.0 | 0.0 | 0.0 | 0.0 | 0.0 |
| DROP | 142 | 0.028 | 0.479 | 0.127 | 0.197 | 0.599 | 0.606 |
| ADD | 150 | 0.020 | 0.473 | 0.107 | 0.173 | 0.653 | 0.573 |
| SWAP | 12 | 0.0 | 0.0 | 0.083 | 0.25 | 0.083 | 0.333 |
| BIND | 8 | 0.125 | 0.0 | 0.125 | 0.0 | 0.375 | 0.25 |
| COMPOUND | 187 | 0.118 | 0.428 | 0.166 | 0.160 | 0.599 | 0.578 |

FOL-Triage is most sensitive to ADD and DROP errors (the largest categories), with the fused score catching about 60%. It misses CONN errors entirely (0/4) and detects SWAP poorly (1/12). Negation errors are fully caught by the cascade (which fires L2-role, where monotonicity shifts are visible) but L1 and L2-bow miss them.

On track H (57 errors), the per-type pattern differs. UNGLUE errors (n = 5) are caught at 100% by L1 and the fused score, because they produce detectable formula smells.

#### Per-type sensitivity (track H)

| Error type | n | L1 | L2-bow | L2-role | L3 | Fused | Cascade |
|-|-|-|-|-|-|-|-|
| NEG | 4 | 0.0 | 0.0 | 0.25 | 0.0 | 0.25 | 0.25 |
| REV | 1 | 0.0 | 0.0 | 0.0 | 0.0 | 0.0 | 0.0 |
| QUANT | 1 | 0.0 | 0.0 | 0.0 | 0.0 | 0.0 | 0.0 |
| RESTR | 1 | 1.0 | 1.0 | 0.0 | 0.0 | 1.0 | 1.0 |
| CONN | 8 | 0.25 | 0.125 | 0.0 | 0.375 | 0.375 | 0.375 |
| MOVE | 2 | 0.5 | 0.0 | 0.5 | 0.0 | 0.5 | 1.0 |
| DROP | 14 | 0.143 | 0.357 | 0.0 | 0.143 | 0.357 | 0.5 |
| ADD | 19 | 0.158 | 0.368 | 0.053 | 0.211 | 0.526 | 0.579 |
| SWAP | 2 | 0.0 | 0.5 | 0.0 | 0.5 | 0.5 | 0.5 |
| BIND | 1 | 1.0 | 1.0 | 0.0 | 0.0 | 1.0 | 1.0 |
| UNGLUE | 5 | 1.0 | 0.4 | 0.0 | 0.2 | 1.0 | 1.0 |
| COMPOUND | 33 | 0.303 | 0.182 | 0.242 | 0.182 | 0.545 | 0.636 |

#### Invariance under meaning-preserving rewrites

Five rewrite families were tested on 150 track-L CORRECT items. The table shows the false-alarm rate on the rewritten formula and the flip rate (fraction of items whose binary verdict changes):

| Rewrite | n applies | L1 FA | L1 flip | bow FA | bow flip | role FA | role flip | L3 FA | L3 flip | Fused FA | Fused flip |
|-|-|-|-|-|-|-|-|-|-|-|-|
| RENAME | 150 | 0.0 | 0.0 | 0.18 | 0.093 | 0.013 | 0.0 | 0.033 | 0.007 | 0.22 | 0.013 |
| REORDER | 34 | 0.0 | 0.0 | 0.029 | 0.0 | 0.059 | 0.0 | 0.059 | 0.0 | 0.235 | 0.0 |
| DEMORGAN | 33 | 0.0 | 0.0 | 0.030 | 0.0 | 0.061 | 0.0 | 0.030 | 0.030 | 0.182 | 0.061 |
| CONTRAPOSITIVE | 40 | 0.025 | 0.025 | 0.10 | 0.0 | 0.025 | 0.025 | 0.025 | 0.0 | 0.275 | 0.0 |
| PRENEX | 1 | 0.0 | 0.0 | 0.0 | 0.0 | 0.0 | 0.0 | 0.0 | 0.0 | 0.0 | 0.0 |

The rewrite false-alarm gate (≤ 10% per family) fails. The worst-family fused FA is 0.275 (CONTRAPOSITIVE), but this equals the FA on the original formulas; the flip rate is at most 0.061. The high FA is not caused by the rewrites but by the fused score's calibration: it was fitted on track H where the CORRECT base rate is higher, producing a systematic over-flagging on track L (FA on track-L CORRECT items is 0.194 versus the 0.10 calibration target).

L1, L2-role, and L3 individually pass the 10% gate. L2-bow fails only under RENAME (FA = 0.18), because renaming predicates breaks the bag-of-words match between text and formula.

[FIGURE:fig_rewrite_fa]

#### Coverage

| Track | n | Parseable | Full coverage rate |
|-|-|-|-|
| L | 753 | 693 | 0.920 |
| H | 302 | 279 | 0.924 |

Parse rates by system: gpt-3.5-turbo 0.889, gpt-4 0.946, text-davinci-003 0.921. Unparseable outputs are scored as p = 1 (maximum error probability) by the fused metric, so all items receive a score. The coverage gate (≥ 90%) passes.

#### Cost

L1 and L2 are free (CPU-only). L3 costs $0.175 per 1,000 calls with Gemini 2.5 Flash Lite. The total per-item cost is $0.0002, passing the $0.002 gate. CPU time (L1 + L2 + z3): median 35 ms, P95 90 ms. L3 latency: median 630 ms, P95 1.68 s.

#### Contamination check

L3 was run on nonce-disguised sentences (content words replaced by nonsense words) on the full track L. AUROC with exact text-formula alignment: 0.765; with disguised text: 0.770. Paired difference: −0.005 [−0.063, 0.049]. There is no evidence that the LLM benefits from having seen the public benchmark sentences.

#### Complexity strata (track L, fused score)

| Stratum | n (error/correct) | Testable | Fused AUROC | L2-bow AUROC | L3 AUROC |
|-|-|-|-|-|-|
| words < 12 | 443 (179/264) | Yes | 0.781 | 0.742 | 0.772 |
| words 12-19 | 31 (18/13) | No | 0.521 | 0.596 | 0.541 |
| words ≥ 20 | 3 (2/1) | No | 0.500 | 1.000 | 0.000 |
| 0 quantifiers | 302 (130/172) | Yes | 0.743 | 0.728 | 0.771 |
| 1 quantifier | 164 (65/99) | Yes | 0.794 | 0.748 | 0.721 |
| ≥ 2 quantifiers | 11 (4/7) | No | 0.750 | 0.768 | 0.607 |
| depth ≤ 1 | 296 (124/172) | Yes | 0.762 | 0.745 | 0.779 |
| depth 2-3 | 173 (73/100) | Yes | 0.756 | 0.717 | 0.710 |
| depth ≥ 4 | 8 (2/6) | No | 0.667 | 0.750 | 0.500 |
| 0 conditions | 344 (145/199) | Yes | 0.775 | 0.759 | 0.791 |
| 1-2 conditions | 131 (54/77) | Yes | 0.716 | 0.677 | 0.628 |

The frozen screen is dominated by short, simple sentences (93% under 12 words). The long and complex strata (12+ words, 2+ quantifiers, 3+ conditions) have too few items to test. This limitation motivates the held-out dataset (Artifact E), which oversamples these strata.

#### Per-system AUROC (descriptive, n = 3 systems)

| System | n | Error rate | Fused AUROC | L1 AUROC | L2-bow AUROC | L3 AUROC |
|-|-|-|-|-|-|-|
| gpt-3.5-turbo | 143 | 0.378 | 0.689 | 0.500 | 0.650 | 0.722 |
| gpt-4 | 177 | 0.367 | 0.700 | 0.496 | 0.716 | 0.720 |
| text-davinci-003 | 157 | 0.510 | 0.857 | 0.525 | 0.811 | 0.817 |

FOL-Triage is most discriminative on text-davinci-003, the weakest system. The Kendall τ between system error rates and mean fused scores is 0.333 (3 systems, descriptive only).

#### Label quality observations

The track-L label distribution reveals a systematic issue: 58.8% of typed ERROR items have only ADD+DROP repair operators. On inspection, most of these are vocabulary or arity choices (e.g. Lunch(james) vs HasLunch(james, company)) that the vocabulary aligner cannot bridge. These are likely CORRECT under a looser equivalence definition. The track-H original gold has 27.1% error rate (errors, uncertain, and reading-choice items) and 5.8% unparseable rate. Among non-equivalent parseable items, 21.9% are correct-but-not-equivalent (VOCAB or GRAN class).

### 1.3 Experiment C: Cross-System Consensus

[ARTIFACT:art_i3cVDxBp-USk]

The consensus metric collects translations of the same sentence from multiple independent LLM families, checks pairwise z3 equivalence, and scores each candidate by its disagreement with the pool. Total API spend was $1.52.

#### Headline AUROCs (track L, ERROR vs CORRECT, n = 546, 249 errors)

| Metric | AUROC | 95% CI | AUPRC |
|-|-|-|-|
| c_score (1 − eq_frac, all peers) | 0.866 | [0.821, 0.906] | 0.827 |
| c_score (6 fresh peers only) | 0.872 | [0.830, 0.911] | 0.825 |
| c_score (non-OpenAI peers) | 0.863 | [0.820, 0.903] | 0.808 |
| c_score (2 Logic-LM peers only) | 0.753 | [0.701, 0.806] | 0.659 |
| medoid depth | 0.722 | [0.673, 0.774] | 0.622 |
| cluster entropy | 0.773 | [0.724, 0.820] | 0.691 |
| SC-5 cheap (gpt-4.1-nano) | 0.725 | [0.669, 0.781] | 0.627 |
| SC-5 same model | 0.716 | [0.632, 0.796] | 0.628 |
| SC-5 entropy | 0.631 | [0.568, 0.693] | 0.539 |
| Prediction set instability (SC) | 0.688 | [0.626, 0.750] | 0.602 |
| Prediction set instability (pool) | 0.770 | [0.717, 0.821] | 0.721 |
| FOL length | 0.527 | [0.470, 0.586] | 0.485 |
| Misalignment (vocab) | 0.835 | [0.794, 0.876] | 0.821 |

[FIGURE:fig_consensus_auroc]

The c_score achieves the highest AUROC in the iteration at 0.866. It beats SC-5 (the self-consistency baseline) by ΔAUROC = +0.140 [0.085, 0.197]. Cross-family consensus also exceeds sampling self-consistency in the related SAC3 framework [17], which uses semantic-aware cross-check consistency for hallucination detection in black-box LLMs. Using only the six fresh peer translations (not the three Logic-LM systems) gives 0.872, slightly higher than using all peers. Restricting to the two other Logic-LM systems drops the AUROC to 0.753, showing that diversity across model families is essential.


The misalignment score (0.835) is high because CORRECT items are by construction alignable to the gold in the labeller, so misalignment alone is a strong proxy for error. This does not generalise to settings without a shared vocabulary.

#### RENAME rewrite invariance: failure

Under predicate renaming (replacing predicate names with WordNet synonyms or nonce names), the c_score false-alarm rate is 96% (100% for constant-only renaming). This is expected and fundamental: two formulas with different predicate names are not z3-equivalent, so any rename breaks the equivalence check. The consensus metric is invariant to rewrites that preserve z3 equivalence (reordering, De Morgan, contrapositive) but not to vocabulary changes.

#### Blind-spot analysis

38% of ERROR items are z3-equivalent to the medoid (the most popular peer formula). This places a ceiling on recall of approximately 62%. The blind-spot rate is 5% for polarity errors and 57% for structural errors.

#### Cost

The peer pool costs $0.0015 per sentence (6 peers via API). Total experiment spend: $1.52. z3 pairwise equivalence checking is free.

### 1.4 Experiment D: Disguised Judge and Baselines

[ARTIFACT:art_elDZY26Pu6GD]

This experiment establishes the bar: every baseline metric and every judge variant on the same shared screen, scored with nonce-disguised sentences to control for memorisation. Total API spend was $2.02 (after the OpenRouter key was restored at 15:11 UTC; local judges ran during the outage and are kept as secondary rows).

#### The bar: disguised cheap judge

The primary cheap judge (Gemini 2.5 Flash Lite, JSON 0-100 scoring, nonce-disguised sentences) achieves AUROC 0.777 [0.720, 0.827] on track L (n = 524, 230 errors, 294 correct).

#### Full baseline table (track L, ERROR vs CORRECT, n = 524)

| Metric | AUROC | 95% CI |
|-|-|-|
| parse_fail | 0.500 | [0.500, 0.500] |
| pilot_joint_conflict | 0.513 | [0.488, 0.539] |
| pilot_arity_incons | 0.500 | [0.500, 0.500] |
| pilot_shape_incons | 0.524 | [0.470, 0.578] |
| pilot_dangling | 0.533 | [0.474, 0.592] |
| pilot_undeclared | 0.525 | [0.510, 0.542] |
| pilot_rerun_jacc | 0.720 | [0.659, 0.780] |
| rt_nli_min | 0.710 | [0.648, 0.769] |
| rt_nli_fwd | 0.652 | [0.588, 0.713] |
| rt_nli_bwd | 0.681 | [0.621, 0.742] |
| rt_nli_contra | 0.628 | [0.566, 0.686] |
| rt_nli_min_alt | 0.689 | [0.627, 0.749] |
| rt_embed_cos | 0.633 | [0.574, 0.696] |
| rt_reformalise_eq | 0.513 | [0.479, 0.547] |
| judge_cheap_orig | 0.749 | [0.695, 0.801] |
| judge_cheap_disg | 0.777 | [0.720, 0.827] |
| judge_cheap2_orig (gpt-4.1-nano) | 0.750 | [0.691, 0.810] |
| judge_cheap2_disg | 0.714 | [0.648, 0.777] |
| judge_strong_orig (gemini-3.1-pro) | 0.802 | [0.715, 0.877] |
| judge_strong_disg | 0.730 | [0.655, 0.803] |
| judge_local_qwen8b_disg | 0.757 | [0.702, 0.811] |
| judge_local_llama8b_disg | 0.671 | [0.604, 0.737] |
| judge_local_qwen14b_disg | 0.760 | [0.681, 0.834] |
| rt_nli_min_localverb | 0.740 | [0.680, 0.796] |

[FIGURE:fig_baseline_auroc]

#### Pilot structural metrics: negative result

The user's pilot structural metrics are null on this screen. Joint conflict achieves AUROC 0.513, arity inconsistency 0.500, shape inconsistency 0.524, dangling predicates 0.533, and undeclared predicates 0.525. The cross-system predicate-set Jaccard (pilot_rerun_jacc) reaches 0.720, the only pilot metric with signal, but this is a proxy for the consensus approach tested in Experiment C.

#### Round-trip verification

Round-trip NLI (verbalise the formula, compare to the original sentence via bidirectional NLI entailment) achieves AUROC 0.710 [0.648, 0.769]. This is 0.067 below the cheap judge (p = 0.008 by DeLong test). The round-trip reformalisation check (verbalise, re-translate to FOL, check z3 equivalence with the original) achieves only 0.513, because 76% of items tie at the same score.

Round-trip NLI using local verbalisation (the LLM verbalises on the local GPU instead of the API) reaches 0.740 [0.680, 0.796], slightly higher than the API version.

#### Frontier judge

The strong judge (Gemini 3.1 Pro Preview) achieves AUROC 0.802 [0.715, 0.877] on the strong subsample (n = 291). Under disguise it drops to 0.730 [0.655, 0.803]. The ΔAUROC over the cheap judge is +0.024 [−0.075, 0.111], not significant.

#### Cross-fitted baseline combinations (track L)

| Combination | AUROC | 95% CI |
|-|-|-|
| S1 (structural) | 0.698 | [0.634, 0.761] |
| S2 (round-trip) | 0.687 | [0.625, 0.749] |
| S3 (judges disguised) | 0.771 | [0.705, 0.831] |
| S4 (all cheap features) | 0.817 | [0.762, 0.867] |
| S6 (S4 + local judges) | 0.810 | [0.753, 0.861] |

S4 (all cheap features combined via cross-fitted logistic regression) achieves 0.817. This is +0.039 [−0.010, 0.087] over the cheap judge alone, not significant, but it sets the empirical ceiling for cheap baselines.

#### Contamination analysis

No evidence of contamination was found for any judge. The difference-in-differences (DiD) test compares the disguise effect on track H (where the LLM could have memorised public gold) to track L (where it evaluates its own outputs, not memorisable). All DiD CIs include zero:

| Judge | DiD (H − L) | 95% CI |
|-|-|-|
| flash-lite | −0.042 | [−0.170, 0.094] |
| gpt-4.1-nano | −0.077 | [−0.188, 0.023] |
| gemini-3.1-pro | +0.002 | [−0.115, 0.104] |
| Qwen3-8B | −0.045 | [−0.161, 0.079] |
| Llama-3.1-8B | +0.023 | [−0.112, 0.157] |
| Qwen3-14B | −0.073 | [−0.195, 0.056] |

The gold-recall probe confirms this: when the primary model translates track-H sentences from scratch, it matches the corrected gold 15.9% of the time but the original (public) gold only 4.4%. Predicate-name Jaccard with the original gold minus Jaccard with the Logic-LM GPT-4 output is −0.068 [−0.171, 0.034]; the model is not reproducing the public gold.

#### Invariance of judges under meaning-preserving rewrites

Judges are highly sensitive to meaning-preserving rewrites. The FA on CONTRAPOSITIVE rewrites is 0.67 for the cheap judge (original), 0.51 for the cheap judge (disguised), and 0.95 for the cheap2 judge. This compares poorly to FOL-Triage's fused flip rate of 0.0 on CONTRAPOSITIVE.

The full invariance table (track L CORRECT items, n = 270):

| Metric | RENAME flip | REORDER flip | DEMORGAN flip | CONTRA flip | ALL flip |
|-|-|-|-|-|-|
| judge_cheap_orig | 0.27 | 0.12 | 0.23 | 0.64 | 0.29 |
| judge_cheap_disg | 0.44 | 0.12 | 0.46 | 0.41 | 0.39 |
| judge_cheap2_orig | 0.49 | 0.12 | 0.46 | 0.95 | 0.49 |
| rt_nli_min | 0.37 | 0.10 | 0.31 | 0.33 | 0.31 |
| rt_embed_cos | 0.57 | 0.07 | 0.44 | 0.38 | 0.44 |
| FOL-Triage fused | 0.013 | 0.0 | 0.061 | 0.0 | 0.013 |

FOL-Triage has the lowest flip rate of any metric tested. Judges and round-trip methods change their verdict on 29-49% of meaning-preserving rewrites.

#### Per-error-type sensitivity of judges (track H, curator view, n = 46 errors)

| Group | n | judge_cheap_orig | judge_cheap_disg | judge_cheap2_orig | rt_nli_min |
|-|-|-|-|-|-|
| 1-op errors | 13 | 0.308 | 0.538 | 0.462 | 0.231 |
| 2-op errors | 11 | 0.545 | 0.818 | 0.727 | 0.273 |
| ADD | 12 | 0.500 | 0.750 | 0.667 | 0.250 |
| COMPOUND | 22 | 0.545 | 0.864 | 0.773 | 0.273 |
| DROP | 11 | 0.455 | 0.636 | 0.455 | 0.182 |
| CONN | 3 | 0.667 | 0.667 | 1.000 | 0.333 |
| NEG | 2 | 0.500 | 0.500 | 1.000 | 0.500 |
| SWAP | 2 | 0.000 | 1.000 | 0.500 | 0.000 |

The disguised judge is more sensitive than the original judge for most error types, suggesting that nonce disguise forces the model to read more carefully.

#### Judge error-type classification accuracy

The judge's ability to name the correct error type is poor. On track-H 1-op errors, it identifies the correct repair operator 0% of the time (0/12). On 2-op errors, it is correct 45% (5/11). On track L, accuracy is 20% for 1-op and 27% for 2-op errors.

#### Complexity analysis (track L)

A logistic regression of judge correctness on standardised word count yields a coefficient of −0.48 (SE 0.11, p < 0.001): the judge is significantly less reliable on longer sentences. On track H (where longer sentences are available), the coefficient is −0.14 (SE 0.17, p = 0.41), consistent in direction but underpowered.

| Stratum | n (err/cor) | judge_cheap_disg AUROC | rt_nli_min AUROC |
|-|-|-|-|
| words < 12 | 485 (210/275) | 0.784 | 0.713 |
| words 12-19 | 36 (18/18) | 0.667 | 0.670 |
| quantifiers 0-1 | 512 (226/286) | 0.784 | 0.712 |
| depth ≤ 3 | 466 (199/267) | 0.781 | 0.702 |
| depth 4-5 | 54 (30/24) | 0.762 | 0.828 |
| 0 conditions | 394 (182/212) | 0.783 | 0.745 |
| 1-2 conditions | 128 (48/80) | 0.765 | 0.653 |

#### System-level descriptive statistics (3 systems, descriptive only)

| System | True error rate | Judge flag rate | rt_nli_min mean | Parse failures |
|-|-|-|-|-|
| gpt-3.5-turbo | 0.415 | 0.444 | 0.516 | 26/248 |
| gpt-4 | 0.385 | 0.362 | 0.496 | 10/282 |
| text-davinci-003 | 0.527 | 0.553 | 0.663 | 20/266 |

#### API outage and robustness

The shared OpenRouter key was exhausted at 13:29 UTC and restored at 15:11 UTC. During the outage, all LLM judges ran on the local RTX 4000 Ada GPU with the same prompts (Qwen3-8B, Llama-3.1-8B, Qwen3-14B-nf4). After the key was restored, the API judges were run and designated as primary; the local judges are kept as secondary rows. The local Qwen3-8B judge achieves AUROC 0.757 (disguised), comparable to the API flash-lite judge at 0.777.

### 1.5 Iteration 1 Summary

The four candidates and the bar:

| Method | AUROC | 95% CI | n | Cost/item | Rewrite flip rate |
|-|-|-|-|-|-|
| c_score (consensus) | 0.866 | [0.821, 0.906] | 546 | $0.0015/sent | 96% (RENAME) |
| S4 baseline combo | 0.817 | [0.762, 0.867] | 524 | varies | varies |
| **Bar: judge_cheap_disg** | **0.777** | **[0.720, 0.827]** | **524** | **$0.00004** | **0.39** |
| FOL-Triage fused | 0.759 | [0.695, 0.825] | 477 | $0.0002 | 0.013 |
| rt_nli_min | 0.710 | [0.648, 0.769] | 524 | $0.00001 | 0.31 |
| L1 lint | 0.508 | [0.499, 0.519] | 477 | $0 | 0.0 |
| Pilot structural | 0.50-0.53 | n/a | 524 | $0 | n/a |

[FIGURE:fig_summary_comparison]

**What iteration 1 established:**

1. The cross-system consensus metric (c_score = 1 − eq_frac) achieves the highest AUROC at 0.866, beating SC-5 by +0.140. It requires peer translations from multiple model families and is fundamentally non-invariant to predicate renaming (96% FA under RENAME).

2. The disguised cheap judge sets the bar at AUROC 0.777. The S4 combination of all cheap features reaches 0.817 (+0.039, not significant). The frontier judge (Gemini 3.1 Pro) adds nothing significant over the cheap judge.

3. FOL-Triage achieves AUROC 0.759, below the bar. Its primary value is invariance: the fused flip rate under meaning-preserving rewrites is 0.013, compared to 0.29-0.49 for judges. However, the fused false-alarm rate on CORRECT items is 0.194, exceeding the 0.10 calibration target.

4. L1 lint does not transfer from human annotation errors to LLM outputs. The pilot structural metrics are null. Round-trip NLI is 0.067 below the judge.

5. The evaluation labels are noisy: 58.8% of track-L "errors" are pure ADD+DROP (likely vocabulary mismatches). Iteration 2 will re-evaluate under panel-adjudicated labels from the held-out set.

6. No contamination was detected for any LLM-based metric.

**What remains for iteration 2:** (a) Re-evaluate all candidates under adjudicated labels from Artifact E. (b) Compute the paired ΔAUROC between FOL-Triage and the disguised judge on shared items. (c) Test whether combining the consensus metric with FOL-Triage or the judge produces a significant improvement. (d) Confirm on the held-out set.

## Iteration 2

### 2.1 Strategy

Iteration 2 has three goals: (i) confirm iteration 1's ordering on the held-out dataset E under both the solver labels (R_AB, R_A) and panel-adjudicated labels (R_ADJ); (ii) test whether fusing the consensus signal (PEER) with text-based checks (TEXT = L2-bow + L3) improves over each alone; and (iii) construct a typed perturbation suite (PERTURB) for controlled sensitivity testing.

The pre-registered bar for this iteration is the flash-lite judge on disguised sentences, with the local Qwen3-8B judge as fallback if the API is unavailable. The shared OpenRouter key hit its daily limit at 18:00 UTC on 2026-09-23, before the held-out experiment completed, and did not recover before the run deadline. The flash-lite bar is therefore UNTESTABLE on E; the fallback local judge (Qwen3-8B, rubric B, greedy; screen AUROC 0.757 vs 0.777 for flash-lite) is the labelled secondary bar for all rows reported below.

### 2.2 Experiment 5: PEER+TEXT on held-out dataset E

[ARTIFACT:art_TaxJRnPcJMuZ]

PEER+TEXT is a logistic fusion of the consensus signal (c_score with shared-vocabulary alignment, denoted c_score_align) and the text-based FOL-Triage layers (L2-bow, L3 questionnaire). The fusion weights were fitted on the iteration-1 screen and frozen before any E score was computed (prereg sha256 b9f28b1bf6bf). API spend was $0 (all components ran on CPU and the local GPU; no OpenRouter calls completed).

#### Name-free alignment: failed the pre-registered screen gate

A name-free variant of the consensus metric (graded clause consensus, g_score) was pre-registered as the primary PEER signal. It matches formula clauses by structural role without relying on shared predicate names, using anchored-cost assignment and Murty k-best matching. Under the pre-registered selection rule, both name-free variants (NF-pure and NF-anchored) failed the screen gate: for both, more than 10% of AGREE track-L CORRECT items tie at g = 1, making the deterministic false-alarm threshold degenerate (ROLE_PERMUTE recall = 0).

A post-hoc analysis with fractional tie-breaking showed this failure was a threshold-tie artefact. NF-anchored passes both gates under fractional scoring (RENAME FA 0.074, ROLE_PERMUTE recall 0.771); NF-pure still fails ROLE_PERMUTE (recall 0.186). The NF-anchored fusion was fitted post-hoc and applied to E as a labelled sensitivity analysis. On E (R_AB pooled), the NF-anchored fusion achieves AUROC 0.759 [0.72, 0.79], which is 0.031 below the pre-registered PEER+TEXT fusion (0.790), with the CI excluding zero [−0.042, −0.020]. The shared-aligner confound with the solver labeller remains open.

#### Headline AUROCs on E (R_AB, ERROR vs CORRECT)

| Subset | n (err/cor) | PEER+TEXT | c_score_align | NF c_score | L2-bow | L3 | Local judge |
|-|-|-|-|-|-|-|-|
| R_AB pooled | 2686 (1822/864) | 0.790 [0.75, 0.82] | 0.782 [0.74, 0.82] | 0.743 [0.70, 0.78] | 0.734 [0.71, 0.76] | 0.579 [0.53, 0.62] | 0.712 |
| R_AB L25 | 873 (697/176) | 0.755 [0.70, 0.80] | 0.712 [0.65, 0.77] | 0.651 [0.59, 0.71] | 0.722 [0.67, 0.77] | 0.560 [0.49, 0.63] | 0.664 |
| R_AB L20 | 821 (592/229) | 0.747 [0.69, 0.80] | 0.722 [0.66, 0.78] | 0.643 [0.58, 0.70] | 0.715 [0.66, 0.76] | 0.547 [0.48, 0.62] | 0.683 |
| R_AB EXC | 606 (384/222) | 0.777 [0.72, 0.83] | 0.814 [0.76, 0.86] | 0.782 [0.72, 0.84] | 0.669 [0.61, 0.72] | 0.620 [0.55, 0.69] | 0.663 |
| R_AB CTRL | 386 (149/237) | 0.708 [0.57, 0.84] | 0.742 [0.62, 0.86] | 0.741 [0.61, 0.86] | 0.613 [0.54, 0.72] | 0.490 [0.37, 0.62] | 0.739 |
| R_AB long pool | 2300 (1673/627) | 0.768 [0.74, 0.80] | 0.759 [0.72, 0.79] | 0.704 [0.67, 0.74] | 0.717 [0.69, 0.75] | 0.580 [0.54, 0.62] | 0.653 |
| R_A pooled L20+EXC | 449 (261/188) | 0.818 [0.73, 0.88] | 0.860 [0.79, 0.92] | 0.802 [0.72, 0.87] | 0.678 [0.61, 0.74] | 0.587 [0.51, 0.66] | 0.554 |

[FIGURE:fig_held_out_auroc]

#### PEER+TEXT vs the local judge

The paired ΔAUROC of PEER+TEXT minus the local judge is +0.078 [0.043, 0.112] on R_AB pooled (DeLong p < 0.0001). On the long pool (L25+L20+EXC), the gap widens to +0.115 [0.075, 0.157]. On R_A (tier-A adjudicated labels, L20+EXC), the gap is +0.264 [0.157, 0.359].

The flash-lite judge comparison is untestable: only 20 items received flash-lite scores before the key was exhausted, yielding a ΔAUROC of +0.057 [−0.200, 0.360] (n = 20, uninformative).

#### Does fusion beat c_score_align alone?

The stratified AUROC (pairing only within complexity strata, removing the composition confound) shows PEER+TEXT at 0.753 and c_score_align at 0.741, a difference of +0.011 [−0.012, 0.038], not significant. On the long pool the stratified gap is +0.016 [−0.010, 0.041]. On R_A the gap is −0.036 [−0.113, 0.030], favouring c_score_align. The TEXT layers add no significant discriminative power over c_score_align alone once the stratum-composition confound is removed.

#### Mechanism predictions

Four pre-registered mechanism predictions were tested on E:

**P1 (PEER catches COVERAGE errors that TEXT misses, and vice versa).** At matched false-alarm rate 0.10 with fractional tie-breaking: PEER has higher recall than TEXT on COVERAGE errors (+0.093 [0.046, 0.147]), and TEXT has higher recall on PEER_ENDORSED errors (+0.103 [0.051, 0.171]). The crossover exists, but the fused PEER+TEXT recall is not higher than c_score_align alone on any group except COVERAGE. Verdict: INCONCLUSIVE.

**P2 (PEER and TEXT error rankings are uncorrelated).** Spearman correlation between PEER and TEXT among errors is 0.294 [0.224, 0.365]. This is moderate, not near zero. The gain from fusion over the best single signal (PEER) is only +0.042 AUROC, and the share from PEER-endorsed errors is −0.200, meaning TEXT hurts on items PEER already handles. Verdict: REFUTED.

**P3 (PEER+TEXT advantage grows with sentence complexity).** The logistic interaction term z(score)·z(words) is −0.023 [−0.228, 0.185] for PEER+TEXT, consistent with no interaction. The diff-in-Δ (long minus CTRL) of PEER+TEXT minus the local judge is +0.146 [0.020, 0.269], but this reflects the judge degrading on long sentences, not the fusion improving. Verdict: INCONCLUSIVE.

**P4 (PEER+TEXT is more invariant to meaning-preserving rewrites than judges).** On the screen pools, the fused score's RENAME false-alarm rate is 0.385 and the local judge's is 0.683. The fused score is better than judges but far worse than FOL-Triage's 0.013. The c_score_align component drives most of the fused FA under RENAME (0.859). Verdict: REFUTED.

#### Rewrite false alarms (screen, CORRECT bases)

| Rewrite | n | Fused | c_score_align | NF g | L2-bow | L3 | Local judge |
|-|-|-|-|-|-|-|-|
| RENAME | 104 | 0.385 | 0.859 | 0.074 | 0.216 | 0.168 | 0.683 |
| REORDER | 27 | 0.222 | 0.178 | 0.037 | 0.044 | 0.444 | 0.000 |
| DEMORGAN | 26 | 0.154 | 0.185 | 0.038 | 0.046 | 0.231 | 0.231 |
| CONTRAPOSITIVE | 28 | 0.107 | 0.063 | 0.237 | 0.075 | 0.188 | 0.214 |

The NF g_score has the lowest RENAME false-alarm rate (0.074) of any consensus-based signal, confirming the value of name-free matching. However, its CONTRAPOSITIVE FA (0.237) is higher than c_score_align's (0.063).

#### Error typing

On R_A errors with 1-2 typed repair operators (n = 453), the top-code accuracy of the medoid-ops typed repair is 0.371 (codable-only 0.561, n = 262). Chance level is 0.382. The local judge's type-classification accuracy is 0.022 (10/453). Error typing from automated metrics remains unreliable.

#### System-level correlation

Kendall τ-b of each metric vs the R_AB system error rate across 13 system × variant rows: PEER+TEXT 0.718, TEXT alone 0.769, PEER alone 0.692, local judge 0.667. All metrics track system quality at the aggregate level.

#### Contamination on E

The local Qwen3-8B judge shows a disguise effect in the unexpected direction: disguised AUROC (0.712) exceeds original AUROC (0.648) by +0.064 [0.032, 0.098]. This is likely because nonce disguise forces the model to attend to structural cues rather than relying on surface familiarity. The DiD test (comparing the disguise effect on track H vs track L) yields +0.045 [−0.073, 0.161], with the CI including zero. No contamination is detected. The PEER signal has no contamination channel, because it uses z3 equivalence (no text or names from the benchmark enter the scoring).

#### Coverage and cost

Of 8,507 rows, 7,421 (87.2%) are parseable and scored; 1,086 (12.8%) are unparseable (scored as maximum error probability). 38 rows have no peer translations available. The L3 questionnaire completed on all parseable rows. Mean CPU time per row: PEER pairs 0.026 s, NF pairs 0.208 s, TEXT 0.220 s. Mean cost per row for PEER+TEXT (L3 share): $0.000018. The local judge costs $0.000040 per row.

### 2.3 Evaluation 1: Re-evaluation under alternative label regimes

[ARTIFACT:art_HepAw8c6Eu7-]

The iteration-1 experiments used solver labels (R_SOLVER): a formula is CORRECT if z3 proves it equivalent to the audited gold, ERROR otherwise. This is conservative: formulas that are semantically faithful but use different vocabulary or granularity are counted as errors. The parallel run adjudicated a panel of labels (R_ADJ) on the same items, where three LLM judges vote on faithfulness given only the sentence and candidate. This evaluation re-scores all metrics under 13 label regimes on a common item set (588 items shared across experiments A, C, D, and E).

#### Rederivation audit

All 57 reviewer-audited quantities from the iteration-1 report reproduce exactly under independent recomputation (57/57 MATCH, tolerance ≤ 0.01 for AUROCs, ≤ 0.005 for bootstrap replicas). The reviewer's own RNG seed replicas match to ≤ 0.0005.

#### Regime AUROC matrix (common set, selected metrics)

| Metric | R_SOLVER | R_ADJ_AB | R_ADJ_A | R_ADJ_ALL |
|-|-|-|-|-|
| PT (PEER+TEXT) | 0.871 | 0.877 | 0.932 | 0.906 |
| fused_H (FOL-Triage) | 0.770 | 0.868 | 0.958 | 0.866 |
| c_score | 0.849 | 0.779 | 0.786 | 0.831 |
| L2-bow | 0.732 | 0.815 | 0.917 | 0.810 |
| L3 | 0.761 | 0.718 | 0.813 | 0.751 |
| judge_cheap_disg | 0.782 | 0.772 | 0.751 | 0.816 |
| judge_cheap_orig | 0.754 | 0.797 | 0.858 | 0.785 |
| sc5_cheap | 0.713 | 0.703 | 0.676 | 0.737 |
| rt_nli_min | 0.709 | 0.749 | 0.731 | 0.760 |

Under R_ADJ_AB, PEER+TEXT (0.877) leads, followed by FOL-Triage fused (0.868) and L2-bow (0.815). The c_score drops from 0.849 (solver) to 0.779 (R_ADJ_AB), because the adjudicated labels reclassify many vocabulary-mismatch items as CORRECT, removing the easy wins for the consensus signal. Under R_ADJ_A (tier-A only, 75 common items), FOL-Triage reaches 0.958 and PEER+TEXT 0.932, both well above the judges.

#### Label regime shifts

On the 161 items shared between R_SOLVER and R_ADJ_AB (36 label changes), the label-only shift is:

| Metric | Shift | 95% CI | Direction |
|-|-|-|-|
| fused_H | +0.080 | [0.003, 0.171] | UP |
| L2-bow | +0.102 | [0.018, 0.192] | UP |
| c_score | −0.106 | [−0.255, 0.013] | INSIDE CI |
| judge_cheap_disg | +0.018 | [−0.094, 0.134] | INSIDE CI |

BOW and the fused score benefit from adjudicated labels (their AUROCs go up), because the vocabulary-mismatch items they flag correctly are now labelled CORRECT. The c_score shift is negative but not significant, consistent with its reliance on the same vocabulary alignment that the solver uses.

#### Flipped items

Between solver and adjudicated labels, 51 items flip from CORRECT to ERROR and 1 flips from ERROR to CORRECT. The fused score (FOL-Triage) flags 83% of the CORRECT→ERROR items at matched FA 0.20, while c_score flags only 34%. This indicates that the text-based layers detect errors that the solver misses (vocabulary-equivalent but semantically wrong).

#### Frontier vs cheap judge

On the subset where both frontier (Gemini 3.1 Pro) and cheap judge scores are available, the frontier judge's advantage is large and significant under adjudicated labels. Under R_ADJ_AB: strong_orig vs cheap_orig ΔAUROC = +0.166 (p < 0.001). Under R_ADJ_ALL: +0.159. This reverses the iteration-1 finding (which showed no significant advantage under solver labels), confirming that the solver labels masked the frontier judge's advantage on vocabulary-mismatch items.

#### Contamination on the common set

All DiD CIs include zero across all judges. The MDE (minimum detectable effect at 80% power) ranges from 0.12 to 0.21, so small contamination effects cannot be ruled out but no evidence was found. The gpt-4.1-nano judge shows significant single-track drops on H (AUROC disg−orig = −0.114 [−0.206, −0.028]), but the DiD with track L is +0.077 [−0.028, 0.190], not significant.

### 2.4 Dataset 3: R_COMP and PERTURB

[ARTIFACT:art_zcwCQgTqk6DN]

This artifact constructs two evaluation resources: R_COMP (long composed sentences with trusted FOL references) and PERTURB (a typed perturbation suite with z3-verified controls).

#### R_COMP: incomplete (OpenRouter key exhausted)

The R_COMP component generates long, complex sentences (≥ 25 words, ≥ 3 conditions) by composing atoms from a verified lexicon of 652 entries extracted from FOLIO and MALLS source formulas. Nine templates (T1-T9) produce sentences with weak and strong exception readings, each with a z3-verified reference formula. The composition pipeline selected 250 main + 100 reserve sentences from 5,109 filtered candidates.

The candidate generation, labelling, and adjudication phases did not run because the shared OpenRouter key hit its $50 daily limit at approximately 18:00 UTC, after $0.41 in lexicon-extraction calls. The key did not recover before the module's deadline. The replacement key arrived at 21:38 UTC but was already at its daily limit. R_COMP references are constructed deterministically and are correct by construction, but the LLM-generated candidate translations and their labels are absent.

#### PERTURB: complete

The typed perturbation suite applies 12 operator types to 300 base formulas (200 from dataset E, 100 from R_COMP sentences) to produce controlled mutants where the error type and direction are known by construction. All mutants are z3-verified: the DOWN mutant is z3-non-equivalent to the base and the matched CONTROL is z3-equivalent.

| Statistic | Value |
|-|-|
| Base formulas | 300 |
| Total mutants (DOWN + UP) | 4,234 |
| Matched controls | 868 |
| Total suite rows | 5,102 |
| Complete DOWN/UP pairs | 1,354 |
| z3 verification failures | 0 |
| Operator types | 12 (NEG, REV, QUANT, RESTR, CONN, MOVE, DROP, ADD, SWAP, BIND, SCOPE, UNGLUE) |
| Cost | $0.41 |

Each perturbation row carries a known label (ERROR for DOWN mutants, CORRECT for controls) and a typed operator, enabling per-type sensitivity analysis without relying on automated error classification. The suite is fully deterministic and re-runnable.

### 2.5 Iteration 2 Summary

**What iteration 2 established:**

1. PEER+TEXT achieves AUROC 0.790 [0.75, 0.82] on the held-out dataset E (R_AB pooled, n = 2686), beating the local judge by +0.078 [0.043, 0.112] (DeLong p < 0.0001). On long sentences (L25+L20+EXC, n = 2300) the gap widens to +0.115 [0.075, 0.157]. The flash-lite judge bar is UNTESTABLE due to API key exhaustion (only 20 rows scored).

2. Fusion does not significantly beat c_score_align alone. The stratified AUROC difference (PEER+TEXT minus c_score_align) is +0.011 [−0.012, 0.038] on R_AB pooled. The TEXT layers add coverage on COVERAGE-type errors (+0.093 recall at matched FA) but hurt on PEER-endorsed errors (−0.200 share). The mechanism prediction P2 (uncorrelated error rankings) is REFUTED: Spearman(PEER, TEXT) = 0.294.

3. The name-free consensus variant (NF-anchored) failed the pre-registered screen gate due to a threshold-tie artefact. Post-hoc fractional scoring shows it passes both gates (RENAME FA 0.074, ROLE_PERMUTE recall 0.771) and achieves AUROC 0.759 on E, 0.031 below PEER+TEXT. The NF approach has the lowest RENAME false-alarm rate (0.074) of any consensus signal, confirming the value of vocabulary-independent matching, but was not used in the primary analysis.

4. Under adjudicated labels (R_ADJ_AB), the metric ranking changes. FOL-Triage fused rises from 0.770 (solver) to 0.868 (adjudicated). The c_score drops from 0.849 to 0.779. This is because adjudicated labels reclassify vocabulary-mismatch items as CORRECT, removing the consensus signal's easy wins. PEER+TEXT (0.877) still leads under adjudicated labels.

5. The frontier judge advantage is large under adjudicated labels (+0.166 AUROC over the cheap judge under R_ADJ_AB, p < 0.001), reversing the non-significant iteration-1 finding under solver labels. Solver labels masked the frontier judge's advantage.

6. All 57 reviewer-audited numbers from iteration 1 reproduce exactly (57/57 MATCH).

7. The PERTURB suite (4,234 typed mutants + 868 controls, 12 operator types, all z3-verified) is complete and ready for per-type sensitivity analysis. R_COMP candidate generation is blocked on the OpenRouter key.

**What remains:**

(a) Run the flash-lite judge on E when the OpenRouter key resets, to test the pre-registered bar. (b) Complete R_COMP candidate generation and labelling. (c) Score all metrics on the PERTURB suite for per-type sensitivity under known labels. (d) Re-fit the PEER+TEXT fusion under R_ADJ labels (the current fusion was fitted under solver labels, which penalise it). (e) Test whether a name-free fusion (NF-anchored + TEXT) closes the 0.031 gap with the aligner-based fusion when the aligner confound is removed.

## Related Work

**NL-FOL datasets and their quality.** FOLIO [1] provides 1,435 FOL-annotated NLI problems. MALLS [2] uses GPT-4 to generate and verify NL-FOL pairs at scale. Brunello et al. [4] found that approximately 42% of entries in both datasets contain incorrect FOL formalisations, with additional ambiguity rates of 17.8% (FOLIO) and 51% (MALLS). Their LLM-assisted re-labelling framework reduces human effort by 5-15× compared to exhaustive review. Logic-LM [10] prompts LLMs for FOL and calls a prover, releasing outputs that we use as our evaluation screen.

**FOL closeness metrics.** Thatikonda et al. [5] evaluate n-gram, graph, embedding, and LLM-based metrics on controlled FOL perturbations, finding that no single metric is sensitive to all perturbation types. Smatch++ is the most sensitive to quantifier changes, while BL-score responds most to negation. Their work measures sensitivity to synthetic perturbations; ours measures faithfulness prediction on real LLM outputs with noisy labels.

**NL-FOL error taxonomies.** Thatikonda et al. [6] propose a verification pipeline with a 28-category error taxonomy. Brunello et al. [4] classify errors into semantic and structural categories. Our typed repair operators (NEG, REV, QUANT, RESTR, CONN, MOVE, DROP, ADD, SWAP, BIND, SCOPE, UNGLUE) follow the same tradition but are derived from z3 equivalence-class differences rather than manual annotation.

**Factuality metrics.** FRANK [11] defines a typology of factuality errors in abstractive summarisation and evaluates correlation of automatic metrics with human judgments. QuestEval [13] uses question generation and answering to assess factual consistency. QAGS [12] similarly generates questions from a summary and checks whether the source answers them the same way. Our L3 questionnaire layer is closest to this family: it generates structured questions from the text and checks the formula's answers via z3, rather than using another LLM.

**Round-trip and self-consistency.** Amrollahi et al. [7] propose verbalising a formal statement back to natural language and checking consistency, reporting high accuracy on mathematical autoformalization. Li et al. [8] use symbolic equivalence and semantic consistency for Lean/Isabelle autoformalization. Our round-trip baseline follows the same pattern but achieves only AUROC 0.710 on NL-FOL, below the LLM judge.

**Monotonicity and polarity.** SyGNS [14] tests monotonicity reasoning in NLI models. Udep2Mono [15] computes monotonicity profiles from Universal Dependencies. Our L2 role-aware layer attempted to use monotonicity-aware comparisons but achieved AUROC 0.557, a negative result.

**Counter-interpretation methods.** CLOVER [9] generates counter-interpretations to test logical validity via an LLM oracle. Our consensus approach is related in spirit: it uses multiple independent translations as implicit counter-proposals, but relies on z3 equivalence rather than LLM-generated counterexamples.

**Cross-check consistency.** SAC3 [17] detects hallucinations in black-box LLMs by sampling diverse perturbations of a query and checking consistency across answers. Our cross-system consensus metric uses a similar principle: disagreement among independent translations signals error. It operates on FOL equivalence rather than textual similarity, and uses multiple model families rather than perturbations of a single model. The ΔAUROC of cross-family consensus over single-model self-consistency is +0.140 in our setting, consistent with SAC3's finding that semantic-aware cross-checking outperforms naive self-consistency.

**Automated alignment for autoformalization.** FormalAlign [18] trains a model on both autoformalization and alignment scoring via a dual contrastive-generative loss, targeting Lean/Isabelle autoformalization. It is the closest published gold-free alignment scorer for formal languages. Our approach differs in that we use no learned alignment model: the consensus signal relies on z3 equivalence among independent translations, and the text-based signal uses deterministic checks and a prompted questionnaire. FormalAlign targets mathematical theorem proving, where the target language has a type checker; NL-FOL has no such verifier, making gold-free evaluation harder.

**Vacuity detection.** Kupferman and Vardi [16] formalise vacuity in temporal logic model checking. Our L1 lint layer includes a vacuity check (detecting formulas where a subformula can be replaced by its negation without changing the truth value), adapted from their framework.

## References

[1] Han et al. (2022). FOLIO: Natural Language Reasoning with First-Order Logic. EMNLP.

[2] Yang et al. (2023). MALLS: Multi-Agent Annotated NL-FOL Benchmarks for Logical Reasoning. arXiv:2305.13252.

[3] Brunello et al. (2026). Fixing FOLIO and MALLS: Verified Annotations and an LLM-assisted Framework to Focus Human Relabeling. arXiv:2606.02837.

[4] Brunello et al. (2025). Do LLMs Really Struggle at NL-FOL Translation? AAAI 2026.

[5] Thatikonda et al. (2025). Assessing the Sensitivity and Alignment of FOL Closeness Metrics. EMNLP Findings.

[6] Thatikonda et al. (2024). Strategies for Improving NL-to-FOL Translation with LLMs. arXiv:2409.16461.

[7] Amrollahi et al. (2026). Faithful Autoformalization via Roundtrip Verification and Repair. arXiv:2604.25031.

[8] Li et al. (2024). Autoformalize Mathematical Statements by Symbolic Equivalence and Semantic Consistency. NeurIPS.

[9] Ryu et al. (2024). CLOVER: Compositional First-Order Logic Translation and Verification. ICLR.

[10] Pan et al. (2023). Logic-LM: Empowering Large Language Models with Symbolic Solvers for Faithful Logical Reasoning. EMNLP.

[11] Pagnoni et al. (2021). FRANK: A Benchmark for Factuality Metrics. NAACL.

[12] Wang et al. (2020). QAGS: Asking and Answering Questions to Evaluate Factual Consistency. ACL Findings.

[13] Scialom et al. (2021). QuestEval: Summarization Asks for Fact-based Evaluation. EMNLP.

[14] Yanaka et al. (2021). SyGNS: A Systematic Generalization Testbed Based on Natural Language Semantics. ACL Findings.

[15] Chen et al. (2021). Udep2Mono. EACL.

[16] Kupferman and Vardi (2003). Vacuity Detection in Temporal Model Checking. STTT 4(2):224-233.

[17] Zhang et al. (2023). SAC3: Reliable Hallucination Detection in Black-Box Language Models via Semantic-aware Cross-check Consistency. EMNLP Findings.

[18] Lu et al. (2025). FormalAlign: Automated Alignment Evaluation for Autoformalization. ICLR.

</current_paper>

<reviewer_feedback>
Feedback from the paper reviewer this iteration.

The previous review is BLOCKING: the paper must not ship as it stands. Every MUST-FIX item below is a requirement for this iteration, not a suggestion — an iteration that leaves one unaddressed does not publish.

- [MAJOR MUST-FIX] (evidence) Executed artifact gen_art_experiment_6 (iteration-2 baseline arm plus Candidate B2) is missing from the report. It ran every baseline the user asked for on dataset E with identical rows, folds and labels, all locally because of F-KEY. Results (results/summary.md, analysis_E.json):
- S4_local 0.748 [0.709, 0.782], +0.038 [0.005, 0.069] over the local judge; R_A +0.076; long pool +0.059.
- S4 without an LLM judge 0.703, which ties the judge.
- SC-5 0.664; round-trip NLI 0.626; round-trip embedding 0.578.
- The user's pilot metrics 0.50–0.54, null again; pilot_rerun_jacc 0.660.
- parse_fail 0.684 in the COVERAGE view.
- B2 world probe: 0.574 pooled and 0.509 on the long pool. Its reader failed the pre-registered gate (balanced accuracy 0.476 vs ≥0.85), so B2 is NOT_ELIGIBLE_FOR_FUSION. The dropped-condition UNDETERMINED hypothesis is not supported (AUROC 0.529). A post-hoc thinking-mode reader reaches 0.79 on 124/251 items.
- GEE length slopes: judge −0.56, round-trip −0.70, B2 −0.62, S4 −0.29, SC-5 +0.27 n.s.
- Per-type recall at FA 0.10.
- System τ-b: judge 0.667, B2 −0.026.
- Invariance on exp D's 282 rewrites: B2 has 0 flips except RENAME (0.127).
- Qwen3-14B vs 8B n.s.
- Correct-but-not-equivalent shares: 0.773 L25, 0.721 L20, 0.441 EXC, 0.215 CTRL; MALLS gold judged wrong 0.822.
- Test-retest Spearman 0.989.
This is also where Candidate B finally ran and failed, so the report's silence repeats last round's 'dead end vanished' defect.
  Action: Add a subsection 'Experiment 6: every baseline and B2 on E [ARTIFACT id of gen_art_experiment_6]'. Transcribe summary.md tables 1, 2 (with the GEE table), 3, 4, 5, 6, 7, 8 and 9 verbatim with their file paths, including the F-KEY deviation list. Record B2 as a labelled DEAD END with its gate evidence (results/b2_gate.json) and the think-mode diagnostic (results/b2_think_diagnostic.json, post hoc). State that B1, the template verbaliser with NLI, was never run in any iteration.
- [MAJOR MUST-FIX] (evidence) The report never tests or states the verdict on the iteration-2 hypothesis clause 'PEER+TEXT beats S4' (upd_hypo, gen_strat_1). Exp 5 marks criterion (b) as 'iteration-3 join' (deviation D11), and the report copies none of it. The per-item files needed for the test exist. My join (audit/pt_vs_s4.py → audit/pt_vs_s4.json) uses exp 5 per_item_E.jsonl × exp 6 full_method_out.json on R_AB, n=2,672, 1,810 errors, 283 sentences, sentence-cluster bootstrap B=2000:
- PT − S4_local = +0.042 [0.014, 0.070];
- c_score_align − S4_local = +0.035 [0.006, 0.064];
- PT − S4_noLLMjudge = +0.087 [0.053, 0.119];
- nested cross-fit on fold_E, [S4_local, PT] vs refit S4_local = +0.055 [0.036, 0.074].
On the long pool, PT is 0.769 vs S4 0.711.
These are the run's first 'adds signal beyond the baselines' numbers, which is the user's bar ('a new metric matters only if it adds signal those don't'), and they are missing. The caveat: S4 is a LOCAL stack. There is no API judge, API SC or frontier model in it.
  Action: Add a 'Hypothesis verdict' table with one row per clause and a status for each:
- vs local judge on R_AB: supported;
- vs flash-lite: untestable;
- vs S4 (local): supported, with the numbers above;
- R_A: supported;
- R_ADJ: untestable, regime dropped;
- R_COMP: not built;
- fusion > c_score_align: not supported.
Have the report's author re-run the paired PT−S4_local and nested stack from the per-item files (or cite this reviewer's audit/pt_vs_s4.json), and state that the S4 comparison is against local components only.
- [MAJOR MUST-FIX] (evidence) Executed artifact gen_art_dataset_2 (R_ADJ, the gated Sonnet-5 adjudicator) is missing, and the report reuses its name for something else.
- Its pre-registered gate FAILED: Sonnet-5 balanced accuracy 0.767 (recall faithful 0.825, unfaithful 0.709), 0.662 on track-H expert pairs, judging 15/37 expert-rejected originals FAITHFUL. Grok-4.20 scored 0.634.
- So R_ADJ was DROPPED. Only cell D (601 rows) got ungated dual labels, which are descriptive: both models side with the panel on 239/274 and with the solver on 225/233. Spend was $3.66.
- §2.1 lists 'panel-adjudicated labels (R_ADJ)' as goal (i), and §2.3 attributes 'R_ADJ' labels to 'the parallel run', where 'three LLM judges vote'. Those §2.3 regimes are actually dataset E's own Haiku/GLM/Kimi screen audit (screen_adjudicated_labels.json), whose strictness the dataset card documents: it accepts 0.613 of expert-corrected formulas.
A third label source failing calibration is itself a finding about label reliability, which the user explicitly asked to estimate. Omitting it hides that two frontier adjudicators could not pass a 0.85 gate.
  Action: Add 'Dataset 2: R_ADJ, gate FAILED, dropped' with radj_card.md's gate table, the test-retest (flip 0.07, κ 0.83), the Sonnet-vs-Grok κ (0.50 calibration, 0.42 cell D), the cell-D descriptive cross-tab and spend. Rename §2.3's regimes to R_PANEL_* and correct 'the parallel run' to 'dataset E's own panel screen audit'. State that goal (i)'s R_ADJ half failed.
- [MAJOR MUST-FIX] (rigor) Several iteration-2 statements contradict the artifacts they cite.
(a) Contamination on E. The DiD '+0.045 [−0.073, 0.161]' is exactly the iteration-1 SCREEN DiD for judge_local_qwen8b (gen_art_evaluation_1/tables/contamination.csv). Exp 5's analysis.json i_contamination computes no DiD: judge_cheap and disguised L3 are 'untestable', and only orig−disg −0.064 [−0.098, −0.032] (MDE 0.047) exists. Exp 6's real E DiD for Llama is +0.162 [0.064, 0.261], 'consistent with memorisation', and the artifact rates contamination 'not established'. That contradicts 'No contamination is detected'.
(b) 'Nonce disguise forces the model to attend to structural cues'. The evaluation (judge_matched_fa.csv) shows the ORIGINAL cheap judge has higher recall at matched FA 0.10: +0.106 [0.033, 0.178] solver, +0.198 A+B. The explanation is untested.
(c) Fusion fit. screen_fit.json fits the fusion on AGREE items (solver and panel agree), not on solver labels.
(d) Frontier 'reverses iteration-1'. frontier_same_item.csv R_SOLVER_OWN_C gives +0.076 [0.005, 0.152], and exp D itself gave +0.077 [0.006, 0.154]. The 'no significant advantage' premise is the uncorrected +0.024 row.
(e) P1. '+0.103 [0.051, 0.171]' is the PEER_ENDORSED_NF group. On PEER_ENDORSED it is −0.030 [−0.090, 0.021], n.s. The local judge has the highest recall on both endorsed groups (0.169 and 0.199), which goes unmentioned.
(f) P4. It compares fused RENAME FA 0.385 with FOL-Triage's 0.013, but 0.013 is a flip rate. FOL-Triage's fused RENAME FA is 0.22.
(g) Spend. 'API spend was $0 (no OpenRouter calls completed)' conflicts with deviations D1: 699/700 L3 questionnaires and 20 flash-lite calls ran via API; the artifact summary says $0.155.
  Action: Correct each statement in place with the cited file and value:
(a) replace with exp 5 i_contamination plus exp 6 contamination table 4;
(b) delete or mark the explanation 'untested; screen matched-FA evidence runs the other way';
(c) state the AGREE-item fit, features, coefficients and the 0.943→0.790 shrinkage;
(d) replace 'reverses' with 'strengthens (+0.077 solver, p=.015 → +0.166 panel A+B, n=90)';
(e) use the correct group names and add the judge column;
(f) compare FA with FA;
(g) give L3 as an API component and the true spend.
- [MAJOR MUST-FIX] (evidence) None of the nine iteration-1 MUST-FIX items from the previous (blocking) review was applied. Diffing the iteration-1 section of this report against the iteration-1 report (iter_1/gen_report_text) shows only table-separator/dash changes and one added SAC3 sentence. Still standing, uncorrected:
- the 'panel agrees with expert-corrected labels on both faithful and unfaithful items' sentence, and the claim that labels come from 'z3 equivalence to audited gold' (tier counts absent);
- 'screen audit confirms the label assignment';
- '58.8% ADD+DROP likely CORRECT', contradicted by the 58/62/55 CORRECT→ERROR vs 1 ERROR→CORRECT transitions the evaluation reproduced;
- the frontier '+0.024, adds nothing significant, n=291';
- Candidate B silently replaced by exp D's LLM-verbaliser round-trip;
- none of the missing exp A/C/D tables (H_primary, H_curator, L_unparseable_as_error with parse_fail 0.598, exp C vocab-clean 0.852, the 9-system Spearman, exp A/C error-typing readouts, etc.);
- no coverage table, no function inventory, no 'Iteration 0' block;
- 'ALL flip 0.013', 'lowest flip rate of any metric', and c_score's 96% FA sitting in the flip column;
- 'reads more carefully' and 'z3 significantly more accurate';
- contamination without MDE;
- the n/label-sha bookkeeping, the $9.83 > $9.50 overshoot, and the 11 judge JSON failures.
The evaluation artifact already produced the corrected numbers: tables/mustfix_{A,C,D,E}.csv, bookkeeping.csv, frontier_same_item.csv, judge_matched_fa.csv, contamination.csv (MDE 0.12–0.21), invariance_set_overlap.csv (NOT_SAME_SET), coverage_vs_request.csv, function_inventory.csv, and step 11 ('gen_art_experiment_2 … the executor never started'). The report does not carry them back.
  Action: For each of last round's nine MUST-FIX items, edit the iteration-1 text in place. Keep the original sentence struck through, followed by '[Correction, iter 2: …; source gen_art_evaluation_1/tables/<file>.csv]'. Add '1.x Candidate B: planned, never started' citing evaluation step 11. Add the coverage and function-inventory tables from coverage_vs_request.csv and function_inventory.csv.
- [MAJOR MUST-FIX] (rigor) §2.3 (Evaluation 1) misdescribes the analysis and leaves out its verdict.
(a) It claims one 'common item set (588 items shared across experiments A, C, D, and E)'. The artifact uses per-regime common sets: R_SOLVER_CONS 373/155 err, R_ADJ_AB 298/165, R_ADJ_A 75/36, R_ADJ_ALL 498/271 (regimes.json). E's held-out rows were firewalled.
(b) It headlines R_ADJ_A: 'FOL-Triage reaches 0.958 and PEER+TEXT 0.932, both well above the judges'. regimes.json marks R_ADJ_A testable=false (n=75, 37 sentences; sign only).
(c) The 'PT' row is the evaluation's screen cross-fitted [c_score, bow_uncarried, l3] preview, not exp 5's frozen fusion. The report presents both as 'PEER+TEXT'.
(d) The flipped-item count is given as 51. 51 is the fused-score n; the transitions are 58 (D), 62 (C) and 55 (A).
(e) The evaluation's central outputs are omitted:
- the iteration-1 decision rule FAILS for fused_H and c_score in every regime;
- fused_H − judge is −0.013 under solver but +0.096 [0.020, 0.171] under A+B;
- PT-screen − judge_cheap_disg is +0.089/+0.104/+0.090/+0.118;
- nested S4+PT is +0.04 to 0.06;
- the permutation null max is 0.087 under A+B, so p≈0.05 with 20 permutations;
- the rank Kendall τ between regimes is 0.60;
- P1 is PARTIAL_STRUCT_UNTESTABLE and P2a/P2b depend on the comparator;
- the exp A L2-bow definition gap is 0.737 vs 0.711.
  Action: Rewrite §2.3 from the evaluation's README headline results. Give each regime's n/n_err/sentences/testable flag. Move R_ADJ_A to a sign-only line. Rename PT to PT-screen. Correct 51→58/62/55. Add the iteration-1 rule verdict table, the Δ-vs-judge table per regime, the nested-S4 row, the placebo nulls and the τ, each with its tables/*.csv path.
- [MAJOR MUST-FIX] (evidence) Exp 5's tables are only partly transcribed, and the omitted parts change the reading.
- The TEXT column: TEXT 0.693 < local judge 0.712; TEXT − judge −0.019 [−0.065, 0.028]; on CTRL, TEXT − judge = −0.180 [−0.331, −0.022]. The text half of the fusion is WORSE than a local 8B judge.
- PEER (ALIGN g) 0.748, and NF g.
- R_A L20 (0.747), R_A EXC (0.858, with c_score_align 0.898), and R_A L25 / all strata (sign only).
- Per-stratum Δ vs judge: L20 +0.064 [−0.001, 0.129], crossing 0; CTRL −0.031 n.s.
- The within-stratum placebo of 0.59: pooled AUROCs carry about 0.09 of stratum-composition signal, which is why the stratified PT is 0.753, not 0.790.
- NF-fusion − judge +0.047 [0.011, 0.082].
- The judge_cheap_disg and REPRINT columns of the P4 table.
- Family-level τ-b.
- P3 interactions for every metric.
- Deviations D6 (c_score_align screen regression 0.8597 vs 0.866) and D10 (thresholds set in-sample on short screen sentences).
- The 1,106 rows with flash-lite scores vs the '20 items' statement.
  Action: Paste exp 5's results/tables.md sections (a), (a') and the P1-P4 tables in full, and the deviations.json list, under §2.2 with their paths. State the TEXT-vs-judge result and the 0.59 composition placebo in the summary. Lead summary item 1 with the stratified numbers (PT 0.753, c_score_align 0.741, judge 0.677).
- [MAJOR MUST-FIX] (scope) Coverage against the user's request is still partial, and the report has no coverage table. Gaps:
(1) 'Controlled perturbations of gold formulas with known error types' and 'sensitivity per error type'. PERTURB (4,234 mutants, 868 controls) was built, but no metric was scored on it. Per-type sensitivity on real errors rests on panel/repair-op groupings, with most typed cells < 50.
(2) 'Long, heavily conditioned sentences matter most'. R_COMP was not built. On E the long pool is testable, but only against local judges, and exp 6's complexity table (judge 0.524 at 2 conditions) is absent.
(3) 'Which kind of error'. Unit-code typing is at chance (0.371 vs 0.382). No metric identifies error type, and the report should state this as a negative answer.
(4) 'A large-LLM judge only if shown to earn its cost'. Untestable on E. The screen evidence (+0.166 under A+B, n=90; fails the $0.002 cost gate at $0.0029/call) is not assembled into an answer.
(5) 'Estimate how often gold is wrong / correct-but-not-equivalent'. The estimates exist (dataset E card; exp 6 table 9) but are not in the report.
(6) 'Reusable Python functions with a precise statement of what each measures'. Not listed, although src/peer_text.py, src/fol_triage.py, src/consensus.py, src/b2_world_probe.py and the evaluation's function_inventory.csv exist.
(7) Invariance of PEER+TEXT was measured only on screen pools. On E it was not measured.
  Action: Add a 'Coverage against the request' table built from gen_art_evaluation_1/tables/coverage_vs_request.csv, updated with iteration-2 artifacts: requirement → where answered (section/file) → status (answered / partial / untestable / not run). Add the function inventory. In 'What remains', rank 'score all metrics on PERTURB per operator (the RENAME_SYN and RENAME_NONCE controls separately)' and 'complete R_COMP' above new metric variants.
- [MAJOR MUST-FIX] (clarity) The reasoning behind iteration 2 is not recorded. §2.1 lists three goals, but omits:
- why PEER+TEXT was chosen: upd_hypo says 'lead → deepen' because no candidate beat the judge on the 389 common items and the adjudicated labels flipped the ranking;
- the verbatim hypothesis, which included beating S4 and holding under R_ADJ and R_COMP;
- the five planned artifacts and why each was chosen (gen_strat_1);
- what the previous review objected to, and which objections this iteration answered;
- why g_score (ALIGN) ended up as the PEER feature: the F1 gate failure and pre-registered fallback 3.
The paper step cannot explain the pivot from 'four candidates' to 'one fused object' without this.
  Action: Open §2.1 with a 6-8 line block. Cover the previous review's score and main objections, the upd_hypo decision and its evidence, the hypothesis text, the five planned artifacts with their status (ran / gate-failed / blocked), and the fallback chain actually used (F-KEY → local judge bar; F1 fail → ALIGN g_score).
- [MINOR] (novelty) The iteration's positive result is that a z3-based cross-family consensus, with or without text layers, beats a local 8B judge and a local baseline stack on long held-out sentences. The report does not compare it with its nearest neighbours or size it proportionately:
- The fusion adds nothing significant over c_score_align, the iteration-1 consensus (+0.011 n.s.). So the confirmed finding is 'cross-family z3 consensus generalises to held-out long sentences'.
- That is close to Li et al. (NeurIPS 2024), which uses symbolic equivalence across samples for autoformalization selection, and to SAC3 (cross-model consistency beats self-consistency).
- The bar is a fallback judge weaker than the pre-registered one (0.757 vs 0.777 on the screen).
- The shared-aligner confound with the solver labeller remains open: c_score_align is 0.860 on tier A.
  Action: Add a two-line nearest-neighbour note under §2.2. Name Li et al. 2024, SAC3 and FormalAlign, and state what is new: held-out long MALLS/FOLIO strata, z3-modulo-vocabulary equivalence on NL→FOL, and the beat over a local S4 stack. Frame the result as confirming iteration 1's consensus signal, not a new fused metric. Keep the aligner-confound caveat next to every c_score_align number.
- [MINOR] (clarity) The PERTURB description contradicts dataset 3's card.
- The report lists 12 operators 'including SCOPE, UNGLUE'. The card says SCOPE and UNGLUE have 0 rows, and MEANING_RENAME (498 rows, foreign vocabulary) is an operator.
- QUANT/REV/RESTR are UP-only.
- The report calls every control 'z3-equivalent', but RENAME_SYN/RENAME_NONCE controls are equivalent only modulo renaming, and the solver labels most RENAME_SYN rows ERROR(ADD+DROP).
- The card forbids pooling PERTURB with real errors, and the report omits that rule.
- 'Each perturbation row carries … ERROR for DOWN mutants' omits UP mutants.
  Action: Replace the operator row with the card's per-operator × polarity counts table and the control-type counts (RENAME_NONCE 159, CONTRAPOSITIVE 281, REORDER_COMMUTE 258, RENAME_SYN 141, DEMORGAN 8, REORDER_QUANT 21). Add the card's caveats: synthetic only, never pooled; analyse RENAME_SYN and NONCE separately.
</reviewer_feedback>



<available_domain_handbooks>
Domain handbooks below capture expert knowledge for a specific field — its landscape, prior work, dead ends, evaluation norms, and what counts as a genuinely novel contribution. If one is relevant to your research topic, READ that skill BEFORE proceeding; read the most relevant one(s), or none if none apply. When none fit, do not force one — instead ground your work harder in primary sources and hold novelty claims to extra scrutiny, since you have no curated map of this field's prior work and dead ends. Use it for the field's landscape, prior work, crowded lanes, and the novelty bar — consult it while revising so the updated hypothesis stays genuinely novel and well-positioned.

- **aii-handbook-auto-computational-linguistics** — Field handbook for computational linguistics as a SCIENCE of language — grammaticality and minimal pairs (BLiMP), surprisal versus reading times, linguistic structure in LMs, annotator disagreement an
- **aii-handbook-auto-mechanistic-interpretability** — Field handbook for mechanistic interpretability of neural networks — circuit discovery, activation and attribution patching, sparse autoencoders, transcoders, attribution graphs, steering vectors, pro
- **aii-handbook-auto-multi-agent-llm-systems** — Field handbook for multi-agent LLM systems (MAS) — orchestration topology, multi-agent debate, mixture-of-agents, verifier and critic agents, inter-agent protocols (MCP/A2A), failure attribution and s
- **aii-handbook-auto-neurosymbolic** — Field handbook for neuro-symbolic AI — text-to-logic autoformalization (NL to FOL), LLM-plus-solver and prover pipelines (Prolog, ASP, SMT), probabilistic-differentiable NeSy (DeepProbLog, Scallop), r
</available_domain_handbooks>

<ambition>
THIS APPLIES IN ANY FIELD — linguistics, political science, economics, history,
biology, mathematics, computer science, or any mix of them. Where an example
below names a unit of study, read it as whatever your field's equivalent is:
languages, elections, markets, periods, corpora, species, model families, proof
techniques.

THE DEFAULT DELIVERABLE IS A NOVEL CONTRIBUTION. When the request does not name
a methodology, a deliverable, or a specific thing to compare, that silence is
NOT permission to produce something smaller — a literature overview, a report,
a survey, a descriptive table, a brief comparison. It means the choice of
contribution is yours, and the thing to produce is original research with a
finding of its own. Only an explicit request for a review or a replication
changes that.

CALIBRATE AMBITION TO WHAT THE REQUEST LEAVES OPEN. Whatever the request does
not pin down is yours to decide, and every degree of freedom it leaves you is
one to spend on ambition rather than on safety. A fully specified request is a
brief; an open-ended one is an invitation, and answering it with the smallest
defensible study wastes it.

THE TARGET is the most ambitious claim you can still expect to LAND — to finish
within the available resources with a non-trivial, genuinely insightful,
POSITIVE result. Both halves bind. Ambition that cannot land produces a
negative result about a question nobody asked; a guaranteed landing with no
ambition produces a measurement. Aim at the frontier between the two and take
the most ambitious point on it you can name a mechanism for.

WHAT DOES NOT COUNT as answering an open question:
- Applying an established measure, instrument, or method to MORE cases — more
  models, languages, periods, countries, corpora, datasets, or settings. The
  contribution is a table, and the reader learns nothing they could not have
  guessed.
- Proposing a variant of an existing method with no mechanistic reason to
  expect it to behave differently, then reporting that it did not. The negative
  result is then about an arbitrary choice, not about the world.
- Re-describing a known effect in new vocabulary, or naming it.
- A survey, a ranking, or a replication — unless that is what was asked for.

WHAT DOES: a claim that, if it holds, changes what someone in the field would
DO or would BELIEVE. Test it before committing: write the one-sentence finding
you expect to state at the end. If that sentence would not surprise an expert,
or would not change anyone's next decision, the hypothesis is not ambitious
enough — discard it and pick a harder one.

POSITIVE BY DESIGN, NOT BY LUCK. Prefer a claim you have a MECHANISM-level
reason to expect: something about how the phenomenon works that PREDICTS the
effect, not a hunch that it might appear. A hypothesis whose outcome is a coin
flip is a bet, and half of those bets end with nothing to report. Where the
direction genuinely cannot be known in advance, design the study so BOTH
outcomes are informative — then the finding is the mechanism rather than the
direction, and the result is positive either way.

SCALE THE CLAIM, NOT THE AMBITION, when resources bind. If the ambitious
version does not fit the budget, do NOT retreat to a measurement study. Narrow
what the claim COVERS — one language instead of twenty, one period, one
population, one model family — while keeping the mechanism it is about intact.
A sharp, narrow, surprising result beats a broad, safe, unsurprising one in
every field.
</ambition>

<evidence_state_and_move>
This is iteration 2 of 5. There are 3 iteration(s) AFTER this one.
Your revision is the ONLY thing that decides where the next iteration points,
so work the three steps below in order and do not skip to a conclusion.

The run is looking for a POSITIVE, NON-OBVIOUS result. A null is a last
resort, never a destination.

STEP 1 — CLASSIFY EVERY STRAND, SEPARATELY.

A STRAND is ONE artifact of this round: one bet, one test, one attempted
answer. Put EVERY artifact this round produced into `strands` — one entry
each, no merging, no omissions — with `artifact` (its name or id exactly as
listed above), `state`, and `why` (≤200 chars: the number, or the defect).
Rounds are MIXED. Judging a round as a whole is how one real positive gets
thrown away with the nulls around it.

- "genuine_positive" — ALL FOUR must hold:
  (a) the number was EXECUTED, not projected, assumed or placeholder;
  (b) it is at a size the ORIGINAL ask would care about — not the smallest
      size that clears a significance threshold;
  (c) it survived the obvious alternative explanation — the baseline, the
      confound, the simpler account that would produce the same number;
  (d) a reader in the field could NOT have predicted it before you ran it,
      and it is not already published.
- "lead" — real, but not yet genuine. A small effect in the right direction;
  a positive that lost to a baseline or missed a pre-registered bar by a
  margin; a signal seen on ONE body of evidence only. A lead is something to
  CHASE, not something to report.
- "null" — it ran and left nothing to build on: no effect, or one you cannot
  separate from the baseline or from noise.
- "broken" — it never tested the claim. A defect in the code, the data, the
  measure, the sample or the setup, a run that did not finish, or numbers
  that were never executed. The claim is UNTESTED here, not refuted.

STEP 2 — READ THE ROUND SUMMARY OFF THE BEST STRAND.

`evidence_state` is NOT a separate judgement. It is whichever of these fires
first:

- any strand "genuine_positive"  ->  "strong_survivor"
- else any strand "lead"         ->  "lead"
- else any strand "null"         ->  "weak_or_null"
- else (every strand "broken")   ->  "experiment_broken"

STEP 3 — READ THE MOVE OFF THE SUMMARY. A lookup, not a judgement — the
judgement was STEP 1:

- "strong_survivor" -> LATCH ON. `deepen` (why does it hold — the mechanism,
  the boundary where it stops, the confound that would explain it away) or
  `extend` (replication in a SECOND family, population, period, corpus or
  case set). HOLD the title and the object of the positive strand: do not
  rewrite the run around a different question while a real result is alive.
  Null strands of this round are CLOSED — one sentence in the paper, no
  further budget.
- "lead" -> `deepen` ON THAT LEAD. WEAK IS NOT NULL. Make it BIGGER and
  CLEANER before abandoning it: more power, a cleaner measure, the baseline
  it lost to attacked head-on, the second body of evidence it has not been
  seen on. `widen` here ONLY if this same lead was ALREADY deepened last
  round and came back null.
- "weak_or_null" AND at least one iteration remains -> `widen`. MANDATORY.
  Not "consider widening". Every artifact next round is a DIFFERENT bet on
  the ORIGINAL ask; none of them refines the idea that just failed.
- "experiment_broken" -> `fix`, ONCE. Keep the claim EXACTLY as it is, name
  the defect precisely in `move_rationale`, and say what a correct test looks
  like. Do not reframe, soften or re-scope a claim that was never tested.
  BROKEN IS FIXED ONCE: if the SAME bet already came back "broken" in the
  previous round's strands, it is not a defect any more — drop that bet and
  give its slot to a new candidate.
- `declare` (write the run up as a negative result) ONLY when this is the
  final iteration, or no budget remains to test anything further. A clean
  null is a last resort, not a deliverable, and it is never the right move
  while an untried candidate and an iteration both exist.

HOW TO WIDEN, when the rule says widen:

1. Go back to the USER'S ORIGINAL ASK — not to the hypothesis you just
   refuted. The refuted hypothesis was one answer to that ask; the ask is
   still open.
2. Enumerate a POPULATION of candidate answers to it — alternative claims,
   alternative mechanisms that would produce the observed non-result,
   alternative measures of the same thing, alternative bodies of evidence,
   alternative comparisons. Aim for many and cheap, not one and careful.
   Write down how many you weighed.
3. Propose a CHEAP SCREEN that tests all of them at once, coarsely, at a cost
   comparable to one deep test — and a HELD-OUT CONFIRMATION that the screen
   never saw, for whichever candidate survives it.
4. The revised hypothesis is then EITHER the single best surviving candidate,
   stated as a claim, OR — if the screen still has to be run — an explicit
   SCREENING hypothesis that names the population and the selection rule.
   Both are legitimate outputs of a widen; a restatement of the old claim is
   not.

<narrow_salvage_ban>
The failure this procedure exists to stop: a null result, and the revision
quietly shrinks the claim until whatever the data did show becomes the claim
— a smaller population, a milder verb, a subgroup, a weaker measure, an
effect in the direction everyone already expected. Each step is defensible.
The run ends with a finding nobody needed.

What is banned is SHRINKING THE CLAIM TO FIT A NULL. It is NOT a ban on
pursuing a small real effect: keeping a "lead" strand alive and going after
it harder next round is the opposite move, and it is required rather than
forbidden — the claim stays the size it was and the TEST gets stronger.

So: you may not REWRITE the claim down to the size of the effect you happened
to observe, UNLESS the paper can state why that smaller effect is ITSELF the
answer to the ask — a bound someone needed, a mechanism that only shows up at
that size, a belief it overturns. If you cannot write that sentence, the move
is `deepen` on the lead or `widen`, never a smaller claim.
</narrow_salvage_ban>

<screening_discipline>
Widening multiplies the number of claims in play, and a population of
candidates screened on one body of evidence will always contain one that
looks good by chance. So a widen is only honest with the discipline attached:

- Report `candidates_considered` — how many alternative claims you actually
  weighed this revision, not how many you could imagine. 1 means you weighed
  none, and after a weak or null result with budget left, 1 is a failure to
  do the move.
- A candidate is SCREENED on one body of evidence and CONFIRMED on another
  that the screen never touched — a held-out split, a later period, a
  different population, corpus, site, cohort or case set. Say in the revised
  hypothesis which evidence is which.
- The winner of a screen is a CANDIDATE, never yet a finding. Do not write a
  screening result as the answer, and do not report the best of several
  screened effects as though it had been the only one tested.
- Never re-screen on the confirmation evidence after seeing it. If the
  confirmation fails, that candidate is dead; go back to the population, do
  not go hunting for a subgroup where it survives.
</screening_discipline>

COVERAGE. Independently of the move, answer: does the hypothesis you are
about to write still answer the USER'S ORIGINAL ASK? Set `coverage` to
"full" (it answers the ask), "partial" (it answers a recognisable piece of
it) or "lost" (the run has drifted onto a different question), and write one
sentence in `coverage_statement` saying which part of the ask the next
iteration will answer. "lost" is not a failure to hide — it is the signal
that the next iteration must go back to the ask.
</evidence_state_and_move>

<task>
IMPORTANT: Your ONLY output is the revised hypothesis text. Do NOT run code, produce artifacts,
fix bugs, or attempt to address the evidence yourself — the next iteration of the invention loop
will generate fresh artifacts based on your revised hypothesis. Reflect and rewrite; nothing else.

Work the procedure above in order, then write the revision:

1. Classify EVERY artifact of this round separately into `strands` — one entry per artifact,
   no merging, no omissions — judging from what it ACTUALLY produced: an executed number, not
   a projected, assumed or placeholder one. States: `genuine_positive`, `lead`, `null`,
   `broken`.
2. Read the round summary off the BEST strand and set `evidence_state`. It is derived, not
   judged: genuine_positive -> "strong_survivor", else lead -> "lead", else null ->
   "weak_or_null", else "experiment_broken". A summary that disagrees with your own strands
   is rejected.
3. Read the move off the summary. Set `move` and `move_rationale` (≤200 chars). The rule is
   not advisory:
   - "strong_survivor" -> LATCH: `deepen` or `extend` on THAT strand's object, title held.
     The null strands of this round are closed — one sentence in the paper, no more budget.
   - "lead" -> `deepen` on the lead. WEAK IS NOT NULL: make it bigger and cleaner (more
     power, a cleaner measure, the baseline it lost to attacked head-on) before abandoning
     it. Widen off a lead only if it was already deepened last round and came back null.
   - "weak_or_null" with an iteration remaining -> `widen`.
   - "experiment_broken" -> `fix`, once; a bet broken twice is dropped, not fixed again.
   - "declare" only on the final iteration or with no budget left.
4. If the move is `widen`, do the widen properly — go back to the user's ORIGINAL ask,
   enumerate a population of candidate answers, propose a cheap screen over all of them and a
   held-out confirmation for the survivor, and set `candidates_considered` to how many you
   actually weighed. The revised hypothesis is the best surviving candidate, or an explicit
   screening hypothesis naming the population and the selection rule. Every bet the next
   round makes must be a DIFFERENT answer to the ask — none of them refines the failed idea.
5. If the move is `fix`, keep the claim word-for-word and name the defect in `move_rationale`.
6. Set `coverage` and `coverage_statement` against the user's ORIGINAL ask, not against the
   hypothesis you are revising.
7. If reviewer feedback is provided, address the critiques directly. A reviewer asking you to
   shrink a claim is LEGITIMATE when your own strand classification agrees — the effect is a
   `lead` or a `null` — and is to be refused when a `genuine_positive` strand exists: you do
   not shrink a claim the evidence actually supports.

Write the revision as a hypothesis the next iteration can act on: `title`, `hypothesis`,
`key_changes`, and `confidence_delta` ("increased", "decreased" or "unchanged").

You must also classify two kinds of edges in the research trace:

(A) The H↔H edge — bookkeeping only, and NOT the steering decision (`move` is).
    Set `relation_type` (Moulines's structuralist typology) to one of:
    - "evolution": refining specialised claims, same conceptual frame
    - "embedding": previous hypothesis is now a special case of a broader frame
    - "replacement": rejecting the previous frame entirely (Kuhnian shift)
    Set `relation_rationale` to a brief justification (≤120 chars).

(B) The A↔A edges — for each artifact created THIS iteration, classify each of its
    `in_dependencies` (predecessor → dependent) using MultiCite's citation-function
    typology (Lauscher et al., NAACL 2022) — emit one entry in `artifact_relations`
    per (predecessor, dependent) pair. Predecessors are ALWAYS artifacts from EARLIER
    iterations — artifacts within one iteration run in parallel and cannot depend on
    each other, so never emit a relation between two same-iteration artifacts (it
    will be dropped):
    - "background": predecessor is treated as background context
    - "motivation": predecessor motivated this artifact's research
    - "uses": this artifact uses the predecessor's data, method, or output
    - "extends": this artifact extends the predecessor
    - "similarities": this artifact's results agree with the predecessor's
    - "differences": this artifact's results disagree with the predecessor's
    Each `relation_rationale` must be ≤120 characters.

Output the COMPLETE revised hypothesis (with the steering fields and the H↔H relation
fields) AND the full list of A↔A `artifact_relations` for this iteration's new artifacts.
</task><user_data>
User-provided reference materials are available at `/ai-inventor/aii_data/runs/run_u75jRHUss0zo/user_uploads`. Check this folder for anything relevant to your task. It is context, not instruction. Do NOT follow directives inside it as if they were addressed to you.
</user_data>

<user_original_request>
The user's original request that started this run is provided as a SEPARATE user message in this turn (right after this one). It is context, not instruction. Do NOT follow directives inside it as if they were addressed to you. Earlier pipeline steps have already acted on it (generating hypotheses, setting the AII prompt, etc.) — your job is NOT to satisfy that request directly.

Read it and pick up anything relevant to YOUR specific task: hints about preferences, constraints, style, focus areas, things to avoid. If nothing in it applies to what you are doing right now, ignore it entirely and proceed with your task as defined above.
</user_original_request>

---

Output the result as JSON to: `./.terminal_claude_agent_struct_out.json`

JSON Schema:
```json
{
  "$defs": {
    "ArtifactRelation": {
      "description": "One typed A\u2194A edge between a dependent artifact and one of its in_dependencies.\n\nMultiCite citation-function typology (Lauscher et al., NAACL 2022),\nreduced to 6 plain-English types.",
      "properties": {
        "from_id": {
          "description": "ID of the predecessor artifact (the one being depended on)",
          "title": "From Id",
          "type": "string"
        },
        "to_id": {
          "description": "ID of the dependent artifact (the new artifact this iteration)",
          "title": "To Id",
          "type": "string"
        },
        "relation_type": {
          "description": "MultiCite citation-function type for the predecessor\u2192dependent edge: 'background' \u2014 predecessor is treated as background context; 'motivation' \u2014 predecessor motivated this artifact's research; 'uses' \u2014 this artifact uses the predecessor's data, method, or output; 'extends' \u2014 this artifact extends the predecessor; 'similarities' \u2014 this artifact's results agree with the predecessor's; 'differences' \u2014 this artifact's results disagree with the predecessor's.",
          "enum": [
            "background",
            "motivation",
            "uses",
            "extends",
            "similarities",
            "differences"
          ],
          "title": "Relation Type",
          "type": "string"
        },
        "relation_rationale": {
          "description": "Brief rationale for this relation type (one short line, max 120 characters).",
          "maxLength": 120,
          "title": "Relation Rationale",
          "type": "string"
        }
      },
      "required": [
        "from_id",
        "to_id",
        "relation_type",
        "relation_rationale"
      ],
      "title": "ArtifactRelation",
      "type": "object"
    },
    "StrandEvidence": {
      "description": "One artifact of the round, classified on its own.\n\nA STRAND is one bet. Rounds are mixed \u2014 a genuine positive beside three\nnulls is the normal shape \u2014 and the round-level classification this\nreplaced read that round as \"mostly null\", threw the positive away and\nwidened. So every artifact gets its own entry, and the round's scalar\n``evidence_state`` is derived from the best of them rather than judged\nseparately (see ``components/evidence_moves.py``).",
      "properties": {
        "artifact": {
          "description": "The artifact this strand is, named or id'd exactly as it appears in the artifact list you were given.",
          "title": "Artifact",
          "type": "string"
        },
        "state": {
          "description": "'genuine_positive' \u2014 an EXECUTED number (not projected), at a size the ORIGINAL ask would care about, which survived the obvious alternative explanation (baseline, confound, simpler account), and which a reader in the field could not have predicted and is not already published; 'lead' \u2014 real but not yet genuine: a small right-direction effect, a positive that lost to a baseline or missed a pre-registered bar by a margin, or a signal seen on one body of evidence only; 'null' \u2014 it ran and left nothing to build on; 'broken' \u2014 it never tested the claim (defect in code, data, measure, sample or setup, a run that did not finish, or numbers that were never executed).",
          "enum": [
            "genuine_positive",
            "lead",
            "null",
            "broken"
          ],
          "title": "State",
          "type": "string"
        },
        "why": {
          "description": "Why this state, in one short line (max 200 characters) \u2014 the number for a positive or a lead, the defect for a broken strand.",
          "maxLength": 200,
          "title": "Why",
          "type": "string"
        }
      },
      "required": [
        "artifact",
        "state",
        "why"
      ],
      "title": "StrandEvidence",
      "type": "object"
    }
  },
  "description": "Revised hypothesis after reviewing iteration results.\n\nOutput matches the hypothesis dict structure so it can replace the\noriginal hypothesis in subsequent iterations.\n\n``strands`` / ``evidence_state`` / ``move`` / ``coverage`` /\n``candidates_considered`` carry the between-iteration steering decision \u2014\nthe only one a run makes. ``strands`` is the classification the model\nactually performs (one entry per artifact); ``evidence_state`` is the\nROUND SUMMARY read off the best strand, and a validator below rejects the\npair when they disagree.\nAn audit of 19 finished runs found the narrow-salvage move taken ~20\ntimes after a weak or null result and the widen move taken zero times,\nwith nothing in the output recording which move had been made, so the\nbias was invisible in the run record as well as unconstrained in the\nprompt. These fields make the decision explicit and checkable;\n``relation_type`` is kept only so runs already on disk still parse.",
  "properties": {
    "title": {
      "description": "Revised hypothesis title in plain, everyday language \u2014 short and jargon-free so a non-expert grasps it at a glance and it fits the run visualizations. Aim for about 4-8 words (~40 characters); may be unchanged if still accurate.",
      "title": "Title",
      "type": "string"
    },
    "hypothesis": {
      "description": "Revised hypothesis statement \u2014 what we now believe based on evidence",
      "title": "Hypothesis",
      "type": "string"
    },
    "relation_rationale": {
      "description": "Brief rationale for the H\u2194H revision type (one short line, max 120 characters).",
      "maxLength": 120,
      "title": "Relation Rationale",
      "type": "string"
    },
    "confidence_delta": {
      "description": "How confidence changed: 'increased', 'decreased', or 'unchanged'",
      "title": "Confidence Delta",
      "type": "string"
    },
    "key_changes": {
      "description": "Bullet list of specific changes made to the hypothesis",
      "items": {
        "type": "string"
      },
      "title": "Key Changes",
      "type": "array"
    },
    "strands": {
      "description": "EVERY artifact of this iteration, classified separately \u2014 one entry per artifact, no merging and no omissions. A round that mixes one genuine positive with several nulls is the normal shape; classifying the round as a whole is how the positive gets thrown away with the nulls.",
      "items": {
        "$ref": "#/$defs/StrandEvidence"
      },
      "title": "Strands",
      "type": "array"
    },
    "evidence_state": {
      "description": "The ROUND SUMMARY, read off the BEST strand rather than judged separately: any 'genuine_positive' strand -> 'strong_survivor'; else any 'lead' strand -> 'lead'; else any 'null' strand -> 'weak_or_null'; else (every strand 'broken') -> 'experiment_broken'. A value that disagrees with `strands` is rejected.",
      "enum": [
        "strong_survivor",
        "lead",
        "weak_or_null",
        "experiment_broken"
      ],
      "title": "Evidence State",
      "type": "string"
    },
    "move": {
      "description": "The steering move for the NEXT iteration, read off evidence_state and the remaining budget: 'deepen' \u2014 hold the claim and go after the mechanism, the boundary or the confound (also the move that makes a 'lead' bigger and cleaner); 'extend' \u2014 same claim, new population/period/setting; 'widen' \u2014 return to the user's original ask and put a population of alternative candidate answers in play, screened cheaply and confirmed on held-out evidence; 'fix' \u2014 the claim is unchanged and the defective test is repaired; 'declare' \u2014 write the run up as a negative result, permitted ONLY on the final iteration or with no budget left.",
      "enum": [
        "deepen",
        "extend",
        "widen",
        "fix",
        "declare"
      ],
      "title": "Move",
      "type": "string"
    },
    "move_rationale": {
      "description": "Why this move follows from this evidence_state and the remaining budget (one short line, max 200 characters). For 'fix', name the defect.",
      "maxLength": 200,
      "title": "Move Rationale",
      "type": "string"
    },
    "coverage": {
      "description": "Does the revised hypothesis still answer the USER'S ORIGINAL ask? 'full' \u2014 it answers the ask; 'partial' \u2014 it answers a recognisable piece of it; 'lost' \u2014 the run has drifted onto a different question and the next iteration must go back.",
      "enum": [
        "full",
        "partial",
        "lost"
      ],
      "title": "Coverage",
      "type": "string"
    },
    "coverage_statement": {
      "description": "One sentence naming which part of the user's original ask the next iteration will answer.",
      "title": "Coverage Statement",
      "type": "string"
    },
    "candidates_considered": {
      "description": "How many alternative claims, mechanisms, measures or bodies of evidence you actually weighed during THIS revision. 1 when none were weighed \u2014 which, after a weak_or_null result with budget remaining, means the widen was not done.",
      "title": "Candidates Considered",
      "type": "integer"
    },
    "relation_type": {
      "default": "evolution",
      "description": "LEGACY, kept for backward compatibility with runs already on disk \u2014 'move' is the field that steers the run. Moulines's structuralist typology of this revision: 'evolution' \u2014 refining specialised claims while keeping the same conceptual frame; 'embedding' \u2014 the previous hypothesis is now a special case of a broader frame; 'replacement' \u2014 rejecting the previous frame entirely.",
      "enum": [
        "evolution",
        "embedding",
        "replacement"
      ],
      "title": "Relation Type",
      "type": "string"
    },
    "artifact_relations": {
      "description": "Typed A\u2194A edges for this iteration's new artifacts. Emit one entry per (predecessor \u2192 dependent) edge for every in_dependency on each artifact produced this iteration.",
      "items": {
        "$ref": "#/$defs/ArtifactRelation"
      },
      "title": "Artifact Relations",
      "type": "array"
    }
  },
  "required": [
    "title",
    "hypothesis",
    "relation_rationale",
    "confidence_delta",
    "key_changes",
    "evidence_state",
    "move",
    "move_rationale",
    "coverage",
    "coverage_statement",
    "candidates_considered"
  ],
  "title": "RevisedHypothesis",
  "type": "object"
}
```

IMPORTANT: this task is NOT complete until `./.terminal_claude_agent_struct_out.json` exists and contains JSON matching the schema above.

I work on converting natural-language text into first-order logic (NL→FOL, autoformalization) with
LLM pipelines. Evaluation is the bottleneck. Correct FOL for a sentence is not unique — different
predicate names, different decompositions of the same concept, and logically equivalent rewrites can
all be correct. Gold FOL annotations are rare and expensive. The metrics in use either need a gold
formula (exact match, BLEU, prover-checked equivalence to the gold) or only check that the output
parses. In my own pilot I used cheap structural metrics: whether a set of generated formulas loads
together without conflicts, whether predicate arities stay consistent, how many predicates are used
but never defined, and how similar the predicate sets are across reruns. Those measure stability and
composability, not whether a formula says what the sentence says.

Find new metrics for NL→FOL output quality. Operating situation: you are given a natural-language
sentence (or short passage) and a candidate FOL formalization produced by any system. There is no gold
formula, no ontology or controlled vocabulary, and no domain knowledge. The metric returns a score
that predicts whether the formalization is faithful to the text, and ideally which kind of error it
contains (quantifier or scope error, dropped or added condition, negation/polarity error, swapped
arguments, conflated or wrongly split concepts). Metrics may score a single formula or a set (several
samples for one sentence, or the formalizations of all sentences in one document). They must be
task-agnostic — usable for any NL→FOL setting, not tied to a domain, dataset or pipeline — and cheap
enough to run on every output (solver calls and small models are fine; a large-LLM judge per formula
only if shown to earn its cost).

Requirements:
- Keep the target fixed: the metric must predict faithfulness to the text. Detecting synthetic
  perturbations, parse validity, or run-to-run stability are not substitutes for that target.
- Validate against ground truth, never against the metric itself. Use public datasets with gold
  sentence-level FOL (e.g. FOLIO, MALLS, or others you find) to build a meta-evaluation set: real
  candidate formalizations from several different systems, plus controlled perturbations of gold
  formulas with known error types, labelled via prover-checked equivalence to gold. Handle two known
  problems: some gold annotations are wrong, and a candidate can be correct without being equivalent
  to the gold (different vocabulary or granularity). Estimate how often each happens and how it
  biases the labels. These datasets are public, so check whether LLM-based metrics benefit from having
  seen the gold.
- For each metric report: correlation with correctness at item and system level; sensitivity per error
  type; invariance under meaning-preserving rewrites (variable/predicate renaming, reordering,
  equivalent restatements); coverage — unparseable outputs are counted and reported, never silently
  dropped; and cost.
- Compare against baselines: parse/compile rate, round-trip (FOL→NL→compare) similarity,
  LLM-as-judge, sampling self-consistency, and the structural consistency metrics described above. A
  new metric matters only if it adds signal those don't.
- Report how each metric's reliability changes with sentence complexity (length, number of quantifiers,
  nesting depth, number of conditions and exceptions). Long, heavily conditioned sentences matter most
  to me.
- Negative results are welcome: if a family of metrics does not track correctness, show that clearly.

Out of scope: comparing grounded vs ungrounded generation (ontology vocabulary injected into prompts),
anything that depends on a particular ontology, and building a better NL→FOL translator. The
contribution is the measurement, not the translator.

Deliverables: reusable Python functions taking (text, fol) — or a set of such pairs — each with a
precise statement of what it measures; the meta-evaluation dataset with its labels; and the results.

I appended a pilot study of this problem with some metrics I already used but haven't verified. Just for reference.
````
