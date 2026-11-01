# Demo: spoken script, then presenter notes

**The script below is what you say.** It is word-counted for a three-minute slot. Every number
in it is one a listener can hold. **All other numbers live in the presenter notes** — use them to
answer questions, not to fill the three minutes.

Supersedes `archive/demo-narrative-2026-10-31-refusal-led.md`.

---

# PART 1 — THE SPOKEN SCRIPT (452 words)

### Open · on the viewer

Designing an organism end to end forces a decision at every scale — and shows which ones the
evidence can't yet support.

This is our flying fish, version three. The ray counts aren't artistic: fifteen pectoral, thirteen
dorsal, ten anal, read out of an FAO species sheet that we reuse as a record, not a citation. The
builder **refuses** any candidate breaking that sheet's rule for where the pelvic fins sit — the
first decision, made by the sheet.

### Drill · down through it

Zoom into one scale. A published model of Erk trigger waves driving bone growth in a regenerating
zebrafish scale — every parameter from the authors' own table.

Down again, to cells. BETSE, the real package, on a **generic** patch — not a fish fin, and we
don't claim it is. Raise potassium permeability in two cells and they drop about five millivolts;
so do their neighbours. Block the gap junctions and those two drop four times further while the
neighbours barely move. That's the coupling, shown by removing it.

Down again, to metabolism. A genome-scale zebrafish model ships with no medium, so we **assumed**
one. Growth came out zero — the biomass pool needed a vitamin E catabolite we hadn't supplied.
We added it; it solved.

Then we swept oxygen and growth barely moved. Not biology: under our assumed medium the model was
**making its own oxygen**, one reaction running backwards beside an uncapped vitamin. Block it and
growth collapses. That measured our medium, not a fish.

### The edge · where it stops

Now the interesting part. We built the adapter carrying flow pressure onto a fin ray. It checks
out exactly — force conservation exact, the disabled-load control exactly zero.

And it will not run. Fins are half a millimetre thick, and on our finest completed grid a fin
spans **four tenths of one cell**. The global grid doesn't resolve fin thickness anywhere we've
looked, so the contract refuses those samples rather than quietly loading them.

Underneath sits a second gap: we have not established a sourced stiffness profile for a real
flying-fish fin ray. That one's a wet lab.

**Two gaps with numbers on them, found by connecting a flow solver to a beam.** That's what the
design is for.

### Close · the commons

Here's the loop closing. One exact stiffness claim, read live through the MCP, fed into two
separate leased computations. An independent reviewer re-derived it by hand, wrote their own
solver, matched to ten decimals — then **disputed the evidence anyway**: reproducing mathematics
isn't empirical relevance, and nobody has measured a real fin. Scoped reuse, honest contest.

One honest result. We preregistered a comparison of a single analyst against collaborating agents.
**Every arm scored full marks**, so **this task did not distinguish them.** That's a null about
our benchmark, not evidence that agents coordinate better.

---

**Pacing.** 452 words: **3:14 at 140 wpm, 3:01 at 150**. If the slot is hard three minutes, either
speak at 150 or **drop the oxygen paragraph** (−58 words → 2:47 at 140). Cut the whole metabolism
beat for 2:20, and the scale beat too for 1:55. **Never cut the edge section** — it is the thesis.

---

# PART 2 — PRESENTER NOTES

Numbers, sources and exact limits. Reach for these in Q&A.

## Fish (v3)

- **15 pectoral rays** (range 14–17, only the first unbranched), **13 dorsal** (12–14), **10 anal**
  (8–11); anal fin originates under the **6th dorsal ray**; **28.5 predorsal scales** → 2.38 mm
  spacing → **48 rows, 1,302 scales**; eye diameter = head length / 2.95.
- Source: Parin 2002 after Gibbs 1978, FAO Western Central Atlantic guide vol. 2, read as full
  text, sha256 `f1a35c86…`. Caudal lobes solved to **Fish 1990**'s hypocaudal share **0.6263**,
  reproduced exactly. Daane 2021 gives the stiffened, elongated ventral lobe.
- Refusal rule: FAO requires the pelvic insertion nearer the opercle than the caudal base.
- **Assumed, not sourced:** camber and dihedral. Park & Choi 2010 was unreachable through the
  page, the PDF and the read proxy.
- `docs/fish3d-v3.md`, `engineering/fishv3/`, 13 tests, three candidates.

## Scale growth

- Hayden, Poss, De Simone, Di Talia, *Biophys J* 2021, **read in full**. Erk / activator /
  inhibitor system; every parameter from their Table 1, matching the authors' published MATLAB
  (read, not copied; GPL).
- 520 µm disc, 5 µm grid, 0.01 h step. 7 tests.
- **Limit:** reproduces 5 of the source's bands; **misses** the rise and the synchrony–growth
  impairment. Retained with the miss recorded.

## Cells — BETSE

- **Label it a generic patch.** BETSE 1.5.0 (wheel sha256 `17a11601…`), called not copied. 80 µm
  square, hexagonal, **66 cells, 364 membranes**, BETSE default parameters throughout. **It is not
  fish tissue and fin applicability is an explicit unknown.**
- K⁺ permeability ×5 in 2 cells: targeted **−4.67 mV**, untargeted **−2.62 mV**.
- With gap junctions blocked: targeted **−19.8 mV**, others **−0.16 mV**.
- Block-only control: mean open fraction **0.967 → ~1e-11**, Vm moves ≤0.16 mV, because a
  homogeneous patch has almost no voltage differences to equalise.
- **Limit:** resting Vm ≈ −23.5 mV is a property of BETSE's defaults. A leak-only GHK reference
  gives +0.7 mV and the 24 mV difference is **not decomposed**.

## Metabolism

- Zebrafish-GEM (Wang 2021 PNAS, CC-BY-4.0), commit `846f0b7b3…`. **Measured from the file:**
  12,833 reactions, 8,435 metabolites, 2,709 genes, 1,658 exchanges.
- The SBML defines **no medium**; all exchanges open at ±1000 gives biomass 4.26, which is not a
  medium.
- **Call it an ASSUMED nutrient medium.** An allowlist of 58 basic nutrients → **biomass 0**. The
  cause: the biomass pool's cofactor-and-vitamin term needs vitamin E catabolites reachable only
  from **gamma-tocopherol**; the allowlist supplied alpha. Adding gamma-tocopherol gives **0.265**
  at O₂ uptake 0 and **0.291** at 20.
- **THE OXYGEN SWEEP IS NOT OXYGEN DEPENDENCE and must never be presented as it.** Under the
  assumed, **uptake-uncapped** medium the model makes its own O₂ at +1000 through **MAR04071**,
  pyridoxine oxidase running in reverse beside uncapped vitamin B6 exchanges.
  - At **zero external O₂** it still grows at **0.265**; **block MAR04071 and it does not grow —
    3e-16**.
  - At O₂ uptake 20: **0.291 free versus 0.097 blocked**.
  - A **model-constraint diagnosis**, found by checking. Blocking MAR04071 is **not** biology.
- **Must not say:** that this measures oxygen dependence or fish oxygen use; that growth values are
  physiological (0.29 is a model objective flux); that the model is fin- or tissue-specific.
- **The glucose cap of 10 and every other uptake bound are uncalibrated assumptions**, as are the
  medium composition and the flux unit (mmol/gDW/h — assumed; the SBML does not declare it).
  Absolute growth values mean nothing physiologically.
- No flux table is stored at other O₂ conditions. **No new sweep until nutrient bounds have
  evidence.**
- `work/zebrafish-metabolism` @ `ee74e2d`; `o2_source_diagnostic.json`, `metabolism_results.json`.
- Controls: all uptake closed → 0; glucose alone → 0; max |S·v| ≤ 1e-10; no energy-generating
  cycle with uptake closed.

## The fin coupling — say the assumptions with the number

- Adapter: pressure jump → line load → resultant and root moment → deflection through the existing
  `fin_mechanics` FEM. **No second beam solver was written.**
- Exact checks: uniform and linear pressure against hand closed forms, **grid order 2**, force
  conservation exact, **disabled-load control exactly 0**, deflection scaling exactly **1/EI**.
- **Completed global GPU cases, and what a fin spans in each** (`summary-gpu-v1.json`). Fin plates
  are **0.5 mm**:

  | case | L | fin thickness, cells | shell, mm |
  |---|---|---|---|
  | `gpu_fish_L64_Re200` | 64 | **0.139** | 13.45 |
  | `gpu_fish_L128_Re200` | 128 | **0.277** | 6.73 |
  | `gpu_fish_L128_Re1000` | 128 | **0.277** | 6.73 |
  | `gpu_fish_L192_Re1000` | 192 | **0.416** | 4.48 |

  **A fin is under half a cell at every resolution completed, including the finest.** That is the
  statement to make: *the current global grid does not resolve fin thickness.* Do not compare
  against the older L 32 case, and **do not quote a "times finer" factor** — the global grids have
  moved and the ratio goes stale.
- **The 923-cell figure is arithmetic**, not a demonstrated hardware limit: it is what L must reach
  for a 0.5 mm plate to span 2 cells at uniform spacing. We have not run it and have not
  established that one H100 cannot. Give it only if asked, as arithmetic.
- Samples carry `resolved: false` and the contract refuses them — `MEMBER_UNRESOLVED`.
- **Say "we have not established a sourced flying-fish EI profile"** — not "nobody has measured
  it". We have not searched the literature systematically enough to claim an absence.
- **Grid-convergence pairs, stated exactly:** Re 200, L64→L128, **13.2% apart, grid rule NOT met**.
  Re 1000, L128→L192, **9.8% apart, grid rule met**. **Neither supports a physical force claim** —
  the C1 sphere reference gate **failed** and the fins are sub-grid, and the summary records
  `physical_force_claim: false` for both. Re_L 200 is 13 mm/s in air; intended glide regimes are
  assumed and unsourced, a gap factor of roughly 760-1520.
- `docs/coupled-mechanics.md`, `docs/cfd3d.md`, `artifacts/coupled-mechanics/result.json`.

## Print and design history

- **Six solid props in two versioned sets**, each built from a design JSON with its own display
  stand. Each is an **engineered illustrative form** — not an ancestor, not a viable organism, not
  a demonstrated evolutionary path, not flight-tested. **Fins are thickened so they can print.**
- **Nothing has been sliced, loaded into PreForm or printed. Printer and resin are unknown.**
  Never say "printed forms".
- Candidate history, v1 → v2: **A, precursor-inspired short fin — `unsat`** on the wing-loading
  bound (1891 N/m² against 208.9), retained; **B, two-wing glider** and **C, four-wing glider**
  both feasible and independently verified.
- **A–C have no glide simulation.** The build attaches a glide receipt only when one names the
  candidate's sha256.
- **Two opt-in constraints are deliberately not taken**, and the reason is recorded: Fish's
  aspect-ratio range is for individual pectoral fins and its mapping onto b²/S is unresolved; and
  the 16–20 m/s taxi speed **is not a flight-speed envelope**.
- **New requirement: a strong-fin, sling-launched glider.** It is a design requirement.
  **No prototype has flown, and no flight has been demonstrated.** If asked what would settle it,
  the answer is a launch and a measurement, neither of which exists.

## The commons

- **Repository public** as of 2026-10-31: `github.com/kganjam/delphi-frontier`. Verified
  anonymously — API returns `"private": false`; raw `README.md` is HTTP 200 while a nonexistent
  path 404s.
- Live release **`c1ad527`**: **13 public web checks and 35 MCP checks, 0 failures**, receipts
  `deploy/receipts/rayfan-public-live-check.json` and `rayfan-mcp-live-check.json`, both stamped
  2026-10-31T23:14:54Z. The MCP suite's own scope: *"public client connectivity, search, schema
  discovery and anonymous write denial; not scientific acceptance."*
- **19 tools** — the manifest splits them **16 `read`, 3 `write`**; `frontier_design_context` is
  the newest and is a read. Anonymous reads and bounded calculations work; a well-formed anonymous
  write returns `unauthorized: Authenticated operator token required`.
- Measured 16:15 PDT: **1,315 claim versions**, 1,190 with an upstream Delphi id, **543 artifact
  declarations**. **Re-run the catalogue call before the room** — these move.
- Compute, **snapshot at 16:13 PDT, not a total**: 52 team jobs (37 current queue + 15 prior team
  and setup), 30 unattributed, 2 of ours running + 1 pulling. Relayed from root's correction, not
  re-derived here; infra is still reconciling receipts. **Quote the snapshot time or don't quote
  it.** Spend unknown — no billing meter.

## The collective result

- v3 completed: **27 requests valid**; every answer and every condition-by-repeat aggregate
  **16/16**; all three condition means identical. Conditions: one serial analyst, isolated
  specialists, specialists sharing pinned artifacts.
- **What this shows: the task did not distinguish the arms.** All three hit the rubric's maximum.
  The packet stated the source fit, the stiffness range and the measurement method, so the task was
  answer-explicit — that is the *likely* reason, and the scores alone do not prove the ceiling was
  structural. **Do not say "no room to fail"**; say the task did not separate the conditions.
- Communication treatment **did execute**: 9 pinned artifacts to the serial analyst, 9 peer
  artifacts to collaborators, none to the isolated arm.
- **Do not pool v2 with v3.** v2: 27 HTTP 200, all truncated at `MAX_TOKENS`, scored zero, 49,626
  tokens. v3: 53,802. Total known Google API usage **103,459 tokens over 57 requests**.
- Three **observational** coordination cases exist. The source document states they provide **no
  controlled counterfactual** and must not count as evidence of advantage. We don't count them.
- `results/capability-agency/results-card.md`, commit `92c86683`.

## The claim-reuse loop — the strongest reuse evidence, inspected

**The loop.** One exact public Claim — `node-a/Claim/eng-finmech-claim-ei-crit@4998ef85…`,
EI_crit = **1323/2048000** exactly — was **read before the run** and consumed by **two distinct
leased computations** through the live MCP, at **0.9× and 1.1×** the threshold, with real
proposals, coordinator readiness, leases, running states, proposed Evidence and submitted Actions.
The solver's EI is parsed from the Claim at runtime; **there is no hardcoded fallback stiffness.**
Protocol committed in `be4dfc6` **before** any candidate run.

| candidate | consumed EI | tip/span | max slope | declared linear-model domain |
|---|---|---|---|---|
| 0.9× threshold | 11907/20480000 | 0.111111111158 | 0.148148148207 | **invalid** — retained counterexample |
| 1.1× threshold | 14553/20480000 | 0.090909090883 | 0.121212121180 | inside declared limits |

**The independent review** (`docs/reviews/fin-reuse-review-findings.md`; actor
`fin-reuse-reviewer`, **criteria committed before any author output** at `11fa785`, author
checkout read-only):

- Re-derived by hand in exact fractions: EI_tip = **1323/2048000 — the Claim, exactly**
- Closed form: below → tip/L = **1/9**, slope 4/27, invalid at the 1/10 tip limit; above →
  **1/11**, slope 4/33, valid. Author's values agree to **4.2e-10**
- **Their own Hermite-cubic FEM**, not the author's code, 16/32/64 elements: within **5.1e-10**
- Replay of author code: `profile.csv` **byte-identical**, tip difference **0.0**
- Controls: zero load → exactly 0.0 m; L³ mutant rejected at relative error 5.67; **five altered
  Claim records each refused** by the record digest check

**And the Evidence is still disputed.** Four findings, none changing the numbers:
1. Inherited limitation text copied from the source Claim, wrong in the conservative direction
2. **"Mesh convergence" is round-off, not convergence** — for constant EI under uniform load the
   Hermite element is exact at the nodes, and the author's error *grows* with refinement
   (1.4e-12 → 5.7e-11 → 4.2e-10)
3. Mutation controls are caught by the **digest** check, not the scope gate the Action names
4. The 0.9/1.1 margins live only inside a cache-key digest in the Action payloads

**What it does not support, in the reviewer's words:** anything about a fish, a measured fin-ray
stiffness or load, or fluid-structure behaviour. **No independent non-computational replication
and no empirical data exist for this scope.** The reviewer is an AI agent process — **not a
laboratory, not a human, no biological acceptance.**

**Say this is scoped reuse and honest contest. It is not evidence that agents coordinate better.**

## The Project — a second persisted example, inspected

- **Project `project-flying-fish-mission`, version `1177c609…`**, predecessor `a4953d50…`.
  **22 members**, **13 preserved** from the predecessor, 4 old-version annotations.
  `imports/2026-10-31-curated-v2/project-receipt.json`, recorded 2026-10-31T23:39:09Z.
- **`local_status: "proposed"` — not accepted.** Its own scope line: *"additive declared
  membership; no causal bridge or biological review."* **Say proposed.**
- Curated import: **37 verified, 0 problems**, all 37 `imported_unreviewed`
  (`imports/2026-10-31-curated-v2/verification.json`). Store at that moment: **3,882 versions,
  0 forks**, 1,943 events, 357 write receipts in 24h.
- A failed attempt is retained in the receipt: a record-to-draft conversion carried
  `schema_version` and was **rejected by Draft before any Project write**, then corrected.
- **Do not claim the RD execution graph is persisted** — I have not read its DB ref. The Project
  above is the example to use.

## The diffusion pilot — current status

- The first CUDA control **failed** and stopped before training: network CPU/GPU parity
  **0.001191914** against a **0.001** tolerance.
- A paired diagnosis in the **same allocation** confirmed the TF32 hypothesis: default backend
  reproduces **0.001191914** (fails); **explicit IEEE FP32 gives 2.265e-06 (passes)** — the same
  unchanged 0.001 tolerance. Solver parity 5.95e-14 in both.
- **Training then ran to 30,000 steps, and the primary run FAILED.** The original **1800-second**
  inner timeout fired after the checkpoint was written and before `evaluate()` returned.
- **The outer flag lies and the receipt says so.** `outer_timed_out_flag: false`, because the inner
  subprocess raised `TimeoutExpired` and the wrapper exited 1 normally. Read the failure type.
- Checkpoint independently audited: sha256 `1a0a185c…`, 5,421,109 bytes, 30,000 steps, 16,800
  training rows, **84 weight tensors, 1,348,290 parameters, all finite**. 301 logged rows; loss
  **1.2328 → 0.008265** over **1544.9 s**; 1,831 telemetry samples averaging **97.66%** GPU
  utilisation.
- **That loss curve is not a result, and the receipt says so:** *"Observed training loss only, not
  held-out performance or biological validity."* The collection audit is **`complete: false`** —
  **`evaluation.json` and `examples.npz` are missing.** No held-out comparison, no baseline, no
  shuffled-condition null, therefore **no model-quality claim.**
- A **separately frozen evaluation-only recovery** with unchanged weights is **awaiting publication
  and controls**. Not a retry. **Do not say a job is currently running.**
- Nothing was relaxed: source, config, architecture, optimizer, dataset, splits and tolerance all
  unchanged; both failures retained.
- `results/infra/diffusion-v2/partial-primary.json`, `partial-checkpoint-audit.json`,
  `backend-diagnosis.json`; job `aijob-e00qazx6sby3vav47b`; infra commit `118fe2b`.

## Agents checking each other

- A claim that the textbook Turing criterion is reliable above ~1.5 critical wavelengths was
  falsified by a probe committed **before** its output existed. Error is **windowed**: 0% at
  half-integer multiples of λc, **6.22%** at 1.25 λc, **0.58%** at 4.25 λc. Withdrawn in place,
  historical table kept. The probe's own control failed (89.53% vs a declared 90%) and shipped at
  exit 1 with the threshold untouched.
- A frozen CFD packet failed its gate — 12 STL hashes matched, the float64 candidate hash did not.
  An unchanged retry was refused; CPU-only diagnosis isolated **NumPy AVX-512 dispatch drifting 3
  fields by 1–2 ULP** while float32 STLs stayed identical. A declared geometry-only dispatch
  setting restored byte-identical output.

## Receipt paths that landed late (main `8790824`)

`deploy/receipts/science-integration-20261031.json`, recorded 2026-10-31T23:20:18Z against tested
base `e8f53704`, carries **7 checks**. I read the receipt; I have **not** opened the individual
artifacts under it, so treat the per-item science as recorded-by-that-check, not inspected by me:

- Molecular returned data and controls — `pytest tests/test_molecular.py -q`, **16 passed**
- Portable packet RD software and genomics — **41 passed**; genomics alone **37 passed**
- Molecular manifest — **120 paths with matching byte counts and SHA256, root recomputed**
- **Pilot independent reconstruction — 27 distinct calls, 27 JSON/text/hash matches, all 27 scored
  16/16, 53,802 provider tokens, 18 prior-artifact references**
- Ruff on changed source — passed after 15 style fixes, scientific artifacts unchanged
- Incremental credential scan — 19 commits, 5.84 MB, **0 findings** (gitleaks 8.30.1)
- **Retained failure, kept in the receipt:** the first molecular collection stopped for missing
  OpenMM in the root venv; re-run on the isolated dependency path

### The three that had no path — now inspected, with exact paths

**Perturbation** — `results/infra/perturb-completion-report.json`. **Read directly.**
**357** completions requested, **48** repeats, **405** rows returned. Omitted, divergent,
pattern-flag-change, patterned-mode-change and settled-flag-change lists are **all empty**. Relative
initial-state noise **1e-10**; repeat max absolute difference **1.318e-14** against a 1e-06
tolerance, **0 repeat failures**. `biological_validity: null` — the file says so itself. Scope is
the **frozen model envelope**, not biology.

**OpenFold2** — `artifacts/bio-services/kcnj13_openfold2/metrics.json` and `result.json`.
**Read directly.** 362 residues, chain A, `sequence_exact_match: true`, operation
`op-5ba1d104dbbcd293`. `epistemic_status: "PREDICTED; computational model output, not observed
structure or function"`. **Better than quoting a mean pLDDT: 50.6% of residues are below pLDDT 50,
and only 18.2% reach 70.** Its own limits list: dummy single-sequence MSA, monomer only, no
membrane or tetramer or ligands; confidence and PAE are **model-internal metrics, not calibrated
probability**; it establishes **no** conductance, gating or phenotype; the provider reported
upstream-source-not-nim and returned no hardware allocation.

**OpenMM trajectory** — under `artifacts/molecular/` (CPU controls, CPU trajectory, CUDA v2/v3
parity, job and production receipts, return verification). **Not opened by me.** Say "recorded at",
not "verified".

## If a judge interrupts

- **Does it fly?** No. Print-ready meshes exist; nothing printed, nothing flown.
- **Is the collective better?** Not established, and we ran the experiment. 16/16 in every arm, so
  the task did not distinguish them. Independently reconstructed: 27 distinct calls, 27 JSON/text/
  hash matches, all 27 scored 16/16, 53,802 provider tokens.
- **Novel architecture?** No. Prove2Me, ScienceClaw, Infinite, ASK; and Comlekoglu, Bastek and
  GenCFD for the diffusion roadmap.
- **Yours vs reused?** Sources and software are published and credited; today's work is the
  builds, solves, checks and integrations, each with a dated receipt. A commit date is when an
  artifact entered the repository, not when its content was made.
- **Believe your counts?** Don't — run the catalogue call yourself.
