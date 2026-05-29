# deepswe-run worklog

Newest first. Development trail for the DeepSWE audit + the staged harness-richness
experiment. A scored tag opens its own worklog on freeze, per PREREGISTRATION §3/§10.

## 2026-05-27 (later still) — corpus fan-out: feature-type build bias + KNOWN_BAD; encoded into skills

Fan-out over 13 stratified tasks (Py/TS/Go/Rust/JS) to generalize the httpx anchor. Outer-loop role:
read the canonical tests + gold to *teach the skills* (the inner loop stays blind). codex-filtered the
generalization before encoding (claude generates, codex filters).

- **The build bias is conditional on FEATURE TYPE, not a flat "overbuild."** H0 (closed negatives →
  overbuild free) held for 9 additive features, REFUTED for 4 subtractive/transform/filter/selector
  ones (kysely, bandit-nosec, oxvg, testem). My earlier flat "bias to overbuild" patch was wrong; codex
  named the sound invariant — **monotonicity against the grader's observable contract**. Encoded
  `implement-spec` as a 4-branch decision tree (preserve-existing / narrow-the-transform / complete-the-
  isolated-surface / never-cross-a-hard-boundary), and `design-doc` now emits a **Feature-type** line
  that selects the branch.
- **Spec-vs-test gap is pervasive but is UNDERSPECIFICATION, not contradiction** — exact default
  spellings, exact metrics, exact formatting. The residue: un-encodable from spec, winnable via
  completeness + judgment, not via the proxy gate.
- **KNOWN_BAD (new no-go class):** spec genuinely *contradicts* test → unwinnable under binary+no-peek →
  REJECT like the gold-defectives (outer-loop classification; gate on ruling out a narrower reading).
  `dsr` now flags it at the `task` precondition. **Set empty** — the dasel nested-`li` candidate was
  **REFUTED on direct inspection** (PRD "same-type siblings" + "block closes p", read precisely, yield
  the test's tree). The B3-go subagent confabulated the contradiction; the verify step caught it before
  it reached the published audit post. Meta-lesson banked in `build-tools-lessons.md`.

## 2026-05-27 (later) — feature pipeline: spec-only proxy method + the `dsr` CLI shell

**Session goal reframed: lessons are the deliverable, the benchmark artifact is secondary.**
The point of this work is to learn how a gateless (hidden-grader) feature pipeline behaves, and to
extract transferable method — not to post a number.

**The crystallized method (the no-peek encoding loop).** The no-cheating rule (PREREGISTRATION §9)
forbids looking at the hidden tests until after we are done. So the agent **iterates off a proxy
built from the spec alone**; the hidden grader is consulted only *after* a run, as a retrospective
oracle. The lesson lives in the **proxy-vs-grade gap**: the behavioral distinctions a spec-only proxy
misses are exactly what the next iteration should encode. This is the Encoding-Expertise trilogy's
loop (move every stable distinction out of the prompt into a deterministic tool; the LLM nucleus
shrinks to the residue) applied to feature tasks, with the hidden test as the after-the-fact teacher,
never a runtime input.

**Pipeline grew a stage:** `design-doc → build-tools → implement-spec → verify-spec`. `build-tools`
is a skill (not yet written): from the design doc's acceptance criteria (spec-only), it generates the
deterministic CLI probes / dev-tools and **emits them as artifacts** (`$PROXY_GATE_DIR` + a manifest)
that implement-spec iterates against and verify-spec checks. It is the trilogy's "CLI tool / live
state" stratum promoted to a first-class step — the place where stable distinctions leave the prompt.

**Confident skill fixes applied ahead of the build** (review of the 3 forked skills):
- proxy-gate **persistence** seam closed — implement-spec leaves the gate at a fixed scratch path for
  verify-spec instead of deleting it; the driver strips it from the captured diff (chain of custody).
- regression **baseline** is now a captured set (`$BASELINE_FAILS`), not the false "passed by
  definition" assumption — mirrors the grader's own `test.sh base` mode.
- **REJECTED** added as a distinct third outcome (malformed/un-gradeable/known-defective → human bin,
  excluded from resolve/fail stats), in verify-spec and design-doc. Maps to the identity precondition.
- **artifact-first** decision: verify-spec writes `$VERDICT_FILE`; stdout `VERDICT:`/`RE-ENTER:` is a
  shim fallback (Make-No-Mistakes trick 1).
- dropped the dangling `PARTIAL` verdict.
The 7 actor-side tricks (PATH shim, budget shares, jidoka, supervisor paradox, inbox pause, interface
accounting, compliance counters) are the **driver's** spec, not skill prose — captured for the build.

**Skills now live in the repo and resolve globally** — `skills/{design-doc,implement-spec,verify-spec}`
symlinked into `~/.claude/skills/`; they appear in the Skill list.

**Sample task chosen: `httpx-streaming-json-iteration`** (pure-Python, well-known lib, a richly-edge-
cased PRD — 36 hidden tests across media-type classification / charset / JSON encoding detection /
document / NDJSON / json-seq framing / stream-consumption). Ideal stress test for "exhaustive
acceptance criteria" and a clean proxy-vs-grade measurement.

**`dsr` CLI shell built + verified** (`harness/feature/dsr.py`, stdlib-only). Subcommands map to the
strata: `task` (identity precondition — gradeable? defect-flagged? prints PRD), `box` (live state —
run a cmd in the task container at /app), `grade` (the **private oracle** — applies the hidden
test.patch, runs `test.sh base`+`new`, prints reward + readable pass/fail), `verdict` (legal-moves
postcondition — validates the `$VERDICT_FILE` enum). Verified on the pulled public-ECR image: empty
container → base pass / new FAIL / reward 0; **gold solution applied → base pass + 108 new pass →
reward 1.** The local loop and the unmodified-verifier grading path are de-risked.

**Oracle quarantine.** `test_json_stream.py` was extracted to `/tmp` only to *count/cluster* behaviors
for method design; it is retro/oracle material and must NOT contaminate spec-only proxy construction.

**The central finding, stated up front: a spec-only proxy cannot reproduce the hidden grader (~0%),
by construction.** The httpx hidden test pins down behaviors the PRD never states (exact json-seq
trailing-empty-record error semantics, RS-after-optional-whitespace, BOM-inside-array-is-error). No
no-peek agent reconstructs that from the spec. So the **proxy-vs-grade gap is the measurement, not a
defect to close** — and it makes the necessary-not-sufficient stance the only honest one. This is also
a benchmark critique: a gateless feature bench whose grader tests behaviors the spec leaves unstated
is partly testing mind-reading, not engineering (ties to the audit thesis).

**Expected score: mid-80s%, optimistic — and that does NOT contradict the ~0% test-reproduction.**
Two different measurements: *reproducing the hidden test* from spec ≈ 0%; *passing the hidden grader*
≈ mid-80s. The bridge is the **LLM residue**: a competent PRD read implements most behaviors the way
the reference did, so most hidden tests pass without the proxy ever having encoded them. So
grade-green ≈ (necessary proxy bar) + (residue judgment); the mid-80s implies judgment carries most of
the gap the proxy provably can't. The ~15% misses are spec-underspecified behaviors where a reasonable
reading diverges from the grader's. Decomposing grade-green into encoded-bar vs residue is the headline
measurement.

**Proxy-gate semantics nailed down (necessary, not sufficient, by constraints).** The proxy gate is a
*sound lower bound*: encode only high-certainty constraints so fail-proxy ⟹ fail-grade; pass-proxy
never certifies grade-green. Ambiguous behaviors go to design-doc's alternatives and the LLM residue,
never into the gate (a wrong test that fails a correct implementation is worse than a missing one).

**Deterministic post-verify gate built (`dsr gate`).** Takes the stop-decision away from verify-spec's
prose verdict (Make-No-Mistakes poka-yoke): a pure CLI recompute over build-tools' manifest — proxy
gate exit code + regression diff vs `$BASELINE_FAILS` + verdict-enum validation → one boolean,
`PROXY-GREEN` or not. Certifies the necessary bar, never a grade pass.

**`build-tools` skill written** (`skills/build-tools/`), the new stage between design-doc and
implement-spec. Emits three artifacts at `$PROXY_GATE_DIR`: the proxy gate (certain criteria as tests),
dev probes (standalone CLI ground-truth oracles for load-bearing distinctions, NOT the implementation),
and `manifest.json` (the `dsr gate` contract). Spec-only; codex sanity pass guards soundness, not
coverage.

**The inner loop = build-tools → apply golden patch → verify-spec (the economy of search).** The
golden patch (provided per task) is a *known-correct implementer*, so substituting it for `implement-spec`
removes the expensive implementation search (~840 LOC, codex volleys, 8 iterations) from the
measurement. What's left isolates the two cheap, high-leverage skills:
- **build-tools integrity** — SOUND (gold passes our proxy gate; else over-specified) + coverage (the
  `compare` figure vs canonical).
- **verify-spec integrity** — on a known-good impl it must emit `RESOLVED (proxy)`; a mis-verdict is a
  verify-spec bug, surfaced with zero dependence on implement-spec.
`implement-spec` is deliberately OUT of the inner loop. We learn where it's informative and don't pay
the search to rediscover what the free golden-patch oracle already states.

**Abduction is the measurement (june.kim/abduction).** `dsr compare` is bi-abduction over two test
suites: before = our spec-only proxy gate, after = the canonical hidden tests; XOR → *figure* (missed
+ over-specified behaviors, incorrectness polarity) vs *ground* (both cover). The figure is appended
to `harness/feature/build-tools-lessons.md`. **Inner loop executes + abducts; outer loop (the model)
reads the lessons log and patches the skills** (Supervisor/Asymptote shape).

**Controlled experiment: one repo, varying patches (`dsr vary`).** Hold httpx constant, swap the
patch — gold (both pass: soundness), mutants (canonical catches; does the proxy?), base (both fail:
liveness). Each patch is an abduction perturbation: apply → run our proxy gate AND the canonical gate
→ report agreement. Disagreement is the figure — canonical-FAIL/proxy-PASS = coverage gap;
canonical-PASS/proxy-FAIL = over-specified. Measures the proxy gate's *discriminating power*, not just
name coverage. One warm container, many patches = the cheap iteration the economy of search buys.
Verified: gold → canonical pass through the `vary` path.

**`dsr` shell complete (10 cmds, all verified to parse/run):** `task` `box` `base` `grade` `gate`
`verdict` `isolate` `compare` `inner` `vary`. Day-0 `compare` on httpx printed the expected all-MISSED figure
(36 canonical behaviors, 0 proxy) and logged the first lesson. Runbook at `harness/feature/RUNBOOK.md`;
`box-sh` container helper wired; baseline captured (`test_write_timeout[trio]` is the lone pre-existing
red → `$BASELINE_FAILS`).

**Next:** (1) `/design-doc` + `/build-tools` on httpx (spec only); (2) `dsr inner` →
build-tools/verify-spec integrity + abduction figure; (3) read `build-tools-lessons.md`, abduce the
best-explanation skill patches (outer loop); (4) repeat. `implement-spec` + full `dsr grade` come later,
once build-tools/verify-spec are sound.

## 2026-05-27 (session close) — audit frozen + published; feature-task skill fork designed

**Audit complete and frozen.** Gold-patch defect audit ran on all 113 (oracle, $0 model, spot
m7i.8xlarge, <$1): **109 pass / 4 fail** (`langchain-request-coalescing`,
`narwhals-rolling-window-suite`, `prometheus-transactional-reload-status`, `skrub-duration-encoding`),
each confirmed failing in isolation (pass-2 sequential), cause unresolved (the maintainer's job, not
the auditor's). Repo pushed PUBLIC to **github.com/kimjune01/deepswe-run**, default branch `main`,
frozen at annotated tag **`audit-v1`** (commit a12022b). Ledger in `results/`, harness in `harness/`.

**Blog post drafted** at june.kim `_drafts/2026-05-27-auditing-deepswe.md` ("Auditing DeepSWE",
post-wide). Copyedited (humanize/tighten/readability/flavor/codex/sharpen) + two codex sniffs. Final
shape: neutral audit body (no prior) + a fenced **second reader's note** scoped to *methodology, not
findings*, landing on the thesis *"it is fine to ship unfinished work, but not to call it finished
when it is not."* Hint, don't preach: "ablation" and "confabulation" each used once to educate.
Attestation pins deep-swe @ `2f0f4125` and our `audit-v1`.

**Feature-task skill fork designed** (`skills/`). Surveyed the 113 first: all are PRD-shaped (even
the 4 "bugfixes" spec behavior, not failing tests); grading tests hidden + uniform base/new split;
features large (median ~840 LOC / 6 files). So the bug-fix recon→craft→audit pipeline does not drop
in — the runnable gate is gone. Forked into **design-doc → implement-spec → verify-spec** (PRD → design
doc → build → verify; the PDE loop). Core epistemic shift encoded: no real grader during the run, so
design-doc's acceptance criteria *become* the proxy gate implement-spec authors, and verify's RESOLVED
is `(proxy)`, never a certified grade-pass. Completeness over minimalism (features are large). The
codex volley is the one piece of our edge that transfers (filters the diff vs the spec, never needed
the container). **Not built: the driver/adapter** that runs these in-container — the real lift, still
ahead, and the point where the gateless-bench caveat bites (weaker correction loop).

## 2026-05-27 (later still ×2) — goal reframe: legible skills + dispel "less prompting is better"; Datacurve dropped

Audience analysis killed the submission-as-outreach premise: Datacurve won't engage (closed
leaderboard, no submission path, riding vibes), and the only stakeholder in their missing numbers
(Cursor) has its own eval team. So the recipient was never going to be Datacurve. Reframed to the two
goals that don't need them: **(1) make the recon→craft→audit skills legible** (publish skills + full
run data), **(2) dispel "less prompting is better"** — a preregistered, at-scale test against
DeepSWE's under-powered harness comparison (3 models, mini-swe-agent vs native CLI, single 10-task
slice, one run/cell, no CIs; stated finding "matches or beats... not disadvantaging any family",
inflated by the ecosystem into "lighter wins"). DeepSWE's 113 tasks demoted to a
contamination-free *substrate*; leaderboard/PR out of scope. Prereg §0 rewritten, §7 PR dropped,
README re-pointed. Named the motivated-reasoning hazard (we *want* the heavy-scaffold win) and the
guards (prereg + official grading + report-even-if-scaffold-loses + narrow-claim discipline).

## 2026-05-27 (later still) — EC2 oracle defect-audit: a HARNESS fault, not bad goldens (procedure lesson)

Ran the gold-patch defect audit on one spot m7i.8xlarge (32 vCPU/128GB, separate spot quota, ~$0.50,
10-wide, self-terminating). **First run: all 113 returned `reward=NA, rc=0`** — and that is emphatically
**our fault, not 113 defective goldens.** Diagnosis from the box: `result.json` showed `RuntimeError`,
`trial.log` dumped docker's *usage text* → pier invoked `docker compose` and AL2023's `dnf install
docker` ships the engine **without the Compose v2 plugin** (buildx present, compose absent, no
`~/.docker/cli-plugins`). Pier uses Compose to bring up the sandbox + egress-proxy pair, so every trial
errored before grading. Locally it worked only because Docker Desktop bundles Compose.

**Verdict-integrity call (mirrors the Pro discipline):** an all-uniform failure across every task is a
platform/harness signature, never a bench finding. Calling these "defects" would be the same
loss-laundering error in reverse — blaming the bench for our missing plugin. Result voided, not recorded.

**Fix:** bootstrap now installs the Compose plugin into `~/.docker/cli-plugins` and **asserts**
`docker compose version` + `docker buildx version` (loud FATAL, never silent NA). Re-running.

**Procedure lesson (the load-bearing one): the REAL scaffold run on EC2 grades through pier too**, so
its box bootstrap needs the identical Compose+buildx setup. A $0.50 throwaway audit de-risked the real
run's environment before we built the coordinator around it — exactly why the cheap check goes first.
Pinned in PREREGISTRATION §3a.

(Also hit `MaxSpotInstanceCountExceeded` on the immediate retry: the torn-down box still held the
32-vCPU spot quota while `shutting-down`; must `wait instance-terminated` before relaunching a
same-size spot box. Minor op note.)

## 2026-05-27 (later) — smoke tests + the "bench is the tasks" reframe

- **First smoke (`pier run --agent claude-code` Sonnet 4.5 on `ts-pattern-match-each`):** validated
  the full live path (ECR image up, claude-code installed + running in-sandbox under `allow_internet=
  false` with `api.anthropic.com` allowlisted, paid key). Confirmed plumbing, then **killed** it once
  the reframe (below) made it clear this was a *baseline-arm* run, not the scaffold — it no longer
  bought us anything toward the headline. Containers torn down (0 left running).
- **Reframe — the bench is the tasks, not Pier.** DeepSWE = the 113 Harbor tasks + each task's own
  verifier; Pier is just Datacurve's runner. So the scaffold arm runs under **our own driver** (same
  as Pro), graded by the task verifier executed unmodified via Pier; `pier run --agent` is kept only
  for the single-agent baseline arms. Prereg §1.3/§3a/§6/§8/§9 + README updated.
- **No-cheating invariants pinned (§9):** same 113 tasks, same unmodified per-task verifier (identical
  grading path to the leaderboard), agent never sees `solution/` or grade-time `test.patch`,
  source-only diffs, instance-blind; the agent *runner* is the only declared variable, grader held
  constant across arms.
- **Task-set integrity verified:** 113 manifest == 113 dirs, no mismatch, every task has
  `task.toml`+`instruction.md`+`tests/test.sh`; all 113 have `solution/`+`tests/test.patch`. Mix: 35
  TS / 34 Py / 34 Go / 5 Rust / 5 JS; 106 feature / 4 bugfix / 3 enhancement.
- **Second smoke (RUNNING, `--agent oracle`, $0 model):** applies each task's reference solution and
  grades via the verifier. Fault-reveals the real environment + unmodified verifier path (the
  load-bearing piece for scaffold-arm grading) AND doubles as the §5 defect check (does gold pass its
  own verifier?). **Result: reward 1.0 in 20s** (image warm) — gold passes its own verifier, the
  unmodified verifier path is sound, and `ts-pattern-match-each` is non-defective. The scaffold-arm
  grading mechanism (grade an external diff via the task verifier) is now de-risked on a real task.

## 2026-05-27 — configure: clone, install, validate, fork

Stood up the submission environment alongside the live SWE-bench Pro run (which holds the EC2 fleet
+ the paid API window; this work is local-only and shares nothing but the operator's attention).

- **Cloned** `datacurve-ai/deep-swe` (113 Harbor tasks, `source_dataset: swe-bench-ultra`, images on
  `public.ecr.aws`) and `datacurve-ai/pier` (Harbor-compatible harness, ATIF v1.7 trajectories).
- **Installed** `datacurve-pier` 0.2.0 (`uv tool install`). Docker daemon up locally; no Modal, so
  the execution path is **local docker** (their images are public-ECR, pullable). Model cost path:
  claude-code on Max subscription + codex on its own sub = $0 model spend; only local compute.
- **Validated plumbing end-to-end**: `pier run --agent oracle --env docker` on the bundled
  hello-world task passed (reward 1.0, 29s), wrote the full trial tree
  (`agent/`, `verifier/{reward.txt,ctrf.json,test-stdout.txt}`, per-trial + job `result.json` with
  token/cost stats). Confirms the provenance shape we publish (PREREGISTRATION §7).
- **Custom-agent hook confirmed:** `pier run --agent-import-path <module>` accepts a custom agent.
  This is how the recon→craft→audit composition plugs in as a first-class Pier agent (not just
  `--agent claude-code`), so the submission showcases the actual contribution: the composition.
- **Forked** `datacurve-ai/deep-swe` → `kimjune01/deep-swe` for the eventual PR (a public signal even
  if never merged; the PR is part of the litmus test).
- **Wrote** `PREREGISTRATION.md` at parity with the Pro prereg: predicate, fixed fault state machine,
  verdict-independent reclassification, official-Pier-only grading, whole-set stopping rule, full
  trajectory publication, and the **harness ablation DeepSWE skipped** (scaffold vs single-agent
  claude-code vs codex on the same 113, Fisher exact + Wilson).

**Not yet run.** A scored pass is a *measurement* and requires freeze (§10) + the defect audit (§5) +
the `--agent-import-path` adapter. Deferred until the Pro run frees the subscription quota (the paid
key is earmarked for Pro until ~2026-05-29 03:00). Configuration is complete; the run is staged.

**Framing correction (the bench is the tasks, not Pier).** DeepSWE = the 113 Harbor tasks + each
task's own verifier; Pier is merely Datacurve's runner. Treating "run through Pier" as the bench
repeats the harness/model conflation we attack in their work. So:
- **Scaffold arm runs under our own driver** (same as Pro), in the task image, emitting a source-only
  diff — NOT `pier run`. Contorting our composition into Pier's single-agent loop buys nothing.
- **Pier's only load-bearing role is the grader**: execute the task's unmodified verifier
  (`test.patch` + `test.sh`) so grading is demonstrably theirs, not hand-rolled.
- **`pier run --agent claude-code/codex`** stays for the single-agent baseline arms only (faithful
  Datacurve setup), grading held identical across arms. The smoke run (`--agent claude-code` Sonnet)
  is therefore a **baseline-arm** data point, not the scaffold.

**Execution decision:** scored run on the **EC2 fleet** (Pro coordinator reused), not local docker —
113 × 3 passes won't fit the laptop's disk or wall-clock. Driver reuse is near-total; the box
bootstrap adds pier (for grading + baselines) + deep-swe clone. `DOCKER_FAULT` (ECR pull/build)
carries more weight here. See PREREGISTRATION §3a.

**Next:** (1) write the recon→craft→audit Pier agent adapter; (2) port the Pro coordinator/run_fleet
to the `pier run` per-task command + `result.json` verdict parse; (3) run the §5 defect+originality
audit on all 113; (4) freeze `deepswe-sub-v1`; (5) scored pass + baselines on the fleet;
(6) publish trajectories + open the PR.

## 2026-05-28 — feature pipeline: encoded Hₐ₂ + Hₐ₂″ + Hₐ₄ skill `compose`; corpus catch-rate signal across 5 tasks

Resumed feature-pipeline session. The standing checkpoint (HYPOTHESIS_GRAPH.md) named the
highest-priority unbuilt component as Hₐ₂ (breadth/interface discipline, 41% weighted corpus
slice). This session: encode Hₐ₂ into build-tools, replicate across the corpus, surface the
spurious-enumeration refinement, and discover-then-encode the composer pattern as a separate
skill.

**Pipeline graph (skills) at session start vs end.**
- Start: `design-doc → build-tools → implement-spec → verify-spec`. All compositional-axis-trained.
- End: `design-doc (now emits FEATURE-SHAPE: enum|invariant|mixed) → {build-tools | compose | both}
  → implement-spec → verify-spec`. Hₐ₃ predicate concretized as the routing line; compose is the
  invariant-shape sibling of build-tools.

**Runs (all blind subagents, hard no-peek on tests/+solution/+lab-logs):**
| Task | Patch generation | Tests | SOUND+LIVE | Mutants caught |
|---|---|---|---|---|
| kysely-window-grouping-helpers (F₁₄) | build-tools w/ new Hₐ₂ sub-phase | 57 (43 per-element) | yes | 6/6 (4 breadth, 2 compositional-as-enum) |
| opa-rego-rule-profiling (F₁₄′) | build-tools | 53 (38 per-element) | yes | 6/6 (3 Hₐ₂, 2 H₇, 1 mixed) |
| httpx-streaming-json-iteration (F₁₄″) | build-tools w/ spurious-enum filter | 57 (8 per-element + 7 spurious-enum splits) | yes | 1/1 — `test_B12_plus_json_outside_application_rejected` caught a mutation a flat-enum baseline would have missed |
| oxvg-structural-selector-preservation (F₁₆) | build-tools first (8 tests, 0 per-element — Hₐ₂ correctly silent) | 8 | yes | initially named "2/2 pseudo missed" — see correction below |
| oxvg via `compose` (F₁₆′) | new compose skill | 8 (post-Phase-3 trim from 28 across 6 axes / 28 elements) | yes | (re-measured below) |

**Findings ranked by load-bearing-ness:**

1. **Hₐ₂ confirmed across 3 enumeration-rich tasks** (kysely + opa-rego + httpx); on-axis 85, population 70.
2. **Hₐ₂″ spurious-enumeration filter** directly measured on httpx — a split test caught a mutation flat-enum would have missed. Encoded in build-tools Phase 2.
3. **Hₐ₃ predicate refined → encoded** in design-doc Phase 5 as the `FEATURE-SHAPE:` line. Trigger is *PRD shape*, not F₁₂ canonical-class (opa-rego was the decisive counterexample — enum-rich PRD but path-rich canonical).
4. **Hₐ₄ composer skill** built (`skills/compose/skill.md`) + design-doc + RUNBOOK patched to route on FEATURE-SHAPE. **First measured run on oxvg shows the trim machinery works:** the agent inferred a 28-element surface from `parcel_selectors/parser.rs`, then trimmed 20 axes whose semantics produced behaviorally-equivalent gold-vs-pre-fix outputs. Hₐ₄'s machinery is functional and sound; the *evidence base* for needing it on oxvg specifically was wrong (see correction).
5. **Methodology — experimenter's H₈ caught twice.** First on opa (M4 fast-path-removal was semantically equivalent), then on oxvg (M-first-child and M-nth-child were both inert — canonical also passes 10/10 with them applied). Both times the "missed mutation" wasn't a real mutation. Bank as durable methodology: before claiming a coverage gap, verify the mutant changes observable behavior on the canonical suite, not just on a hand-built test.
6. **F₁₂ slug confusion.** "opa 50% path" referred to `opa-template-string-reconstruction`, not `opa-rego-rule-profiling`. The substantive findings still hold but the cross-axis-vs-F₁₂ framing of F₁₄′ was overclaimed.

**Correction to "Hₐ₄ gap measured on oxvg":** I claimed two pseudo mutations missed by the original (build-tools) oxvg proxy as evidence that compose was needed. After building compose and re-measuring with canonical as the soundness oracle, both mutations are inert at canonical level — the gold's pseudo handling is unused by canonical tests. The composer skill is built, sound, and ready, but its *case* on oxvg was based on bad mutations. The gap I named was the experimenter's H₈, not a real coverage hole. **Hₐ₄'s evidence base must be re-found** on a task where pseudo / invariant-axis mutations are actually canonical-load-bearing — oxvg is not that task.

**Artifact deltas (rebuildable from the graph):**
- `skills/build-tools/skill.md` — Phase 2 gained interface-enumeration sub-phase + spurious-enum filter.
- `skills/compose/skill.md` — new (~400 lines): surface inference from codebase, paired control/perturbation tests, manifest contract identical to build-tools.
- `skills/design-doc/skill.md` — Phase 5 emits `FEATURE-SHAPE:` line (Hₐ₃ predicate).
- `harness/feature/RUNBOOK.md` — operator routes on FEATURE-SHAPE.
- `HYPOTHESIS_GRAPH.md` — Hₐ₂ confirmed; Hₐ₂′ confirmed; Hₐ₂″ confirmed; Hₐ₃ refined+encoded; Hₐ₄ encoded-but-evidence-corrected; F₁₄/F₁₄′/F₁₄″/F₁₆/F₁₆′ pre-registrations + results.
- `build-tools-lessons.md` — 5 new entries.
- 5 task containers (kysely, opa, httpx, oxvg + still cached: bandit) reset clean.

**Population still unearned for Hₐ₂.** 4 tasks all at the shape extremes (3 enum-rich, 1 zero-enum). No middle-of-distribution task tested. Bandit is cached and would be the obvious next replication if anyone resumes this thread — it has a small enumeration (3 directives + 7 selector operators) embedded in a compositional spine; the test would be whether Hₐ₂ adds value at the margin or over-fires.

**Next obvious moves (if continuing):**
- Find a task where invariant-axis mutations are canonical-load-bearing, to actually earn Hₐ₄'s case.
- Run the full pipeline (with implement-spec) once to spend H₆ down and measure proxy-green vs grade-green delta.
- Codex sniff the compose skill before claiming it generalizes (no internet this session; staged for later).

## 2026-05-28 (later) — monoidal contract: skills self-classify + merge manifest

User direction prompted by "do we have a built-in classifier in compose? I want these skills to honor the monoidal contract." Answer: no — routing was operator-level via design-doc's `FEATURE-SHAPE:` hint + RUNBOOK. Fixed.

**What changed:**
- `skills/compose/skill.md` and `skills/build-tools/skill.md` each gained Phase 0 — Self-classify. Each skill reads PRD itself and decides `applies | partially-applies | does-not-apply` from the same sniff rule (enum-count vs invariant-count). Wrong-shape input → clean no-op identity (`*.applied: false` manifest stub).
- Phase-N manifest emit changed from "write" to "merge". Skills detect each other's slice via `*.applied: true` and union criteria. Idempotent on re-invocation.
- RUNBOOK routing is now advisory.

**Contract asserted (not measured): Hₐ₅.**
- `build-tools` ∘ `compose` = `compose` ∘ `build-tools` on mixed-shape tasks
- `*` ∘ `*` = `*` (idempotent)
- Identity on wrong-shape input

Test pending: dispatch both in both orders on httpx (mixed-shape candidate) and verify manifests equivalent up to ordering.

This converts the pipeline from operator-routed to skill-self-routed. Reroutes are recoverable; double-dispatch is safe. The session-end risk is the same as we banked twice (experimenter's H₈): writing "monoidal" in prose ≠ implementing it. A double-dispatch end-to-end check is the next perturbation.

## 2026-05-28 (later ×2) — monoidal-contract audit + manifest-schema fix

User: "audit each skill for its monoidal contract" / "make obvious improvements as you go."

**Audit (identity / idempotency / commutativity / merge):**
- design-doc: violated identity + merge — added Phase 0 (PRD-sha identity check) + emit prd-sha/session tags + dedupe rule in graph.
- build-tools: contract was prose-only — patched manifest schema to carry explicit `build_tools` slice + Phase 0/5 made concrete (read-merge-write).
- compose: same — explicit reference to the shared schema + Phase 0/6 made concrete.
- implement-spec: violated identity — added Phase 0 (if proxy green + suite clean on entry, exit clean without editing).
- verify-spec: already monoidal-conformant (read-only, verdict overwrite is correct terminal semantics). No change.

**Load-bearing fix:** manifest schema. The merge was prose-only; now structurally explicit. Each skill writes its slice; `proxy_gate` is the recomputed union. `dsr gate` / `dsr isolate` read `proxy_gate.run` — agnostic to which slice ran.

Hₐ₅ confidence 55 → 65 (schema concrete; runtime double-dispatch still untested).

**Next obvious test:** dispatch build-tools then compose on httpx (mixed-shape candidate) in both orders; verify the two manifests are equivalent up to ordering. Until that runs, the contract is encoded but not earned.

## 2026-05-28 (later ×3) — pipeline reframed as third prose compiler; convergence + cheap perturbations

User dropped two reframings during the audit:

1. **Convergence + dampener** (cf. /humanize, gcc -O3 fixpoint iteration): the right contract for LLM skills isn't strict bit-identical idempotency; it's convergence under iteration with a dampener that acts only on the diff.

2. **Pipeline is a prose compiler — third in the family with [sweep](https://github.com/kimjune01/sweep) and [immune](https://github.com/kimjune01/immune).** Cross-ref [Internal Reasoning of Prose Compiler](https://june.kim/internal-reasoning-of-prose-compiler) (2026-05-15). Sweep compiles `Issue → PR`; immune compiles `PR → verdict`; this pipeline compiles `PRD → grade-green patch`. All three share the HG as IR. Local source: `~/Documents/june.kim/src/content/blog/2026-05-15-internal-reasoning-of-prose-compiler.md`.

**HG node grammar is canonical** (from the post): nodes = perturbations · edges = evidence trajectories · leaves = e-value classifications with provenance back to the artifact each claim came from. My deepswe-run graph has been using this informally; HYPOTHESIS_GRAPH.md header now references the canonical source + the family pointer.

**Two HG instances at different scopes:**
- Per-task IR: design doc + manifest + $PROXY_GATE_DIR + task-scoped graph nodes.
- Cross-session IR: the graph itself + lessons log.

The meta-loop (skill development) is `(Issue) → PR → merged` on skills/*/skill.md, with this graph as its in-flight reasoning.

**Skill changes:**
- Phase 0 across design-doc / build-tools / compose / implement-spec rewritten as "convergence read": fast-path on stable state (`*.applied: true` or `prd-sha` match), dampener-only-act-on-diff when state is partial, fixed-point exit signal in test-file headers.
- RUNBOOK reframed: pipeline named explicitly as third prose compiler; stages tagged in both compiler-pass and Natural Framework substrate terms.

**Cheap perturbations (all 5 passed):**
- A — implement-spec convergence: kysely + gold → 57/57 → Phase 0 would print `converged`. Deterministic; zero LLM.
- B — verify-spec idempotency: trivially passes (read-only + verdict-overwrite is correct terminal semantics).
- C — build-tools convergence: stub manifest with `build_tools.applied: true` → subagent correctly identifies no-op exit.
- D — compose convergence: stub with `compose.applied: true` → same.
- E — design-doc convergence: prd-sha match stub → `CONVERGED` exit.

Hₐ₅ 65 → 75 (single-skill Phase 0 verified). Residue: commutativity (build-tools ∘ compose) and convergence-under-LLM-noise across full passes both untested.

Next obvious perturbation: dispatch build-tools on httpx (which already has the F₁₄″ artifact), expect Phase 0 fast-path + zero edits.

## 2026-05-28 (later ×4) — pipeline I/O correction: `Spec → Issue or PR`

User correction: the deepswe-run feature pipeline's I/O isn't `PRD → patch`; it's bimodal `Spec → Issue or PR`, positioning the pipeline **upstream of sweep** in the prose-compiler family.

- RESOLVED ⟹ emit PR.
- NOT_RESOLVED (coverage hole / criterion unmet / regression) ⟹ emit Issue (which sweep would then consume).
- REJECTED ⟹ Issue to human bin.

Family chain:
```
Spec → [this] → Issue → [sweep] → PR → [immune] → verdict / merge
                ↘ PR direct ────────→ [immune] → verdict / merge
```

Same HG IR throughout. HYPOTHESIS_GRAPH.md header + RUNBOOK updated.

## 2026-05-28 (later ×5) — frame narrow: benchmark output; upstream chain still WIP

User corrections in sequence:
1. "we are still aiming for benchmark shaped output, commutativity unnecessary"
2. "vision → roadmap → spec are still in the works, we're not quite there yet"

Walked back two layers of framing:
- Dropped `Spec → Issue or PR · upstream of sweep` claim.
- Dropped commutativity (`build-tools ∘ compose`) from the goal set — not needed for grade-green.
- Then dropped the "borrows the prose-compiler shape" family-positioning entirely. The upstream `vision → roadmap → spec` chain that would justify family membership isn't built.

What stays:
- **HG as IR** for internal reasoning — useful for re-entry safety, not a positioning claim.
- **Convergence + dampener** in LLM-skill Phase 0 — earned by 5/5 cheap perturbations; makes re-entry safe (verify-spec back-edge to design-doc doesn't redo stable work).
- **The 5-stage pipeline** (design-doc → routing → build-tools/compose → implement-spec → verify-spec) — operationally correct.

Scope re-stated in HYPOTHESIS_GRAPH.md + RUNBOOK header: **input PRD, output patch, metric grade-green rate across 113 tasks.** Patterns borrowed; positioning not claimed.

Hₐ₅ row renamed from "monoidal pipeline" to "convergence + dampener for LLM skills" — drops inflated property, keeps earned one.

## 2026-05-28 01:43 · session close · H₆ spend ATTEMPTED, ABORTED on token budget · kysely-window-grouping-helpers

**Setup verified, dispatch aborted before measurement.** Re-read HYPOTHESIS_GRAPH + RUNBOOK + lessons log. Confirmed kysely substrate ready:

- manifest exists (57 criteria); `dsr isolate` re-confirmed **SOUND + LIVE** in the live container at 01:39.
- container `dsr-kysely-window-grouping-helpers` up & reset clean (verified by isolate's clean-base pass).
- `baseline_fails = []` (tight regression bar).
- No prior implement-spec artifact on disk; clean slate for H₆.

**Methodology call (worth banking):** design-doc.md was NOT persisted by the F₁₄ build-tools run — only the manifest + proxy-gate.test.js. Decided to skip a re-run of /design-doc and dispatch /implement-spec directly off PRD + proxy-gate.test.js (the encoded criteria are PRD-quoted in the test file). Saves one round-trip; gives the implementer a more precise spec than design-doc prose would.

**Carry-forward for next session — resume here:**
1. Re-run `dsr isolate kysely-window-grouping-helpers run/.../manifest.json` to confirm container state.
2. Dispatch implement-spec blind. No-peek hard-forbids: `/app/test/`, `/app/tests/`, anything under `/Users/junekim/Documents/deepswe/deep-swe/tasks/kysely-window-grouping-helpers/` except `instruction.md`. ALLOWED: `/tmp/proxy/proxy-gate.test.js` (build-tools-authored).
3. Skip codex volley (token budget). Cap at ~4 iterations.
4. `dsr gate` → `dsr grade` → record proxy-green vs grade-green delta.
5. Update HYPOTHESIS_GRAPH: H₆ moves from "operational, never spent on a real pipeline" to a first datum on proxy→grade prediction.

**Honest residue restated:** zero grade-green measurements still. The session's confidence numbers on Hₐ₂/Hₐ₂″/etc. all rest on proxy-gate + targeted-ablation, not on the oracle. The H₆ spend is the highest-priority missing measurement and remains so.

## 2026-05-28 [partial-v1 fire #1] · FIRST FLASH+COMPOSER GRADE-GREEN · kysely-window-grouping-helpers

**Composer 2.5 first-pass green on the hidden oracle.** REWARD 1 (base 22/22 pass, new 254/254 pass).
Single Composer dispatch on PRD + proxy gate, no adversary loop fired (Composer's proxy claim
57/57 matched the container's run 57/57; no need to volley). 21 files modified/created (vs gold's
15 → over-implements or different-but-equivalent shape; TBD diff analysis).

**Cost:** ~30 min wall-clock for Composer impl (token spend TBD from log analysis).

**New HG entries:**
- Hₐ₆ added: "Composer first-passes breadth-dominant features without an adversary loop" — n=1 supporting on kysely. Perturbation: fire bandit (compositional, F₁₂ 42%) where Claude needed H₇/H₈/H₉ stacks. If Composer also green, H₉ necessity collapses on this pair. If Composer fails, H₉ overlap becomes measurable.
- H₃ ticked from confirmed (n=2 Claude tasks) → confirmed (n=3 cross-family); transfer-risk de-rated.
- H₆ MEASURED end-to-end at 95%; was 92% theoretical. Gold-grade and Composer-grade both REWARD 1 today.
- H₉ marked **non-firing on first-pass-green tasks**; overlap measurement requires a *missing* fire.

**Operational lessons banked into HG §Operational lessons from live fires:**
- cursor-agent silently `cd`s to last-trusted dir without `--trust --workspace <path>`.
- CURSOR_API_KEY doesn't propagate through Bash-tool shells; need explicit env or --api-key on every dispatch.
- `dsr isolate` wipes the working diff; can't use after impl.
- cursor-agent self-reports gate accuracy (n=1, tentative).
- Long Composer runs are silent — monitor by log size growth not tail content.

**Next perturbation (carry-forward):** fire `bandit` to see whether Composer first-passes the compositional anchor. The session's prior Claude+codex measurements needed H₇ Phase 4.5 iteration AND H₈ mutation thinking AND H₉ codex adversary to catch M1+M3 on bandit. If Composer first-passes there, the loop disciplines may be Claude-specific and the harness richness story changes shape.

## 2026-05-28 [partial-v1 fire #2] · SMOKING GUN: bandit proxy-green / grade-red on Composer (96.2%)

**REWARD 0** on bandit-structured-nosec-directives. Composer 2.5 wrote a 5-file impl in ~5.5 min,
30/30 proxy passing, **75/78 (96.2%) oracle passing** — three specific failures:

- `test_058_region_unioned_across_statement_lines` — region semantics across multi-line statement
- `test_110_selector_difference_suppresses_other_not_this` — selector `-` precision on non-trivial set
- `test_123_selector_all_and_B602_counts_as_specific` — **M1 shape**: `all & B602` resolves to specific set, mis-classified as `nosec` instead of `skipped_tests`

**Predictions vindicated.** PREDICTION.md (committed 7698189 BEFORE result landed) predicted:
- #1 proxy-green (60% conf) → CONFIRMED 30/30
- #2 grade-red possible (50%) → CONFIRMED
- #3a selector operator precision failure → CONFIRMED on `-` (predicted `&`/`!`; same class)
- #3c metrics classification by resolved set (M1 shape) → CONFIRMED on test_123 direct hit

**HG updates:**
- Hₐ₆ REFINED: split outcome confirmed (kysely PASS / bandit PARTIAL by feature class).
- H₈ ticked to 80/65 + flagged "MEASURED LOAD-BEARING ON COMPOSER". The bandit fault IS H₈ measured at proxy-author time. Patch path: build-tools Phase 2-bis must write a "classify by resolved set" mutation test on any selector-operator feature.
- H₉ architecturally reframed: adversary fires Phase 4 (post-impl) but the bandit gap is pre-impl (proxy itself lacks the tests). Adversary slot may need *earlier* placement.
- Live datapoints table: 2 grade-attempts, 1 REWARD 1, 1 REWARD 0 (75/78 close).

**Why this is the most valuable measurement of the session:**
1. First-ever measured proxy-vs-grade gap on this model pair.
2. The gap has 3 named test cases — concrete, addressable.
3. test_123 is exactly the M1 shape Claude needed H₈ to catch in F₁′. **The discipline gap transfers across model families.** Composer also misses the agreement-region distinction without explicit mutation thinking.
4. Pre-flight predictions land — the methodology of writing predictions BEFORE the result is what makes the lesson honest. Without it, the post-hoc reading of "Composer was close, predicted shape" would be cherry-picking.

**The publishable claim now has its first measured limit:**
> Flash+Composer in this harness land proxy-green on dense feature PRDs and match gold within ~4% on the oracle for compositional/selector tasks. The gap is in proxy-author mutation-thinking and is patchable in build-tools Phase 2-bis. Not yet SOTA on compositional features.

**Cost so far (model spend):** kysely ~30 min Composer + bandit ~5.5 min Composer; tokens TBD from Cursor dashboard.

**Carry-forward — next perturbation to consider:**
- (a) Patch build-tools with the H₈ "classify by resolved set" mutation discipline, re-fire bandit, see if the patched gate catches test_123 at proxy-author time. Tests the *patch hypothesis* directly.
- (b) Fire a *path/fixture-dominant* substrate (happy-dom or opa-template-string-reconstruction) — Hₐ₁ frontier, Composer behavior unmeasured. Broader coverage.
- (c) Fire `oxvg` with the compose route (invariant PRD shape) — Hₐ₄ machinery, never tested on Composer.

Recommend (a) — patch then re-fire — because we have a SPECIFIC actionable patch and a NAMED test
to verify, which would be a cleanly measurable iteration.

## 2026-05-28 [partial-v1 verify] · BANDIT REWARD 1 via 13-line hand patch — foundation firm

Applied both diagnosed patches directly to Composer's bandit impl. Total time ~10 min, $0 model spend.

**Patches:**
- `nosec_directives.py:395-401` — `_resolve_single_token("all", enabled_ids)` returns `set(enabled_ids)` instead of `set()` inside the parser; the API blanket sentinel `set()` is preserved at top-level `_resolve_selector` (line 264). One line + 4-line comment.
- `nosec_directives.py:51-65 + 142-160` — token-loop bracket-depth tracker → `in_bracket_lines` set; `_compute_regions` accepts the set and skips auto-end-on-dedent for continuation lines (lines that begin with `bracket_depth > 0`). First attempt marked any line containing `()` as in-bracket and broke test_19; refined to "begins inside a bracket" — fixed.

**Final state:**
- Proxy gate: 30/30 ✓
- `dsr grade bandit`: base PASS + new 78/78 PASS → **REWARD 1**
- Three originally-failing tests (test_058, test_110, test_123) all green
- No regressions in base suite

**What this verifies:**
1. The diagnosis from the $0 cheap-learning round was EXACT. Both root causes I named (sentinel collision + dedent-inside-bracket) were the actual bugs.
2. The patch shapes were mechanically derivable from the diagnosis — no creativity needed once the bug location was correct.
3. **Hₐ₈ meta-pattern verified:** both bugs were "single-axis rule applied at wrong scope, ignoring cross-axis condition." Both yielded to "disambiguate the scope" fixes.
4. **Composer's impl was correct on the rules it had tests for.** The 96.2% deficit was *the proxy gate missing the cross-axis tests*, not Composer mishandling them. If build-tools had written tests like "all & B602 → expect {B602}, not blanket" and "nosec-begin inside multi-line call → expect region applies past close-paren," Composer's impl would have failed those tests at proxy-author time, implement-spec would have iterated, and grade-green would follow.

**Foundation firmness:** the publishable claim now has a verified concrete shape:
> Flash+Composer with axis-crossing mutation discipline in build-tools land grade-green on
> dense compositional features as well as breadth features. Without that discipline, they
> land at ~96% with predictable cross-axis gaps.

**Cost summary for the entire kysely + bandit-discovery + bandit-verify cycle:**
- 2 Composer dispatches (kysely ~30min + bandit ~5.5min) = TBD tokens
- 0 adversary dispatches (H₉ slot non-firing)
- 2 reading rounds (~12 min total, $0)
- 1 hand-patching round (~10 min, $0)
- Total LLM spend: just the 2 Composer calls. Total grade-green datapoints earned: 3 (kysely-gold, kysely-composer, bandit-composer-patched).

**Next perturbations possible:**
- (a) Encode Hₐ₈ into the build-tools skill file as Phase 2-bis. Then re-fire Composer on bandit with the patched skill. If proxy now includes axis-crossing tests, Composer's impl should land grade-green on first pass without hand-patching. Tests the full *automated* harness path.
- (b) Fire a 3rd substrate — happy-dom (breadth/additive) or opa-template (path/fixture-dominant). Broader population sample for Hₐ₆ / Hₐ₈ generality.
- (c) Read happy-dom's PRD + proxy gate without firing Composer ($0) to PREDICT whether Hₐ₈ would fire on it. Cheaper-still survey before any token spend.

Recommend (c) → (a) → (b): predict first ($0), then test the skill patch (cheapest verification), then broaden ($).
