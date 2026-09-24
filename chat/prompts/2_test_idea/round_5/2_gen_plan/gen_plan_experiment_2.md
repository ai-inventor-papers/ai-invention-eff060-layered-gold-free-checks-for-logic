# gen_plan_experiment_2 — test_idea

> Phase: `invention_loop` · round 5 · `gen_plan`
> Run: `run_u75jRHUss0zo` — Gold-Free Faithfulness Metrics for NL-to-FOL Translation
>
> Full, verbatim record of every prompt the AI Inventor pipeline gave this agent — system-user, human-user and skill-input — in the order they landed. Nothing truncated.

## Task: `gen_plan_experiment_2` (terminal_claude_agent)

### [1] SYSTEM-USER prompt · 2026-09-24 10:58:14 UTC

````
<ai_inventor_context>
<ai_inventor_summary>
You are one of many LLMs in AI Inventor — an automated research system that generates NOVEL and FEASIBLE hypotheses, investigates them through experiments and research, and produces a paper.

Your output feeds other LLMs downstream. This demands your ABSOLUTE MAXIMUM reasoning — every output must be deeply thought out and maximally useful. Surface-level responses waste downstream computation.
</ai_inventor_summary>

<your_role>
YOU ARE: A plan generator (Step 3.2: GEN_PLAN in the invention loop)

You received the hypothesis, an artifact direction to elaborate, and dependency artifacts relevant to the plan.
Your job: elaborate this direction into a detailed, actionable plan for the executor agent.

Specific, actionable plan → valuable artifact. Vague plan → wasted execution.
</your_role>
</ai_inventor_context>

<artifact_type_info>
You are expanding an artifact direction of type: EXPERIMENT

EXPERIMENT
Run code to test hypotheses, implement methods, and collect empirical results.
Runtime: Python 3.12, UV (any pip package), isolated workspace, gradual scaling (mini → full data).
Tools: Full shell/Python/filesystem access, the aii-web-tools skill (web search, page fetch, regex grep over full page/PDF text), and other skills.
Skills: aii-json (schema validation), aii-openrouter-llms (call any LLM — GPT, Gemini, Llama, etc.), domain-specific as needed.
Capabilities: Implement and run any code-based experiment, compare method vs baselines.
Deps: REQUIRED at least one DATASET | OPTIONAL RESEARCH for methodology guidance
</artifact_type_info>

<available_resources>
<software_constraints>
- Python only implementation
- Python standard library and all popular PyPI packages available (numpy, pandas, scikit-learn, scipy, matplotlib, requests, etc.)
- Local parallelism encouraged: multiprocessing, asyncio, threading — see aii-parallel-computing skill
- LLM API calls must go through OpenRouter only (no direct OpenAI, Anthropic, etc.), with base_url=os.environ["OPENROUTER_BASE_URL"] and api_key=os.environ["OPENROUTER_API_KEY"] (the OpenAI SDK's defaults, OPENAI_BASE_URL and OPENAI_API_KEY, point at the same place, so a plain OpenAI() client also works with OpenRouter model ids). The key is this run's own OpenRouter key and works only at that base URL: never hard-code OpenRouter's own URL, or every call fails with 401
- **SPEND BUDGET**: at most $10 USD of OpenRouter API calls for this artifact. Nothing outside your own code enforces this — the key you are given has no per-artifact cap — so it holds only if you track cumulative cost after every call and stop when you approach it. Budget the work up front: estimate the per-call cost and the number of calls BEFORE starting a sweep, not after it overruns. Exceeding it spends real money that the run cannot recover.
</software_constraints>

<skills>
Skills are self-contained capabilities with instructions, context, and tools.

- aii-web-tools: Free-first web search (general + scholarly modes), page/PDF fetch as markdown, regex grep over page/PDF text
- aii-semscholar-bib: Batch-fetch BibTeX from Semantic Scholar
- aii-openrouter-llms: Search and call 300+ LLMs via OpenRouter
- aii-hf-datasets: Search, preview, download HuggingFace datasets
- aii-owid-datasets: Search and load Our World in Data tables
- aii-lean: Compile/verify Lean 4 code, Mathlib search, tactic suggestions
- aii-concept-fig-gen: Generate/edit images via Gemini 3 Pro Image (Nano Banana Pro)
- aii-json: Validate JSON against schemas, generate mini/preview variants
- aii-paper-writing: Academic paper structure, bibliography, citations
- aii-paper-to-latex: Assemble LaTeX papers and compile to PDF
- aii-parallel-computing: GPU acceleration, CPU parallelism, async I/O
- aii-python: Python coding standards for experiment scripts
- aii-use-hardware: Detect CPU/RAM/GPU, memory-safe processing
- aii-long-running-tasks: Gradual scaling pattern for long-running tasks
- aii-colab: Google Colab runtime constraints for notebooks
- aii-file-size-limit: Check and split oversized output files
</skills>
</available_resources>

<time_budget>

The experiment executor has 6h total (including writing code, debugging, testing, and fixing errors).

</time_budget>

<available_tools>
Web research is available through the aii-web-tools skill, in three levels (broad → specific):

1. web search — Returns titles, URLs, snippets. Use first to discover and scan the landscape. Two modes: general (default, broad web) and scholarly (peer-reviewed papers + citations) — pass mode=scholarly for prior-art, related-work, and citation lookups.
2. web fetch — Reads a page and returns its content as markdown (HTML or PDF). Use to understand a source. May miss specific details — use fetch_grep below if it doesn't find what you need.
3. fetch_grep — Regex search over a page/PDF's full text. Returns exact matching sections with context. Use for precise details, exact numbers, methodology, or PDFs.

Workflow: search → fetch (understand) → fetch_grep (extract specifics).
</available_tools>

<tool_use>
Maximize parallel tool calls. Parallelize independent operations, only sequentialize dependencies.
- Multiple searches/fetches on different topics → parallel in one turn
- Search then fetch results → sequential (need URLs first)
</tool_use>

<plan_guidelines>
You are expanding an artifact direction from the strategy into a detailed plan.
The artifact direction specifies what to do at a high level (type, objective, approach, dependencies).
Your job is to make it concrete and actionable as a detailed plan.
Use web research to look up technical details, verify feasibility, and find reference materials
that will make your plan more concrete and actionable for the executor.

GOOD PLANS:
- Make each component SPECIFIC and actionable (not vague platitudes)
- Consider both success AND failure scenarios
- Build on the approach in the artifact direction
- Add concrete details the executor needs

BAD PLANS:
- Vague hand-waving ("do research on X")
- Ignoring the approach in the artifact direction
- Missing critical details the executor needs
</plan_guidelines>

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

<workspace>
Your workspace: `/ai-inventor/aii_data/runs/run_u75jRHUss0zo/3_invention_loop/iter_5/gen_plan/gen_plan_experiment_2`

CRITICAL: Every file you create, write, or save MUST be inside this workspace directory (subdirectories OK). You MUST NOT write files anywhere outside this path — external paths are READ-ONLY. Use absolute paths for all file operations.

EVERY file write MUST start with `/ai-inventor/aii_data/runs/run_u75jRHUss0zo/3_invention_loop/iter_5/gen_plan/gen_plan_experiment_2/`:
GOOD: `/ai-inventor/aii_data/runs/run_u75jRHUss0zo/3_invention_loop/iter_5/gen_plan/gen_plan_experiment_2/file.py`, `/ai-inventor/aii_data/runs/run_u75jRHUss0zo/3_invention_loop/iter_5/gen_plan/gen_plan_experiment_2/results/out.json`
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

<hypothesis>
kind: hypothesis
title: Cross-model agreement, tested on fresh data
hypothesis: |-
  kind: hypothesis (iteration 5 of 5, FINAL). Move = DEEPEN on the one live lead: cross-family solver consensus (frozen c_score_align, with PT = p_peer_text as its fused row). The lead gets its first test on data no earlier decision touched. The two confirmation sets that the budget broke in iteration 4 (E2, and the R_COMP FREE gloss labels) are each FIXED ONCE, with their claims unchanged. The lead's false-alarm cause, which iteration 4 re-diagnosed as wrong and scattered peers rather than vocabulary, is attacked with $0 development-screened variants. Candidate-Signature Consensus (CSC) is CLOSED. The paper is then written from the corrected record below.

  ========================================================================
  0. CORRECTED RECORD (the paper step TRANSCRIBES these numbers; each has a source)
  ========================================================================

  0.1 DATA ROLES
  - E, the screen, R_COMP SIG and PERTURB are DEVELOPMENT data. Every number from them is development evidence. The paper must NEVER call E 'held-out'.
  - The only untouched confirmation evidence is:
    - E2: sealed; seal.json and verify_seal.py are in gen_art_dataset_4;
    - the R_COMP FREE untouched subset (2,198 rows; seal b364a49a…, gen_art_dataset_5).

  0.2 ITERATION 3, CORRECTED
  The iter-3 record in iter_3/upd_hypo §0 is authoritative, together with the eval-3 Part-4 tables in gen_art_evaluation_3/tables/: hypothesis_verdicts_iter3.csv, perturb_corrected.csv, t2_record.csv, rename_selection_dead_end.csv, cost_units.csv, coverage_vs_request_iter3.csv, function_inventory.csv, label_facts.csv, corrections_iter12.csv, artifact_id_map.csv, prior_art.csv. Essentials:

  T1 (art_7GxreYjATkC5), R_AB n = 2,686 (1,822 ERROR / 864 CORRECT, 292 sentences):
  - c_score_align strat AUROC 0.741 vs flash-lite disguised 0.642: Δ +0.099 [0.049, 0.146].
    - long pool +0.116 [0.070, 0.163]; EXC +0.197; vs nano original +0.089 [0.043, 0.134].
  - L25 (the user's priority stratum): Δ +0.069 [−0.020, 0.148], n.s.
  - CTRL −0.069 [−0.23, 0.10].
  - Against the baseline stack:
    - c alone ≈ S4_full: +0.006 [−0.031, 0.042];
    - nested [S4_full + c] − S4_full: strat +0.039 [0.021, 0.057].
  - Frontier frame (n = 284):
    - AUROC: judge 0.741, S4_full 0.745, c 0.710;
    - ratio 0.957 [0.887, 1.034], so the 0.95 bar is met on the point estimate only;
    - nested +0.037 [0.008, 0.066].
  - M3 is INCONCLUSIVE because its two specifications conflict: bootstrap +0.146 [−0.051, 0.361] vs stacked GEE +0.274 [0.190, 0.359].
  - Flash-lite contamination DiD +0.105 [0.006, 0.201]: marginal evidence of contamination.
  - Spend $2.395.

  T2 (art_cxnoDYQNFolW), NOT CONFIRMED:
  - SIG passes: 0.954 vs 0.587; +0.278 vs the original judge. But SIG is the controlled-vocabulary regime the user excluded.
  - FREE was NOT_TESTABLE.
  - [Correction, iter 4] The iter-3 FREE tier-A deltas (c_align − judge +0.214; 'falls to ~0.80') are VOID. Those labels over-call ERROR: 297 of 420 old ERROR rows are MAPPED (gen_art_dataset_5/results/old_label_agreement.json).

  Exp 8 (art_YYD-HDzfQfEj):
  - The pre-registered rename-invariant selection FAILED (HYB 0.841/0.700, NF 0.686/0.485).
  - MEANING_RENAME is an ERROR operator, and c_nf is blind to it (0.499).
  - Per-operator consensus AUROC is a base-endorsement artefact. Do not rank operators by it, and do not claim 'polarity symmetry'.
  - Coverage 3,419 of 5,402 rows.
  - Typing: peer-medoid 0.328 vs judge 0.326; the gold-using oracle reaches 0.802.

  Eval 2 (art_FWy8D4_y9GBn), pre-registered definitions:
  - M1 INCONCLUSIVE; M2 CONFIRMED but non-specific; M4 k95 = 3 overall, 2/3/5 by words tercile (long tercile = 5).
  - NET +0.356 [0.198, 0.493]: consensus DEGRADES with length.
  - SCATTER ratio 4.45; graded − binary +0.114.

  Costs (cost_units.csv):
  - consensus $1.21e-4 per candidate FULL;
  - k = 1/3/5/7 pools: $0.000315 / 0.000946 / 0.001576 / 0.002206 per SENTENCE;
  - flash-lite $4.9e-5 per call; frontier $3.65e-3 per item;
  - SIG generation $0.000116 per candidate; MARGINAL z3 $2.5e-7.
  - The old '$0.000024–0.000170 per sentence' column is wrong.

  Prior art (art_VIF75I5R6f0v; needs its own section and marker in the paper):
  - Not scooped. The method is not new: ARc 2511.09008 uses the same score form; NoTB 2608.21962; GenV 2609.11085 reports a label-target reversal; LLMs-as-Jury recommends 3-4 families.
  - C1 and C3-C5 need qualifiers (prior_art.csv).
  - Iter-3 spend $4.33 (not '$1.58 plus T1').

  0.3 ITERATION 4, the record per artifact (spend from ledgers)

  A. Exp 9, CSC on E (art_D7k2ZWgE3nVd; tables.md T0-T17; csc_gate_E.json). PROVISIONAL.
  Population and selection:
  - The platform refused paid calls after 1,033 of ~9,000 planned. PRIMARY is therefore a COMPLETION-SELECTED subset: 354 R_AB rows (196 ERROR / 158 CORRECT, 144 sentences).
  - CTRL makes up 44.9% of PRIMARY CORRECT rows vs 27.4% on FULL.
  - No stratum reaches 50/50, so L25 is NOT_READ.
  - c_csc tie rate is 0.986.

  Strat AUROC [CIs as in T4]:
  | Metric | Strat AUROC |
  |-|-|
  | c_csc | 0.614 [0.493, 0.736] |
  | FREE_exact (same 3 families) | 0.770 [0.686, 0.844] |
  | FREE_ALIGN | 0.731 [0.635, 0.825] |
  | c_score_align | 0.774 [0.682, 0.857] |
  | p_peer_text | 0.799 [0.700, 0.880] |
  | S4_full | 0.736 [0.635, 0.826] |
  | flash-lite disguised | 0.664 [0.568, 0.750] |
  | HYB_MEAN | 0.709 [0.586, 0.817] |

  Paired Δ for c_csc (T5):
  - vs FREE_exact −0.156 [−0.290, −0.031];
  - vs c_score_align −0.160 [−0.275, −0.064];
  - vs flash-lite −0.050 [−0.212, 0.107], n.s.;
  - vs S4_full −0.123 [−0.269, 0.010], n.s.;
  - phi-4 exemplar leakage removed (T17, 58 CSC calls copied the exemplar): c_csc_clean 0.639; vs FREE_exact −0.132 [−0.251, −0.023].

  e and d:
  - CSC e 0.459 vs FREE_exact 0.173; CSC d 0.139 vs 0.323.
  - FULL T2: FREE_exact d 0.583 vs ALIGN 0.328.

  Anchoring by class (T9, PRIMARY; e_CSC / e_FREE_exact / e_FREE_ALIGN):
  | Class | e_CSC | e_FREE_exact | e_FREE_ALIGN |
  |-|-|-|-|
  | ADD | 0.490 | 0.135 | 0.375 |
  | DROP | 0.472 | 0.169 | 0.380 |
  | COMPOUND | 0.282 | 0.107 | 0.184 |
  | MEANING_RENAME-type (n = 28) | 0.821 | 0.036 | 0.750 |
  | structural | 0.336 | 0.153 | 0.282 |
  | polarity | 0.200 | 0.133 | 0.200 |
  - MEANING_RENAME-type Δ CSC − FREE_ALIGN is +0.071 [−0.083, 0.269], NOT_READ.
  - FULL T9b: FREE_ALIGN e on MEANING_RENAME-type is 0.624, vs 0.104 for exact.
  - READING: every vocabulary bridge (the aligner, or peers cued with the candidate's symbols) lowers d AND raises e, class by class. The aligner that c_score_align uses already endorses meaning-rename errors almost as often as CSC does.

  Gates (the text of prereg_csc_E.json):
  - G1 FAIL: d 0.139 ≤ 0.35, but the words slope is +1.25 [0.41, 2.09].
  - G2 = 'strat ≥ c_score_align − 0.01 AND pooled > c_score_align on L25' → NOT_READ (the R_AB part FAILS; L25 Δ −0.067 [−0.183, 0.040], n = 81, not read).
  - G3-E = RENAME_SYN false alarm: NOT_RUN.
  - G4 null.
  - G5 PASS: $5.25e-4 per candidate ($2.76e-4 deduped).

  Length:
  - M3 bootstrap −0.232 [−0.770, −0.023]; stacked GEE −0.351 [−0.694, −0.009].
  - NET is length degradation WITHIN each arm, and every arm degrades: FULL FREE_exact +0.452, FREE_align +0.401.

  Other tables:
  - T8: 53% of free-exact disagreements with CORRECT candidates are structural; only 20.2% of flagged CORRECT rows are fully vocabulary-resolvable.
  - T10 typing: own_majority 0.185, below the majority class 0.262.
  - T14: CSC τ-b 0.256 (p = 0.25) vs c_score_align 0.513 (p = 0.015).
  - T15: 9-peer c_score_align rename FA 0.595 → 0.868, ΔFA +0.273 [0.164, 0.384].
  - Spend $0.108.
  - Prior art: this is the correlated-failure mode of Chen & Avizienis 1978. What is new is the per-class e measurement and the bridge-trades-d-for-e table.

  B. Exp 10, CSC on PERTURB (art_pAmLrGqsmFUx). BROKEN: 0 CSC peers were generated ($0.0000088). G3-P, G4 and MT are UNTESTED.
  Zero-cost arms:
  - SIGPROXY (out-of-scope controlled vocabulary): k = 3 within-template 0.930 [0.916, 0.943]; d 0.149 cued vs 0.757 uncued FREE3-ALIGN.
  - Prior art for the shared-vocabulary lever: Vossel et al. 2025 ('predicate availability boosts performance by 15-20%') and ARc's fixed schema. The only addition here is a measured d reduction on long templated sentences, in an excluded regime.

  CORRECTIONS:
  - FREE-consensus mutant recall ≈ 1 comes with base FA at c > 0.5 of:
    - 0.712 (c_align_exp8, E);
    - 0.803 (FREE3_exact, E);
    - 0.986 (FREE3_exact, R_COMP);
    - 0.757 (FREE3_align, R_COMP).
    So that recall is trivial.
  - Rename-control FA is mostly base FA. The paired flips are 0.18-0.53 (c_align E: SYN 0.182, NONCE 0.327).
  - LOCAL2 e 0.341 comes entirely from insufficient-peer ties at c = 0.5 (e_excl 0.012/0.007).
  - The judge's 12.4% mutant miss rate is NOT END_MAJ e.
  - Typing:
    - 'oracle' repairs against the gold base, so it is NOT gold-free;
    - free3 on E is 0.123 [0.081, 0.169]; the pooled 0.085 includes R_COMP rows at 0.
  - Split the controls by base source: FREE3_exact REORDER/CONTRA is 0.842/0.840 on E and 0.986 on R_COMP.
  - Uncued d by words tercile: 0.47 / 0.80 / 0.91.

  C. Dataset 4, E2 (art_2OmxzMInZZJY). BROKEN (budget stop).
  - 550 sentences frozen: L25 350, EXC 100 (92 'without' + 8 'but not'; the core-exception supply is exhausted, D3), DT 100 (ProverQA).
  - 30-sentence pilot: 300 candidates, labelled 36 ERROR / 274 UNRESOLVED (incl. gold-as-system) / 20 UNPARSEABLE / 0 CORRECT.
  - Panel drift check:
    - the stop rule is UNDECIDED (passes = false; combined majority agreement 0.394);
    - synthetic gate items 0.974;
    - on 22 unambiguous track-H judgements, today's panel flags 0.12 of original errors vs 0.84 in E: a DRIFT WARNING on small n.
  - Deviations D0-D7 must be listed.
  - Spend $0.241.
  - Power (eval 3):
    - L25 yield 0.37, so 350 L25 gives MDE80 0.110;
    - +0.069 on L25 needs ~882 planned sentences;
    - the long pool needs ~237 usable sentences.

  D. Dataset 5, R_COMP FREE labels (art_Ia_FT284H33j). BROKEN for its purpose: the gloss step was not run, so the CORRECT class is empty.
  - Search-only labels: ERROR_CERT 759, MAPPED 1,506, UNPARSEABLE 188, NO_OUTPUT 199.
  - Search soundness: 0 of 1,595 false ERROR_CERT on SIG renames; known-ERROR rescue 9-10% (T8 0.27; T9 0.37-0.43).
  - Audit: ERROR_CERT precision 0.867; MAPPED faithful 0.867. One MAPPED certificate swaps LivesIn and StudentInClass.
  - Old iter-3 labels are contaminated by UP TO 70.7%. MAPPED is an upper bound. Old/new kappa is 0.058.
  - D6 amended the map family after the freeze. Spend $0.

  E. Eval 3 (art_BvAL_KZTZuw8), $0.
  - MAIN FINDING: among pairs of a CORRECT candidate and a non-agreeing peer, 77% (9-family) / 61% (3-pool) of those peers are labelled ERROR. Only 9% of CORRECT-CORRECT disagreements are vocabulary-resolvable.
  - Pair classes: IRREDUCIBLE 69.4%, EXACT 13.6%, ALIGN_ONLY 15.1%, VOCAB 1.6%.
  - The no-anchoring oracle d floor:
    - 3-pool 0.385;
    - L25 0.542 vs END_MAJ 0.735;
    - 9-family 0.586 > END_MAJ 0.537, because most peers are wrong.
  - The post-hoc instruments predict almost no fix: bracket [0.396, 0.415]; the gap_closed rule is ill-conditioned (denominator 0.013).
  - The instruments are shown to UNDER-COUNT vocabulary effects: predicted endorsement 0.20 vs actual SIG 0.575, calibration error −0.372 [−0.423, −0.323].
    - SIG also changes granularity (D7), so the SIG−FREE agreement drop of +0.479 [0.447, 0.513] is an upper bound.
    - Non-transitivity (0.131) is a separate diagnostic.
  - The number 0.683 is d under the exact rule on E's 3-pool. It is NOT an AUROC and NOT R_COMP. Delete 'theoretical AUROC 0.683'.
  - c_vres on L25: −0.014 [−0.028, −0.001].
  - NET DEGRADES under every rule (+0.35 to +0.39).
  - VOCAB agreements are not label-specific.
  - R_COMP FREE needs ≥ 200 CORRECT rows.

  F. Iteration-4 spend: $0.108 + $0.0000088 + $0.241 + $0 + $0 ≈ $0.35. The rest of the $7 'Test idea' phase budget was consumed by processes recorded in NO iteration-4 artifact ledger. The paper states this and does not guess.

  ========================================================================
  1. WHAT THE EVIDENCE NOW SAYS (the revised diagnosis)
  ========================================================================
  The lead stands on development data: consensus beats cheap judges on long and exception sentences, and it adds signal over the stack only when nested. It is not confirmed on untouched data, and not on L25. The iteration-3 diagnosis said consensus fails on long sentences because CORRECT translations disagree about WORDS. Iteration 4 REFUTES that as the dominant cause on real LLM outputs (E):
  - 61-77% of the disagreement a correct candidate meets comes from peers that are themselves WRONG;
  - only 9% of correct-correct disagreement is vocabulary.
  - Every vocabulary bridge trades d for e:
    - the aligner: d 0.583 → 0.328, but meaning-rename e 0.104 → 0.624;
    - candidate-signature cues: d → 0.139, but e → 0.459, the anchoring.
  - CSC fails provisionally, and the aligner already carries much of the same anchoring cost.

  Vocabulary divergence is real in templated free-vocabulary text (R_COMP: exact agreement 0.048 FREE vs 0.528 SIG). But on real long sentences the binding constraint is PEER ACCURACY: on L25 about 80% of candidates are wrong, so a correct candidate's class is a small plurality.

  Candidate one-sentence finding, if iteration 5 confirms: 'Cross-family solver agreement is a gold-free faithfulness check that beats cheap LLM judges on long, conditioned sentences at ~$1e-4 per candidate. Where it fails, the cause is that the other models are wrong in different ways, not that correct translations use different words. Any device that makes peers share the candidate's vocabulary lowers false alarms only by making peers copy the candidate's errors.'

  ========================================================================
  2. CLAIMS FOR ITERATION 5 (all metrics frozen and hashed BEFORE any confirmation label is joined)
  ========================================================================

  H-PRIMARY (pre-declared in iteration 3; NOT re-selected). On E2 and on R_COMP FREE, the frozen c_score_align:
  - uses the E2 10-slot pool, leave-own-family-out, with the exp-5 code byte-identical;
  - is compared with the flash-lite rubric-A judge (disguised AND original) and with gpt-4.1-nano.
  p_peer_text is a secondary row, frozen.

  H-MECH (the label-based replication of the iter-4 diagnosis; no instrument needed). On E2 CORRECT candidates:
  - (i) ≥ 50% of non-agreeing peers are labelled ERROR;
  - (ii) SCATTER ratio SI_cor / SI_err ≥ 2;
  - (iii) NET Δ(e+d) over the words terciles is > 0 (degradation replicates);
  - (iv) exact vs ALIGN on E2 FULL reproduces the trade: ALIGN has lower d and higher e on MEANING_RENAME-type and ADD/DROP errors.

  H-IMPROVE (the deepen on the cause; a DEVELOPMENT screen at $0, on E's stored pairwise matrix, 29,107 pairs). The mechanism is that wrong peers scatter (they agree with few others), so a correct candidate's plurality is diluted by them. So a score that discounts scattered or unreliable peers should lower d on long sentences WITHOUT raising e. Unlike CSC and the aligner, it changes no peer output and bridges no vocabulary.

  Candidates screened, all label-free:
  - V1 plurality-normalised: c_pn = 1 − share_agree / max_class_share among the sentence's peers;
  - V2 reliability-weighted: per-family weights from mean pairwise agreement across ALL sentences (Dawid-Skene-style, label-free), estimated out of sentence fold;
  - V3 = V1 + V2;
  - V4 two-channel: a cross-fitted logistic on (c_exact, c_align), trading the aligner's d gain against its e cost;
  - V5 V3 on the eval-2 best 3-pool (cost-matched, $0.001 per sentence);
  - V0 the frozen c_score_align.

  Selection rule (pre-registered before running):
  - the winner is the variant with the highest E long-pool strat AUROC that
    - beats V0 by ≥ +0.015 there,
    - AND is ≥ V0 on L25 (point),
    - AND is ≥ V0 − 0.01 on CTRL.
  - If none qualifies, NO variant is carried and V0 stands alone.
  The winner is a CANDIDATE only; E2 confirms or kills it. Report how many variants were screened (5).

  H-RENAME (the user's invariance requirement, the last attempt on a new mechanism, secondary budget). GLOSS-GATED name-free agreement (GG):
  - A peer agrees with the candidate if they are exactly z3-equivalent, OR if an exhaustive injective symbol map (freelab.equivalent_modulo_vocab_exhaustive) yields equivalence AND a cheap LLM gloss check confirms every non-identity mapped symbol pair is a same-meaning pair in this sentence.
  - This targets exactly why NF/HYB failed: NF cannot tell a synonym from a wrong predicate (0.388 of HYB's extra agreements are label-discordant; MEANING_RENAME 0.499). The gloss adds the lexical meaning test the solver lacks, without cueing peers, so there is no anchoring.
  - The gloss model family for GG MUST differ from the one that labels R_COMP FREE (instrument-sharing firewall). GG is therefore never evaluated on R_COMP FREE.
  - Dev gate on PERTURB E-bases plus E R_AB:
    - RENAME_SYN paired flip ≤ 0.05 and FA ≤ base FA + 0.05;
    - MEANING_RENAME recall at fixed threshold ≥ c_align's − 0.05;
    - E strat AUROC ≥ c_score_align − 0.01.
  - Fail → rename non-invariance of consensus is reported as a measured boundary: c_align PERTURB NONCE/SYN FA 0.765/0.565 with paired flips 0.327/0.182; 9-peer ΔFA +0.273. No further rename work.

  ========================================================================
  3. WORK ORDER AND BUDGET (each sweep costed before it runs; stop when the next sweep's estimate exceeds the remainder minus a 10% reserve)
  ========================================================================
  P1. R_COMP FREE gloss (FIX ONCE; the panel route stays dropped). About $0.8-1.8.
  - Gloss gate on the 840 known-answer items: balanced accuracy ≥ 0.90, per class reported.
  - Then gloss the MAPPED rows → CORRECT / ERROR / UNRESOLVED, and seal.
  - A Sonnet-5 audit only on a 120-row stratified sample.
  - Out-of-family faithful forms (13% of ERROR_CERT) are carried as a label-noise bound; the AUROC is reported with and without those template classes.
  - Testable only if ≥ 50 CORRECT rows; power is adequate at ≥ 200. The judge scores for FREE rows already exist from iter 3.

  P2. E2 drift gate FIRST (~$0.3). Replay the full track-H set (192 judgements) with pinned model ids.
  - PASS (flag rate on original errors within the CI of E's 0.84): E's frozen solver + panel protocol labels E2.
  - FAIL: E2-L25/EXC labels are reported as DRIFTED (secondary), and the primary confirmation becomes R_COMP FREE plus E2-DT. DT is labelled by the alignment-free exhaustive-map + gloss labeller against the trusted prover-built gold.

  P3. E2 generation for all 550 sentences (10 slots). Then the panel in the order L25 → EXC → DT, then the L25 surplus (98) if budget remains.
  - The LONG POOL (L25 + EXC) is PRE-DECLARED PRIMARY, and its MDE (~0.11-0.12) is stated in advance.
  - The 30 pilot sentences are included (sealed; never read by a selection step), and results are reported with and without them.

  P4. Judges on E2: flash-lite disguised and original, and nano, on every parseable row (~$0.5). Also a local Qwen3-8B judge, L2-bow and the local round trip for S4_E2, which is cross-fitted by E2 sentence folds.

  P5. The GG dev screen (gloss calls only on pairs where exact/ALIGN fail but a map exists; <$0.5).

  P6. Frontier gemini-3.1-pro on a 300-row stratified E2 subsample (~$1.1). This is the first thing dropped if budget binds.

  DROPPED:
  - all remaining CSC arms (PERTURB G3-P/G4/MT, OTHER-SIG, multi-reading);
  - any new dataset construction beyond E2;
  - the SIG regime as evidence for the user's operating condition.

  ========================================================================
  4. SUCCESS CRITERIA (fixed now)
  ========================================================================

  CONFIRM (the lead becomes a finding):
  - (a) E2 long pool: frozen c_score_align − flash-lite disguised strat CI > 0 AND point > 0 vs flash-lite original and nano.
  - (b) E2 nested [S4_E2 + c] − S4_E2 strat CI > 0.
  - (c) R_COMP FREE untouched (if testable): within-template c_score_align − flash-lite, disguised AND original, CI > 0. This is the first in-scope, free-vocabulary, trusted-reference test on long conditioned sentences.

  PARTIAL:
  - (a) holds, (c) is untestable or n.s.: confirmed on real long sentences, free-vocabulary templated text unresolved.
  - (c) holds, (a) is n.s. with point ≥ +0.05: 'underpowered on E2, confirmed on R_COMP FREE'.

  DISCONFIRM: the (a) point ≤ 0 on the E2 long pool. The E result was development-set optimism, and the judge/stack is the incumbent. This is reported plainly.

  Also reported, not gating:
  - L25 alone (expected MDE 0.11; the point estimate is stated with its power);
  - DT sign (domain transfer);
  - frontier ratio and nested gain on the 300-row subsample;
  - system-level τ-b over 13 system × variant rows;
  - rename FA and paired flip for c_score_align on E2 CORRECT rows under RENAME_SYN and RENAME_NONCE;
  - coverage with unparseables in the denominator;
  - $ and seconds per candidate, FULL vs MARGINAL.

  H-MECH is scored CONFIRMED or REFUTED per item (i)-(iv).

  H-IMPROVE: the carried variant − V0 on the E2 long pool, strat CI > 0 → CONFIRMED improvement; otherwise V0 stands and the variant is reported as a development-only result.

  H-RENAME: CONFIRMED only if GG passed the dev gate AND on E2 CORRECT rows its RENAME_SYN paired flip is ≤ 0.05 while its E2 long-pool AUROC is ≥ c_score_align − 0.01.

  ERROR TYPE (the user's 'which kind of error'):
  - The answer is NEGATIVE outside a shared vocabulary: free3 0.123 on E; medoid 0.328 vs judge 0.326.
  - Within a shared vocabulary, typed repair reaches 0.784 (SIGPROXY), but that regime is out of scope.
  - No new budget.

  ========================================================================
  5. PAPER OBLIGATIONS (all transcription; blocking review items)
  ========================================================================
  - Apply eval-3 Part 4 in place. Each corrected item gets a '[Correction, iter 4: …; source <path>]' marker next to the struck original text:
    - §3.4 from perturb_corrected.csv: MEANING_RENAME = an ERROR operator; per-operator consensus AUROC = base endorsement; the judge cells from perturb_sensitivity.csv; coverage 3,419/5,402;
    - §3.3 from t2_record.csv: T2 NOT CONFIRMED, and the FREE deltas are void;
    - §3.5 with the pre-registered M1-M4, NET +0.356, and cost_units.csv;
    - the iter-1/2 items in corrections_iter12.csv: frontier C4 'strengthens'; the 588 common items; 'fitted under solver labels'.
  - Replace the placeholder artifact IDs from artifact_id_map.csv.
  - Add the following sections and tables:
    - '3.7 Hypothesis verdicts';
    - 'Prior-art positioning [ARTIFACT:art_VIF75I5R6f0v]': scoop rule, neighbour table, C1-C5 verdicts;
    - the coverage-against-request table, with one-line answers: long sentences → pending E2; no controlled vocabulary → pending R_COMP FREE; error type → negative;
    - the function inventory;
    - ONE cost table with units;
    - the iteration-4 spend table (§0.3F);
    - a reasoning block at the start of §3 and §4 (previous review score and blocking status, move, prediction, gates, planned vs actual artifacts).
  - Rewrite §4.2-4.6 from §0.3A-E exactly, with CIs copied verbatim. 'CSC is a dead end' becomes 'provisional negative on a completion-selected subset; L25 and RENAME untested'.
  - Extend the dead-ends table:
    - rename-invariant selection (NF/HYB INELIGIBLE);
    - candidate B1 (never ran);
    - the FOL-Triage rewrite-FA gate;
    - P2 and P4 REFUTED;
    - CSC_graded, CSC_multi and HYB_MEAN (all fail G1);
    - E2 EXC-core supply;
    - correct the c_nf reason to 'selection failure + MEANING_RENAME blindness'.
  - 'What we have learned' must drop '0.954 on R_COMP' and '96% of frontier' as headlines, or caveat them (out-of-scope SIG; point estimate only). It must state the long-tercile k95 = 5.

  ========================================================================
  6. CARRIED AS SECONDARY ROWS; CLOSED
  ========================================================================
  Secondary rows: PT, TEXT (L2-bow + L3), NF/HYB, graded consensus, S4 stacks, round trip, SC-5, pilot structural metrics, the local judges.

  CLOSED, one sentence each in the paper:
  - CSC and all its arms;
  - post-hoc NF/HYB as a rename fix;
  - the panel route for R_COMP FREE;
  - per-operator within-base AUROC for consensus;
  - B1/B2; R_ADJ; L1 lint and L2-role on LLM outputs;
  - the vocabulary-divergence diagnosis of iteration 3 (refuted on E by the label-based decomposition).

  DELIVERABLE FUNCTIONS:
  - consensus_score(mode = align | exact | nf | hyb | pn | rw | gg);
  - graded_consensus;
  - pairwise_matrix / ed_decomposition;
  - exhaustive_map_label + gloss_decision (the labelling tools);
  - equivalent_modulo_vocab(_exhaustive);
  - minimal_typed_repair;
  - fol_triage;
  - peer_text.
  Each has a one-line statement of what it measures, and each is marked gold-free or gold-using.
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
  Same consensus object; CSC closed; cause re-diagnosed as wrong peers; broken confirmation sets fixed once
_confidence_delta: decreased
_key_changes:
- >-
  The CSC fix is CLOSED as a provisional negative. On a completion-selected 354-row subset, c_csc strat is 0.614 [0.493, 0.736]
  vs FREE_exact 0.770, Δ −0.156 [−0.290, −0.031]; anchoring e is 0.459 vs 0.173. G1 FAIL, G2 NOT_READ, G3 NOT_RUN. The title
  changes because the candidate's-own-words idea is dead.
- >-
  The diagnosis is revised from label-based evidence (eval 3). 61-77% of the disagreement a CORRECT candidate meets comes
  from peers labelled ERROR; only 9% of correct-correct disagreement is vocabulary. Every vocabulary bridge trades d for e:
  the aligner's meaning-rename e is 0.624 vs 0.104 for exact. The iter-3 'words not errors' story is refuted on E.
- >-
  Iteration 5 is confirmation-first. The two budget-broken confirmation sets are each fixed ONCE, with claims unchanged: the
  R_COMP FREE gloss labels (priority 1, in-scope free vocabulary) and E2 (long pool pre-declared primary, MDE ~0.11 stated).
  Frozen c_score_align is the pre-declared primary and is not re-selected.
- >-
  A drift gate comes before E2 labelling, because today's panel flags 0.12 vs 0.84 of original errors on 22 track-H items.
  On failure, the primary switches to R_COMP FREE + DT, labelled by the alignment-free map + gloss labeller against trusted
  gold.
- >-
  New $0 development screen aimed at the re-diagnosed cause (wrong, scattered peers): plurality-normalised, reliability-weighted
  and two-channel exact/align consensus. The selection rule is pre-registered; the winner is only a candidate for E2.
- >-
  The last rename attempt uses a new mechanism: gloss-gated name-free agreement. The lexical check separates synonyms from
  wrong predicates, which NF/HYB could not, and no cueing means no anchoring. It is dev-gated on PERTURB; on failure, rename
  non-invariance is reported as a measured boundary.
- >-
  The iteration-4 record is corrected for the paper: CIs copied verbatim from T4/T5, COMPOUND e 0.282/0.107, G2 NOT_READ,
  M3 under both specifications, NET within-arm, FREE consensus recall paired with base FA 0.71-0.99, LOCAL2 ties, typing free3
  0.123 on E (oracle is gold-using), E2 drift, FREE labels 'up to 70.7%', eval-3 misreadings removed ('0.683 theoretical AUROC'),
  and spend ≈$0.35 with the rest of the $7 phase budget unaccounted.
- >-
  Every blocking review item is listed as a paper transcription obligation: in-place corrections from eval-3 Part 4, the prior-art
  section for art_VIF75I5R6f0v, coverage-vs-request, one cost table with units, the spend table, the extended dead-ends table,
  and reasoning blocks.
- >-
  The error-type ask is answered negatively outside a shared vocabulary (free3 0.123; medoid 0.328 ≈ judge 0.326). No further
  budget goes to it.
_strands:
- artifact: art_D7k2ZWgE3nVd
  state: 'null'
  why: >-
    CSC strat 0.614 [.493,.736] vs FREE exact .770 (Δ −.156 CI<0); anchoring e .459 vs .173; G1 fail, G2 NOT_READ; completion-selected
    subset but clear negative
- artifact: art_pAmLrGqsmFUx
  state: broken
  why: >-
    0 CSC peers generated (budget 403); G3-P/G4/MT untested; $0 arms are out-of-scope SIGPROXY or trivial (FREE recall≈1 at
    base FA .71-.99)
- artifact: art_2OmxzMInZZJY
  state: broken
  why: >-
    Budget stop after 30/550 sentences: 0 CORRECT, no testable cell; drift stop rule UNDECIDED (track-H flag .12 vs .84 on
    22 items)
- artifact: art_Ia_FT284H33j
  state: broken
  why: >-
    Gloss step not run so CORRECT class empty, FREE AUROC untestable; search sound (0/1,595 false ERROR_CERT) and shows old
    FREE labels over-call ERROR
- artifact: art_BvAL_KZTZuw8
  state: lead
  why: >-
    Label-based: 61-77% of peers disagreeing with CORRECT candidates are ERROR; only 9% vocab-resolvable; d is peer error
    not vocabulary; oracle d L25 .542 vs .735
_evidence_state: lead
_move: deepen
_move_rationale: >-
  Lead (consensus + eval-3 cause). Deepen: confirm frozen consensus on untouched E2/R_COMP FREE (fix each once), attack wrong-peer
  cause at $0; CSC closed.
_coverage: full
_coverage_statement: >-
  Iteration 5 answers whether a cheap gold-free cross-model agreement score predicts faithfulness on long, conditioned sentences
  with no controlled vocabulary. It tests this on untouched data against judges and the baseline stack, and also reports invariance,
  per-type recall, coverage and cost, plus a negative answer on error typing.
_candidates_considered: 12
relation_type: evolution
</hypothesis>

<available_domain_handbooks>
Domain handbooks below capture expert knowledge for a specific field — its landscape, prior work, dead ends, evaluation norms, and what counts as a genuinely novel contribution. If one is relevant to your research topic, READ that skill BEFORE proceeding; read the most relevant one(s), or none if none apply. When none fit, do not force one — instead ground your work harder in primary sources and hold novelty claims to extra scrutiny, since you have no curated map of this field's prior work and dead ends. Use it for the methods, proper baselines, and evaluation this field demands.

- **aii-handbook-auto-computational-linguistics** — Field handbook for computational linguistics as a SCIENCE of language — grammaticality and minimal pairs (BLiMP), surprisal versus reading times, linguistic structure in LMs, annotator disagreement an
- **aii-handbook-auto-mechanistic-interpretability** — Field handbook for mechanistic interpretability of neural networks — circuit discovery, activation and attribution patching, sparse autoencoders, transcoders, attribution graphs, steering vectors, pro
- **aii-handbook-auto-multi-agent-llm-systems** — Field handbook for multi-agent LLM systems (MAS) — orchestration topology, multi-agent debate, mixture-of-agents, verifier and critic agents, inter-agent protocols (MCP/A2A), failure attribution and s
- **aii-handbook-auto-neurosymbolic** — Field handbook for neuro-symbolic AI — text-to-logic autoformalization (NL to FOL), LLM-plus-solver and prover pipelines (Prolog, ASP, SMT), probabilistic-differentiable NeSy (DeepProbLog, Scallop), r
</available_domain_handbooks>

<strategy_domain_reasoning>
How the strategist established that researchers in this field reason, at the level of the field's principles and standards of evidence. Take it as the starting point for the concrete practice below — extend or correct it where your own reading disagrees, and say so when you do.

FIELD: meta-evaluation of reference-free (gold-free) quality metrics, the methodology of the WMT metrics shared tasks, summarization-factuality meta-evaluation (FRANK, TRUE, SummaC) and LLM-as-judge validation, applied to neuro-symbolic NL->FOL autoformalization. READ FOR THIS STEP: the neurosymbolic handbook (aii-handbook-auto-neurosymbolic): [S13] FOLIO/MALLS gold is about 36-39% wrong; [S6] compilation is not faithfulness; [S9] gold-free round-trip certification is occupied; [S8] predicate lists are the NL->FOL lever; open question 3, 'no agreed gold-free faithfulness metric'. Also the iteration-4 artifacts and the power file (eval-3 power_E2.json), E2's prereg / census / drift file, dataset 5's resume script, and the prior-art artifact art_VIF75I5R6f0v (ARc, NoTB, GenV, LLMs-as-Jury, Chen & Avizienis). I ran no new web lookups in this bounded step. The MT/summarization norms below are standing knowledge (WMT's fresh test set each year; Deutsch et al. on metric CIs and ties), marked provisional.
(1) PRINCIPLES. Taken as given:
- benchmark gold is partly wrong, so the label construction is itself part of the result;
- several FOL formulas are correct for one sentence, so solver-exact vs intent labels can reverse rankings (GenV);
- compiling is not faithfulness;
- the incumbent a practitioner uses is a cheap API LLM judge.
Still argued: which label target is right, and whether a metric validated on one label regime transfers.
(2) WHAT CONVINCES. A metric win counts when it is paired, item-level and threshold-free, on real system outputs, against the incumbent, and scored ONCE with frozen parameters on data that no selection step touched. That is why WMT re-scores metrics on each year's fresh test set. It must also be shown to add signal by nesting over the best baseline combination, and must hold under a second, instrument-disjoint label regime. A development-set win plus a mechanism story is a lead, not a finding. A mechanism is believed when a label-based decomposition that could have come out the other way replicates on new data.
(3) STANDARD MOVES and what each rules out:
- stratified within-stratum AUROC: stratum composition;
- a sentence-clustered bootstrap: item dependence;
- a pre-declared primary cell with its MDE stated: forking paths and underpowered nulls read as wins or losses;
- a score seal before the label join: post-hoc metric tuning;
- instrument-disjoint labels: circular validation (the aligner shared by labeller and metric);
- a cost-matched and a frontier comparator: the 'you beat a weak judge' objection;
- nonce disguise with a DiD: memorised gold;
- base FA next to every recall: trivial recall (iteration 4's FREE recall of about 1 came at base FA 0.71-0.99);
- a paired flip, not raw FA, for invariance: base-rate confusion.
(4) USUAL FAILURE MODES:
- development-set optimism (the lead was chosen on E);
- completion-selected subsets after a budget stop (exp 9's PRIMARY was 45% CTRL);
- label drift when a panel is replayed months later;
- shared-instrument labels;
- quantised scores at unattainable thresholds;
- underpowered strata (the L25 +0.069 needs about 882 planned sentences);
- cost in the wrong unit (off by 13x in iteration 3);
- transcription drift between artifacts and the paper, the current BLOCKING cause.
</strategy_domain_reasoning>

<domain_practice>
FIRST WORK OUT HOW THIS KIND OF STUDY IS ACTUALLY BUILT IN THIS FIELD. Then
write the plan.

The strategy already settled what the field believes and what it counts as
convincing. Your job is the level below that: how work of exactly this kind
is designed, run and reported by the people who do it, concretely enough that
the executor's output would be recognised as competent by one of them.

Establish, for this field and this artifact type:

- BASELINES AND COMPARISONS. Which comparisons appear in every paper of this
  kind, named specifically. Which one would a reviewer name first if it were
  missing, and what is the standard way of tuning it fairly?
- CASES AND DATA. Which datasets, corpora, cohorts, benchmarks, case sets or
  sources are standard here, and which are known to be saturated, leaked,
  deprecated or unrepresentative. Prefer the ones the field actually uses,
  and say why when you pick something else.
- CONTROLS AND WHAT IS HELD CONSTANT. What has to be held fixed for the
  comparison to mean anything, and which confound this design is most likely
  to be caught on.
- HOW MUCH IS ENOUGH. Sample sizes, item counts, seeds, repeats, splits —
  the number below which nobody in this field believes a result, and what the
  field reports alongside a point estimate (variance, intervals, a
  significance or uncertainty treatment). When a power analysis, or the
  effect sizes already on record, say the panel cannot detect the size of
  effect the plan is chasing, the fix is more graded samples or checkpoints
  — not more candidate metrics. An underpowered panel stays underpowered no
  matter how many readouts run over it.
- MEASURES AND REPORTING CONVENTIONS. Which measures are standard, how they
  are computed here, and the conventions a reader will expect to see — what
  is reported, against what, in what form.

Not every axis applies to every artifact type: a proof has proof standards
and an accepted level of rigour rather than sample sizes, a research artifact
has source quality and coverage, a dataset has provenance, licensing and
documentation norms. Answer the ones that apply and skip the ones that do not
rather than inventing content for them.

HOW MUCH EFFORT. Bounded, like the strategist's: the fitting domain handbook
plus a handful of targeted lookups — one or two recent papers doing this exact
kind of study, a benchmark or dataset card, a methods or reproducibility note.
Read what the field does; do not reason it out from first principles. You
cannot run code, so this is reading only.

THEN CHECK THE PLAN AGAINST IT.
- `domain_practice`: what you established above, concretely — named baselines,
  named data, the numbers, the measures, with what you read.
- `practice_alignment`: go through the plan you just wrote against that list
  and say, point by point, where it MEETS the field's practice and where it
  DEPARTS from it. For every departure: why it is justified here (budget,
  scope, the claim being narrower) and what it costs the result's
  credibility. A departure nobody named is the one a reviewer finds.
- Where the check exposes a gap you can close inside the budget, close it in
  the plan rather than reporting it. `practice_alignment` is for what remains
  after you have fixed what you can.
</domain_practice>

<artifact_direction>
Make this direction concrete and actionable. Keep the same type and respect dependencies.

id: experiment_iter5_dir2
type: experiment
objective: >-
  MORE POWER: a second, independent untouched L25 sample. E2-A's 350 L25 sentences give MDE80 about 0.11 on L25, and the long
  pool has about 194 usable sentences, below the 237 that eval 3 says are needed. The observed E effect on L25 (+0.069) is
  therefore undetectable without more graded sentences. E2-B draws about 400 fresh MALLS-train L25 sentences by E2's frozen
  selection rule (the 98-sentence pre-ranked surplus first, then the next sha1-ordered eligible sentences, about 700 remain
  after filters). It generates and labels them with the byte-identical E2 code and scores the same frozen metrics with the
  same seal. It also adds the two comparators a reviewer names first: a COST-MATCHED stronger cheap judge and the frontier
  judge on a 300-row subsample.
approach: |-
  SHARED CROSS-ARTIFACT CONTRACT (identical text in all five directions). The five artifacts run in parallel and this is the last iteration, so every piece that joins two artifacts is done by polling for a marker file, and every consumer has a stated fallback that still produces a reportable result.
  (M1) FREEZE marker, written by the 'freeze' experiment: <its workspace>/freeze/CONSENSUS_FREEZE_READY.json with token 'aii_iter5_consensus_freeze_v1'. It holds the sha256 of freeze/consensus_variants.py, of freeze/selection.json (the H-IMPROVE winner, or 'NONE: V0 stands'), and of freeze/gg.py + freeze/gg_gate.json (H-RENAME: PASS/FAIL, gloss model id, prompt sha). Consumers find it with glob('/ai-inventor/aii_data/runs/run_u75jRHUss0zo/3_invention_loop/iter_5/gen_art/*/freeze/CONSENSUS_FREEZE_READY.json'), check the token, and copy (never import across paths) the frozen files into their own workspace. The expected write time is within about 90 minutes of start (V) and 3.5 h (GG).
  (M2) DRIFT marker, written by the E2-A experiment: <ws>/e2/E2_DRIFT_DECISION.json with token 'aii_iter5_e2_drift_v1' (PASS/FAIL, the numbers, the pinned provider per panel model).
  (M3) FINAL markers: <ws>/e2/E2A_FINAL_READY.json and <ws>/e2b/E2B_FINAL_READY.json with tokens 'aii_iter5_e2a_final_v1' and 'aii_iter5_e2b_final_v1'. Each points to that artifact's per-row file (row_key, sentence_id, stratum, label, tier, every frozen score) and gives its sha256.
  Every poll loop sleeps 5 min, logs each attempt, and has a hard deadline written into the prereg. A path found by glob is read-only; nothing is written outside the artifact's own workspace.
  SPEND: OpenRouter only, via os.environ OPENROUTER_BASE_URL / OPENROUTER_API_KEY. Make a 1-token probe first. Log cost after every call to cost_ledger.jsonl, and stop hard at the artifact cap. Estimate every sweep's cost from a small pilot BEFORE running it, and do not start a sweep whose estimate exceeds the remaining budget minus a 10% reserve. On HTTP 403/402 (run budget) do all CPU work first, then poll every 15 min; if the block persists past the deadline, report the partial result as partial.
  NO COMPLETION SELECTION (the lesson of iteration 4, exp 9): every paid sweep over sentences runs in a pre-registered sha1 order, and each batch of 50 sentences is completed end to end (generation, then labels) before the next batch starts. A budget stop therefore leaves a random subsample of each stratum, not a completion-selected one, and the report states the completed fraction per stratum.

  FROZEN METRIC DEFINITIONS (verbatim; the freeze experiment implements them in consensus_variants.py; fallback implementers use this text).
  For a candidate x of sentence s, P = the parseable peer outputs of s from slots whose family differs from x's family (exp 5 leave-own-family-out, byte-identical to /ai-inventor/aii_data/runs/run_u75jRHUss0zo/3_invention_loop/iter_2/gen_art/gen_art_experiment_5/src). A(x,p) = the frozen exp-5 ALIGN equivalence modulo vocabulary (z3 2 s; UNKNOWN = not equivalent, counted). E(x,p) = exact equivalence (lowercased names + arity, no aligner).
  - V0 c_score_align = 1 - |{p in P: A(x,p)}| / |P|. This is the PRIMARY, pre-declared in iteration 3 and never re-selected.
  - V1 c_pn (plurality-normalised) = 1 - min(1, share_A(x) / max_class_share). Classes = the eval-2 pairwise_matrix class ids over P under A. max_class_share = the size of the largest class / |P|. A candidate in the plurality class scores 0.
  - V2 c_rw (reliability-weighted) = 1 - sum_{p in P, A(x,p)} w_f(p) / sum_{p in P} w_f(p). w_f = the mean pairwise A-agreement of family f with every other family, over sentences in the OTHER 4 sentence folds (fold = sha1('E_folds_v1|'+sentence_id) % 5 on E; the same recipe with 'E2_folds_v1|' on E2). It is label-free, a Dawid-Skene-style reliability, shrunk toward the grand mean with 20 pseudo-sentences.
  - V3 = V1 computed with w_f-weighted shares.
  - V4 two-channel = a logistic on (c_exact, c_align), cross-fitted on E's 5 folds for the screen, then refit once on all E R_AB rows and frozen (coefficients in selection.json) for E2.
  - V5 = V3 restricted to the eval-2 cross-fitted best 3-pool (deepseek + microsoft + openai), the cost-matched $0.001-per-sentence variant.
  - PT p_peer_text = the frozen exp-5 fusion, a SECONDARY row.
  - GG (gloss-gated, H-RENAME): x and p agree if E(x,p), OR if an exhaustive injective arity-consistent symbol map from x's symbols onto p's (dataset 5 freelab.equivalent_modulo_vocab_exhaustive, adapted from template atoms to peer symbols, capped at 2e4 maps / 10 s per pair; a cap hit counts as not agreeing) yields z3 equivalence AND the gloss checker confirms that EVERY non-identity mapped symbol pair means the same thing in this sentence. The aligner is NOT used. c_gg = 1 - share of peers agreeing under GG.

  INPUTS: the same as E2-A. Copy /ai-inventor/aii_data/runs/run_u75jRHUss0zo/3_invention_loop/iter_4/gen_art/gen_art_dataset_4 (without .venv) into ./e2bsrc. Relevant: census_E2.json (L25 supply after filters: 960 at 25-29 words + 186 at >= 30), prereg_E2.json (seed string, order, exclusion rules, surplus_rule), select_e2.py. Dataset E, exp 5, exp 6, eval 2 as in E2-A.
  Hard cap $9.5. Projected: 400 x $0.0118 = $4.7 + judges $0.4 + cost-matched judge $1.0 + frontier 300 rows $1.1 = about $7.2. Shrink order: frontier -> cost-matched original view -> L25 sentences (floor 250, always a sha1-order prefix).

  STEP 0, PREREG (prereg_iter5_E2B.json + sha256, before selection):
  - E2-B is a pre-registered REPLICATION SAMPLE drawn by E2's frozen rule; it is a declared deviation from E2's freeze (D-E2B), and the reason is written: power;
  - selection = E2's surplus order (98), then continue the SAME sha1 order ('E2_v1|' + sentence_id) over the remaining eligible L25 pool, disjoint from E, the screen, FOLIO, E2's 550 and the DT reserve, applying E2's 12-gram rule; target 400;
  - the same metric list, seal order and analyses as E2-A;
  - the union and meta-analysis rule;
  - the cost-matched judge spec.

  STEP 1, DRIFT: poll for E2_DRIFT_DECISION.json (M2) until T+1.5 h. Generation runs meanwhile, so no time is lost. Use its decision and its pinned providers. Fallback, only if M2 is absent at the deadline: run E2's gate yourself with the same pinning procedure (about $0.3), and record the pinning procedure in deviations.

  STEP 2, GENERATION + LABELS: E2's run_all.sh steps 5-7 on the E2-B sentences, 10 slots, in batches of 50 completed end to end. Rename controls: controls_e2.py.

  STEP 3, LABEL-FREE SCORING + SEAL: identical to E2-A Step 3 (same file-access allowlist, same fallback rule for M1).
  Plus two comparators:
  - COST-MATCHED JUDGE: deepseek/deepseek-v3.2 (reasoning off), rubric A JSON 0-100, disguised and original. Its cost per candidate (about $2-4e-4) brackets consensus FULL ($1.21e-4 per candidate for 9 peers). Frozen prompt = the flash-lite rubric A text byte-identical. Pilot on 30 rows for parse rate and cost.
  - FRONTIER: google/gemini-3.1-pro-preview, original view, on a 300-row subsample stratified by label-free words tercile x system family, drawn BEFORE labels are joined. Report IPW-corrected AUROC as in T1.

  STEP 4: join after both seals verify.

  STEP 5, ANALYSES (the same code as E2-A where shared):
  - L25 strat AUROC Delta V0 - flash-lite disguised with CI, plus vs flash-lite original, nano, the cost-matched judge and the frontier (ratio V0 / frontier with CI, and nested [frontier + V0] - frontier on the subsample);
  - nested over S4_E2B (cross-fitted);
  - H-MECH (i)-(iv) on E2-B;
  - H-IMPROVE carried variant;
  - rename FA + flip;
  - complexity curves;
  - coverage;
  - cost per candidate FULL/MARGINAL for every metric, including the cost-matched judge and the frontier: the 'does a large judge earn its cost' row the user asked for;
  - tau-b over system x variant.
  UNION: write E2B_FINAL_READY.json (M3), then check for E2A_FINAL_READY.json. If present, compute the union long-pool analysis and the inverse-variance meta-analysis with the SAME code and definition as in E2-A (sentence-cluster bootstrap over the union; strata = L25_E2A, L25_E2B, EXC; primary = V0 - flash-lite disguised). Also give the between-sample heterogeneity (Delta_E2A - Delta_E2B with CI): a replication check that could come out against us.

  OUTPUT:
  - e2b/ (sealed rows, seal.json, testability);
  - scores_E2B.jsonl, score_seal.json, per_item_E2B.jsonl;
  - confirm_verdict_E2B.json;
  - union_longpool.json (if computed here);
  - judges_costmatched.jsonl, judge_frontier.jsonl;
  - tables.md with source lines;
  - method_out.json (exp_gen_sol_out);
  - deviations.json, cost_ledger.jsonl, README.
what_it_would_show: ''
depends_on:
- id: art_2OmxzMInZZJY
  label: sampling frame
  relation_type:
  relation_rationale:
- id: art_U4Hsqt4Ay9Tg
  label: dev dataset
  relation_type:
  relation_rationale:
- id: art_zcwCQgTqk6DN
  label: rename code
  relation_type:
  relation_rationale:
</artifact_direction>

<dependencies>
Completed artifacts this artifact can use during execution.

--- Dependency 1 ---
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
out_dependency_files:
  file_list:
  - data.py
  - full_data_out.json
  - mini_data_out.json
  - preview_data_out.json
  data_file_paths:
  - full_data_out.json
  - mini_data_out.json
  - preview_data_out.json

--- Dependency 2 ---
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
out_dependency_files:
  file_list:
  - data.py
  - full_data_out.json
  - mini_data_out.json
  - preview_data_out.json
  data_file_paths:
  - full_data_out.json
  - mini_data_out.json
  - preview_data_out.json

--- Dependency 3 ---
id: art_2OmxzMInZZJY
type: dataset
title: Fresh logic test set, paused by budget
summary: >-
  E2 (PARTIAL, budget-stopped): the frozen, sealed design of a fresh NL->FOL faithfulness confirmation set disjoint from dataset
  E, labelled by E's byte-identical code (code_freeze.json). The run-level 'Test idea' OpenRouter budget ($7, shared by all
  concurrent artifacts) ran out at 07:26 UTC after this artifact spent $0.24. The proxy refuses paid calls until the user
  raises the budget. WHAT EXISTS: (1) 550 active sentences with gold references, pre-registered and hashed before generation
  (prereg_E2.json): L25 350 (MALLS-v0.1-train, >=25 words, >=3 conditions, 45% in the 30-34-word bin, mean 28.8 words / 4.65
  conditions); EXC 100; DT 100 (ProverQA dev, prover-built gold, 1 per entity skeleton, >=15 words and >=2 conditions). Also
  a ranked L25 surplus order (98) and a DT reserve (10). EXC CAVEAT: the core-exception supply is exhausted (E took all 67
  MALLS-train items; MALLS-test has 3, all excluded), so E2-EXC is 92 'without' + 8 non-XOR 'but not' items, core-marker share
  0.0. (2) A 30-sentence pilot (12 L25 / 8 EXC / 10 DT): 300 real candidates from E's 10 few-shot slots (9 families, temperature
  0) + 30 gold-as-system rows, solver-labelled by E's labeller. Without panel votes E's final rule gives 36 ERROR (tier A_unaudited_ref),
  244 UNRESOLVED, 20 UNPARSEABLE, 0 CORRECT. (3) A partial panel drift check: the 77 synthetic gate items were replayed with
  a fresh cache (majority agreement with E's stored votes 0.974; balanced accuracy P1 0.861 / P3 0.875 / R1 0.837 vs E 0.861
  / 0.85 / 0.863). Track H was cut off, so the stop rule is UNDECIDED. (4) A seal: candidates_E2_nolabels.jsonl vs sealed/labels_E2.jsonl
  + references, sha256 in seal.json, verify_seal.py passes. (5) testability_E2.json: NO cell is testable now. Projected MDE80
  if completed is 0.112 at L25=350 and 0.099 at 450; the direction's '400 L25 detect +0.08' claim is wrong (needs ~690). full_data_out.json
  groups: e2_candidates (300), e2_gold_as_system (30), e2_sentences (550, status PENDING_GENERATION_BUDGET_STOP for 520),
  e2_panel_drift (173). All source-checked rows verify. RESUME: `bash src_e2/run_all.sh` (resumable; projected $6.8, ~2.5
  h). DOWNSTREAM: in this state E2 cannot confirm any metric. Iteration 5 must either wait for the resume or use E2 only as
  a pipeline/seal smoke test. Deviations D0-D7 are in dataset_card.md.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_u75jRHUss0zo/3_invention_loop/iter_4/gen_art/gen_art_dataset_4
out_expected_files:
- data.py
- full_data_out.json
- preview_data_out.json
- mini_data_out.json
- reproducibility.md
out_dependency_files:
  file_list:
  - data.py
  - full_data_out.json
  - mini_data_out.json
  - preview_data_out.json
  - reproducibility.md
  data_file_paths:
  - full_data_out.json
  - mini_data_out.json
  - preview_data_out.json
</dependencies>

<prior_work>
Everything this run has already produced, earlier rounds included. This is what
the plan builds on.

--- Artifact 1 ---
id: art_d0njuqy2Csj-
name: gen_art_experiment_1
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
iteration: 1
workspace_path: >-
  /ai-inventor/aii_data/runs/run_u75jRHUss0zo/3_invention_loop/iter_1/gen_art/gen_art_experiment_1
out_expected_files:
- method.py
- full_method_out.json
- mini_method_out.json
- preview_method_out.json
out_dependency_files:
  file_list:
  - method.py
  - full_method_out.json
  - mini_method_out.json
  - preview_method_out.json

--- Artifact 2 ---
id: art_i3cVDxBp-USk
name: gen_art_experiment_3
type: experiment
title: Do other models' translations agree? Consensus metric for NL-to-logic
summary: >-
  Experiment 3 screens candidate C, a text-free, gold-free consensus metric for NL->FOL faithfulness, on the shared frozen
  screen (label hash 0e43cbdd...). c_score = 1 - eq_frac: the share of OTHER systems' translations of the same sentence that
  are NOT z3-equivalent t
ontology vocabulary injected into prompts),
anything that depends on a particular ontology, and building a better NL→FOL translator. The
contribution is the measurement, not the translator.

Deliverables: reusable Python functions taking (text, fol) — or a set of such pairs — each with a
precise statement of what it measures; the meta-evaluation dataset with its labels; and the results.

I appended a pilot study of this problem with some metrics I already used but haven't verified. Just for reference.
````

### [2] SKILL-INPUT — aii-handbook-auto-neurosymbolic · 2026-09-24 10:58:30 UTC

The agent loaded the **aii-handbook-auto-neurosymbolic** skill; its `SKILL.md` (the instructions injected into the agent's context) follows verbatim.

```
---
name: aii-handbook-auto-neurosymbolic
description: "Field handbook for neuro-symbolic AI — text-to-logic autoformalization (NL to FOL), LLM-plus-solver and prover pipelines (Prolog, ASP, SMT), probabilistic-differentiable NeSy (DeepProbLog, Scallop), reasoning faithfulness and scope laundering, ontology and KG grounding, logic benchmarks (FOLIO, ProverQA, MALLS). ALWAYS read before ANY neuro-symbolic research work — ideation/novelty assessment, study planning, experiment/eval design, or write-up; do NOT work from priors alone (several obvious-looking directions are already crowded). Triggers: neurosymbolic, text2logic, autoformalization, semantic parsing to logic, solver-verified reasoning, Kautz coupling taxonomy, proof-chain evaluation. NOT for: pure formal methods or Lean proving with no neural component, generic prompt engineering, KG-embedding work without logic, activation-level interpretability (use aii-handbook-auto-mechanistic-interpretability), or agent orchestration (use aii-handbook-auto-multi-agent-llm-systems)."
tools: Read, Write, Bash
---

<!-- GENERATED by amg-handbook-forge — DRAFT for expert review. generated: 2026-07-07 ·
     next_check: 2026-10 (volatile half-life ≈ months). ✓x=exec · [Sn]=cited · ⚠️=candidate.
     Row fails → `STALE: <what>` in place. -->

# Neuro-symbolic AI — field handbook (mid-2026)

## Overview
The SUBSTRATE below is the star: a dense, grounded map of the field as of mid-2026 — organizing principles, a theme-balanced frontier, and an explicit do-not-redo list. The only lens is OPEN QUESTIONS (tensions the reader resolves their own way; no prescribed directions), then a thin execution floor. Every claim resolves to a verbatim quote in [SOURCES.md](SOURCES.md).

## Organizing principles (how the field reasons)
- **No settled integration recipe.** ["To date, no single predominant approach exists"](https://en.wikipedia.org/wiki/Neuro-symbolic_AI) [S2]. The shared design-space map is Kautz's coupling taxonomy; the text2logic pattern is type 3 — a ["neural architecture to interpret perceptual data as symbols and relationships that are further reasoned about symbolically"](https://en.wikipedia.org/wiki/Neuro-symbolic_AI) [S2].
- **Verification is entering BOTH inference and training.** The 2024–2026 through-line: techniques ["that increasingly connect generation with verification"](https://arxiv.org/abs/2606.08728) [S12] — verification is no longer a post-hoc add-on.
- **Deep work is judged on principled integration serving trust.** The durable framing centers ["trust, safety, interpretability and accountability"](https://arxiv.org/abs/2012.05876) [S4]; the 2024 systematic review (1,428→167 papers) finds ["Explainability and trustworthiness are less represented (28%), with meta-cognition being the least explored area (5%)"](https://arxiv.org/html/2501.05435v1) [S1].
- **The stated scale bottleneck is knowledge acquisition, not inference:** ["knowledge extraction is the main bottleneck"](https://en.wikipedia.org/wiki/Neuro-symbolic_AI) computationally at large scale [S2].
- **The field now applies a correction rule to its own headlines:** ["high compilation rates or accuracies should not be equated with faithful reasoning"](https://arxiv.org/abs/2604.19459) [S6][S5] — accuracy gains no longer certify the reasoning behind them.

## Frontier (2025 H2 – 2026 H1, recency-weighted, theme-balanced)

**Text→logic / autoformalization.**
- Scale is not the lever for NL→FOL: ["Our fine-tuned Flan-T5-XXL achieves 70% accuracy with predicate lists, outperforming GPT-4o and even the DeepSeek-R1-0528 model with CoT reasoning ability"](https://arxiv.org/abs/2509.22338); ["predicate availability boosts performance by 15-20%"](https://arxiv.org/abs/2509.22338) — the predicate list, not model size, is the lever [S8] (2025-09).
- **Wedge now OCCUPIED (rank it down):** gold-free certification of autoformalization exists — ["We propose a roundtrip verification approach which does not require ground-truth annotations: formalize a statement, translate the result back to natural language, re-formalize, and use a formal tool to check logical equivalence."](https://arxiv.org/abs/2604.25031) [S9] (2026-04, SMT-community authors). Proposing gold-free roundtrip certification as novel re-treads this.
- The "LLMs can't do NL→FOL" premise is being walked back — ["recent literature provides contrasting results"](https://arxiv.org/abs/2511.11816), but sentence-level translation is largely handled [S23] (2025-11) → crowded lane 4.

**LLM+solver coupling.**
- The intermediate representation is a live design axis: reframing math reasoning as verifiable code (SymPy) moves failures from opaque fallacies to transparent program errors, ["demonstrating significant accuracy improvements of up to 13.6 percentage points over baselines"](https://arxiv.org/abs/2510.25975) [S11] (2025-10).
- Formalize-everything, forward-only pipelines are the diagnosed failure shape — they ["often suffer from redundant inference paths, hallucinated steps, and semantic drift"](https://arxiv.org/abs/2512.03360); the 2025-12 counter-design couples selective, confidence-aware translation with hypothesis-driven backward reasoning [S20].

**Probabilistic / differentiable NeSy.**
- Normative result, live controversy: the independence assumption (the tractability trick in DeepProbLog/Scallop-style predictors) formally ["entails that a model can never represent uncertainty over certain concept combinations"](https://arxiv.org/abs/2507.11357) [S14] (2025-07).
- Adoption is bottlenecked by tooling, not algorithms: ["A majority of the NeSy research focuses on algorithms instead of providing generic frameworks for declarative problem"](https://arxiv.org/abs/2509.07122)-solving [S15] (2025-09).

**Benchmarks & eval methodology.**
- Benchmark-validity result: canonical NL→FOL gold is broken — ["approximately 39% and 36% of entries, respectively, contain incorrect FOL formalizations (i.e., ground truth labels)"](https://arxiv.org/abs/2606.02837) in FOLIO and MALLS; corrected labels shift model accuracy +9–22pp, so scores on the originals partly measure annotation noise [S13] (2026-06).
- Eval is shifting from one-gold-proof to multi-path: LogicGraph ships solver-verified instances ["where each instance is associated with an exhaustive set of minimal proofs"](https://arxiv.org/abs/2602.21044) [S19] (2026-02).

**Faithfulness / auditable traces** *(hottest thread — deliberately capped here; see crowded list).*
- Formal structure raises accuracy, yet ["this gain does not imply faithful reasoning"](https://arxiv.org/abs/2606.16118): scope laundering — reporting solver-inconsistent verdicts without executing the formal reasoning — ["persists across all models"](https://arxiv.org/abs/2606.16118) [S5] (2026-06, COLM-2026 under review).
- Baseline-correcting dissent: under UNIFIED generation there is ["no evidence of systematic gaming in unified generation"](https://arxiv.org/abs/2604.19459) — ["models prefer reporting failure over forcing proofs"](https://arxiv.org/abs/2604.19459); unfaithfulness surfaces in the TWO-STAGE split and differs by model (axiom fabrication vs premise mistranslation that evades detection) [S6] (2026-04). Reading this paper as "models game formalization" is a documented misreading.
- Per-step trace validation exists: VeriCoT formalizes each CoT step to FOL and types its grounding premise (source / commonsense / prior step); validity ["serves as a strong predictor of final answer correctness"](https://arxiv.org/abs/2511.04662) [S10] (2025-11).
- Terminology (single 2-author preprint — lead only): ["a formal statement can typecheck and be provable, yet still encode a different theorem than the source intended."](https://arxiv.org/abs/2606.16541) [S7] (2026-06).

**Ontology / KG grounding.**
- **Wedge PARTLY OCCUPIED — and this section's one peer-reviewed anchor:** pretrained NL-term embeddings collide with formal ontology term syntax (SUMO/SUO-KIF), so models ["produce syntactic errors or hallucinate non-existent terms due to conflicting embeddings learned during base training"](https://proceedings.mlr.press/v284/thompson25a.html); a tokenization fix mitigates it [S18] (NeSy 2025, PMLR v284). "Ontology as a faithfulness lever" is no longer blank space.
- Ontology-grounded pipelines are being positioned for high-assurance domains (law/medicine), whose reasoning is ["inherently involving defeasible or non-monotonic logic due to numerous exceptions"](https://arxiv.org/abs/2510.01530) — grounding as an assurance lever, not just background knowledge [S16] (2025-10).

## Recent (~1–2 yr, compressed)
- **ProverGen/ProverQA** (ICLR 2025): prover-synthesized FOL eval — scalable, contamination-resistant, with ["accessible and logically coherent intermediate reasoning steps for each problem"](https://arxiv.org/abs/2502.06563); ["state-of-the-art LLMs struggle to solve ProverQA problems, even with CoT prompting"](https://arxiv.org/abs/2502.06563) [S25] (2025-02).
- **NL2FOL** (2024-05): the named key challenge is ["the integration of implicit background knowledge"](https://arxiv.org/abs/2405.02318) [S32].
- **GSM-Symbolic** (2024-10): pure-neural reasoning is perturbation-fragile — ["Adding a single clause that seems relevant to the question causes significant performance drops (up to 65%)"](https://arxiv.org/abs/2410.05229) [S29].
- **AlphaGeometry** (Nature 2024): the field's flagship result — the 2024 review found ["only one entry at the intersection of all 4 of the main research focal areas"](https://arxiv.org/html/2501.05435v1): AlphaGeometry [S1][S28].

## Durable core (foundations an expert still leans on)
- **Logic-LM / LINC** (2023) — the canonical parser+solver pattern: the LLM translates; ["These expressions are then offloaded to an external theorem prover, which symbolically performs deductive inference."](https://arxiv.org/abs/2310.15164) [S26][S24]. Self-refinement = the solver's error messages fed back [S24].
- **DeepProbLog / DeepStochLog / Scallop / Logic Tensor Networks** — settled probabilistic-differentiable canon; know them, do not re-propose them [S1][S2].
- **Kautz coupling taxonomy + Garcez & Lamb third-wave framing** — the field's shared vocabulary [S2][S4].

## Already crowded — go ELSEWHERE (do-not-redo)
Saturated threads with strong 2025–26 work; adding to them is incremental. The blank space is NOT here:
1. **Accuracy ≠ faithfulness diagnosis** — the gap is documented across [S5][S6][S7]; merely diagnosing it again is months late. Nuance inside the lane: the "formalization gaming" headline is already contested [S6].
2. **Interventional / counterfactual faithfulness** — a named lane: RFEval [S21]; Executable Counterfactuals — which itself notes existing evals ["tend to skip the abduction step, effectively reducing to interventional reasoning"](https://arxiv.org/abs/2510.01539) [S17]; label-flip evaluation with judge-model selection (Truth-or-Twist [S22] — a judge-selection study, not a proof-DAG benchmark).
3. **Proof-DAG / counterfactual-twin benchmarks** — LogicGraph already ships solver-verified, exhaustive minimal-proof sets [S19]; LogiConBench is a further lead (403-blocked; candidate lane).
4. **Bare NL→FOL translators** — saturated since Logic-LM/LINC 2023 [S24][S26]; ["state-of-the-art, dialogue-oriented LLMs demonstrate strong NL-FOL translation skills"](https://arxiv.org/abs/2511.11816) [S23]. Another translator is incremental.
5. **Per-axiom / per-step source-grounded ATTESTATION at the formalization seam** — grounding each formal atom or CoT step in an identified source premise + a solver/entailment check is an occupied lane: VeriCoT types each step's grounding premise and finds validity ["serves as a strong predictor of final answer correctness"](https://arxiv.org/abs/2511.04662) [S10], and premise-correspondence / scope-laundering checks already probe the same seam [S5][S7]. "Gate every premise against the source" re-treads this — the open move is what these do NOT do (e.g. defeating *shared-bias* mistranslation, not just per-premise support).
6. **Reverse-direction / NL-first, solver-certified benchmarks** — real-text (not template) inputs, expert-audited + Z3-checked, scored on formalization faithfulness: an active 2026 lane — LLMEval-Logic ["verifies annotated answers with Z3, constructs expert rubrics for natural-to-formal grading"](https://arxiv.org/abs/2605.19597) [S33]. "A reverse-direction certified benchmark" as the contribution re-treads it; only a distinct axis (e.g. a synthetic→natural transfer diagnostic) stays open.

## Open questions the field hasn't answered (the whole lens — answer in your own way)
1. Canonical pipelines equated accuracy boosts with ["a promising avenue for faithful logical reasoning"](https://arxiv.org/abs/2305.12295) [S24]; 2026 evidence shows the gain ["does not imply faithful reasoning"](https://arxiv.org/abs/2606.16118) [S5]. What property should a text→logic system be optimized and reported on — and what evidence would let a faithfulness claim survive both [S5]'s divergence protocol and [S6]'s two-stage protocol?
2. A solver in the loop is assumed to transfer soundness to the user-visible answer — ["a solver produces a sound and independently verifiable answer"](https://arxiv.org/abs/2606.19588) — yet ["the soundness guarantee can be lost in the interaction between the solver and the model"](https://arxiv.org/abs/2606.19588) [S27], scope laundering ["persists across all models"](https://arxiv.org/abs/2606.16118) [S5], while a Lean-4 study finds no systematic gaming under unified generation [S6]. Where along NL → formalization → execution → reported answer does soundness actually leak, and what task / pipeline-split / model differences reconcile the clashing results?
3. Per-step validators exist [S10] and roundtrip equivalence certification covers translation [S9], but there is no agreed gold-free faithfulness metric (as of 2026-07). What would a gold-free, process-level faithfulness measure have to certify for the field to accept it as a primary reported number?
4. Prover-synthesis provides gold chains [S25] and exhaustive minimal-proof sets [S19], while hand-curated gold is ~36–39% wrong [S13] — yet accuracy is still the primary reported metric. What blocks process-level scoring from becoming the default, and what would unblock it?
5. The independence assumption is ubiquitous for tractability yet formally ["entails that a model can never represent uncertainty over certain concept combinations"](https://arxiv.org/abs/2507.11357) [S14]. Where does this limitation actually bite on realistic tasks — and does the community's scepticism that it rarely matters hold up?
6. An upper ontology is assumed to supply clean background structure, but peer-reviewed evidence shows NL-term embeddings collide with formal term syntax, yielding hallucinated terms [S18], while high-assurance framings demand defeasible, evidence-grounded reasoning [S16]. What is ontology grounding actually good for in an LLM-era pipeline — and at what integration cost?

## What counts as DEEP here (taste)
| Deep / killed | Contrast | Separating cue · reopening condition | src |
| --- | --- | --- | --- |
| AlphaGeometry (Nature 2024): dissolved the structural bottleneck (proof-data scarcity) — ["sidesteps the need for human demonstrations by synthesizing millions of theorems and proofs"](https://www.nature.com/articles/s41586-023-06747-5) | AlphaGeometry2: same recipe scaled/tuned — ["we have significantly boosted the overall solving rate of AG to 84%"](https://arxiv.org/abs/2502.03544) (from 54%) | deep = attack the bottleneck so a new capability becomes possible; incremental = push the same paradigm's number | [S28][S31] |
| killed: the bare NL→FOL translator as the contribution | dismissal (2025-11): SOTA dialogue LLMs translate sentence-level logic well [S23] | reopen where translation still fails: beyond sentence level (long documents; dense modal/temporal/higher-order logic), or where ["embedding-centric models perform markedly worse"](https://arxiv.org/abs/2511.11816) | [S23] |
| killed: purely-neural end-to-end reasoners | dismissal (2024-10): ["current LLMs cannot perform genuine logical reasoning; they replicate reasoning steps from their training data"](https://arxiv.org/abs/2410.05229); compositional collapse [S30] | reopen only on demonstrated out-of-distribution, clause-count-robust reasoning that clears the GSM-Symbolic bar | [S29][S30] |
| killed: trusting FOLIO/MALLS original gold labels | dismissal (2026-06): ~39%/36% incorrect formalizations [S13] | reopen via the released corrected splits — relabeling framework reached ["90% dataset accuracy after reviewing fewer than 24% of instances"](https://arxiv.org/abs/2606.02837) | [S13] |

The line as THIS field draws it: contributions are weighed on principled integration serving trust/interpretability [S4], and the under-served areas (explainability & trust ~28%, meta-cognition ~5% [S1]) are where work reads deep — not another accuracy point on a saturated translator [S23].

## Critical rules (execution · eval · validity)
| Naive move | Expert move | Why (failure prevented) | src |
| --- | --- | --- | --- |
| Evaluate NL→FOL on FOLIO/MALLS as shipped | Use the corrected re-annotations or prover-synthesized sets; state which labels you scored on | ~39%/36% wrong gold; +9–22pp label-noise swings → wrong-result | [S13][S25] |
| Read compilation / typecheck / accuracy as faithfulness evidence | Measure faithfulness separately, on the reported answer | compilation rates ≉ faithful reasoning [S6]; typecheck+provable can encode a different theorem [S7] → wrong-result | [S6][S5][S7] |
| Default to prompting the largest reasoning LLM for NL→FOL | Also benchmark a fine-tuned small encoder-decoder and supply the predicate list | predicate availability +15–20%; T5-XXL beats GPT-4o / R1-0528 → wasted-cost | [S8] |
| Formalize the whole document and forward-chain | Weigh selective, confidence-aware translation and hypothesis-driven backward reasoning | forward-only: redundant paths, hallucinated steps, semantic drift → wrong-result | [S20] |
| Assume ontology terms ground cleanly | Test formal-term grounding separately (NL-embedding / term-syntax collision) | hallucinated non-existent terms in SUO-KIF-style languages → wrong-result | [S18] |
| Score reasoning against one gold proof chain | Account for alternate minimal proofs (multi-path eval) | penalizes valid derivations; distorts process scores → wrong-result | [S19] |

## Decision guide
- **Benchmark choice:** template sets (RuleTaker/ProofWriter) when you need scale + control and accept shortcut risk; FOLIO/MALLS ONLY with corrected labels [S13]; ProverQA for contamination-resistant, chain-accessible eval [S25]; LogicGraph when multiple valid proofs matter [S19].
- **Intermediate representation:** verifiable code (SymPy-style) when the domain is computational math [S11]; logic forms when deduction/entailment is itself the object [S24][S26].
- **Probabilistic substrate:** independence-assuming predictors (DeepProbLog/Scallop lane) buy tractability but formally cannot represent uncertainty over some concept combinations [S14] — decide by whether that uncertainty is load-bearing for the task.
- **Sourcing:** most 2025–26 results above are arXiv preprints; [S18] (PMLR) and the 2023–25 EMNLP/ICLR/Nature anchors are the peer-reviewed exceptions — prefer published versions for load-bearing claims (volatile.md tracks status).

## Ground rules (known-lane — terse)
- LLM = semantic parser, solver = deterministic inference — the Logic-LM/LINC division of labor [S24][S26].
- Self-refinement = feed the solver's error messages back to revise formalizations [S24].
- NL→FOL's named key challenge: implicit background knowledge the text leaves unstated [S32].
- Template benchmarks: scalable but simplistic; hand-curated: small + contamination-prone; prover-synthesis is the scalable route [S25].
- Scope laundering = reporting a solver-inconsistent verdict without executing the formal reasoning; sibling failure modes: implicit-constraint blindness, program-synthesis errors [S5].
- text2logic sits at Kautz type 3 ("Neural | Symbolic") on the coupling map [S2].
- Knowledge extraction is the stated main computational bottleneck at scale [S2].

## Reference documentation
- **[volatile.md](volatile.md)** — wedge-occupancy status, peer-review status of load-bearing preprints, venue/edition facts; re-check before any novelty verdict or write-up.
- **[SOURCES.md](SOURCES.md)** — provenance: every [Sn] resolves here with its verbatim quote and scrutiny verdict.

## Candidate lane  ⚠️ (expert to resolve — NOT verified)
- ⚠️ **LogiConBench** (OpenReview forum id ULEHJkolxB; reportedly ICLR 2026, controllable-depth reasoning graphs) — PDF returned HTTP 403 during mining; lead only. If confirmed, it further crowds lane 3. Confirm via OpenReview.
- ⚠️ **FRIT** (intervention-training for faithfulness) and **SATBench** (EMNLP 2025) — named by the tool-equipped baseline, not independently fetched; their lanes are confirmed by [S21][S19] regardless. Fetch abstracts before citing either.
- ⚠️ **Driftbench** — real: 2,183 NL/Lean-4 ["pairs with controlled drift labels across six subfields of mathlib4"](https://arxiv.org/abs/2606.16541), released by [S7], NOT by the formalization-gaming paper a search snippet attributed it to; [S7] is a quality-flagged single preprint, so treat as a lead until corroborated.
- ⚠️ **NeSy 2026 logistics** (Lisbon, Sep 1–4; PMLR; OpenReview, 10pg full / 5pg short; X-NeSy special issue) — from a live baseline fetch whose quote was not retained. Confirm at nesyconf.org before venue planning.
```

### [3] SYSTEM-USER prompt · 2026-09-24 11:05:03 UTC

````
<validation-feedback>
Attempt 1 failed validation.

The output file `./.terminal_claude_agent_struct_out.json` does not exist yet.



---

Output the result as JSON to: `./.terminal_claude_agent_struct_out.json`

JSON Schema:
```json
{
  "description": "Plan for an EXPERIMENT artifact.",
  "properties": {
    "domain_practice": {
      "default": "",
      "description": "How a study of exactly this kind is actually built and run in THIS field: the baselines every comparable paper reports, the datasets/corpora/cohorts/case sets that are standard (and the ones known to be saturated or unrepresentative), what is held constant, the sample sizes and repeats below which nobody believes a result, and the measures and reporting conventions a reader expects. Name what you read.",
      "title": "Domain Practice",
      "type": "string"
    },
    "practice_alignment": {
      "default": "",
      "description": "This plan checked point by point against that practice: where it meets the field's norms and where it departs from them, with why each departure is justified here and what it costs the result's credibility.",
      "title": "Practice Alignment",
      "type": "string"
    },
    "builds_on": {
      "default": "",
      "description": "What this plan REUSES from earlier rounds, named concretely: which artifacts, files, datasets, checkpoints, fitted models or negative findings, and where the executor picks each one up. If the plan starts a fresh line instead, say so here and give the reason it is allowed to \u2014 the iteration is a widen, or the prior line is a settled negative.",
      "title": "Builds On",
      "type": "string"
    },
    "title": {
      "description": "Plan title in plain, everyday language \u2014 short and jargon-free so a non-expert grasps it at a glance and it fits the run visualizations. Aim for about 4-8 words (~40 characters).",
      "title": "Title",
      "type": "string"
    },
    "summary": {
      "default": "",
      "description": "Brief summary",
      "title": "Summary",
      "type": "string"
    },
    "runpod_compute_profile": {
      "anyOf": [
        {
          "type": "string"
        },
        {
          "type": "null"
        }
      ],
      "default": "cpu_basic",
      "description": "Compute tier for execution \u2014 pick from the available profiles list (e.g., 'gpu_basic', 'gpu_plus', 'cpu_plus', 'cpu_basic'). Only used in RunPod mode.",
      "title": "Runpod Compute Profile"
    },
    "implementation_pseudocode": {
      "description": "High-level pseudocode for the experiment implementation",
      "title": "Implementation Pseudocode",
      "type": "string"
    },
    "fallback_plan": {
      "description": "What to do if the primary approach fails - alternative methods, simplified versions",
      "title": "Fallback Plan",
      "type": "string"
    },
    "testing_plan": {
      "description": "How to validate the experiment works: start with small/fast tests, look for confirmation signals before running full-scale experiments",
      "title": "Testing Plan",
      "type": "string"
    }
  },
  "required": [
    "title",
    "implementation_pseudocode",
    "fallback_plan",
    "testing_plan"
  ],
  "title": "ExperimentPlan",
  "type": "object"
}
```

IMPORTANT: this task is NOT complete until `./.terminal_claude_agent_struct_out.json` exists and contains JSON matching the schema above.

Produce `./.terminal_claude_agent_struct_out.json` again so it contains corrected JSON that matches the schema. Do not invent new fields.
</validation-feedback>
````
