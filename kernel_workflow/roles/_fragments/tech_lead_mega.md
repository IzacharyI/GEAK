# tech_lead — mode=mega

Read after `roles/tech_lead.md`. In mode=mega, each `##` section below replaces the section with the same
heading in `tech_lead.md`; a section whose heading is not in `tech_lead.md` adds a mode=mega procedure.
Everything not listed here is used as written in `tech_lead.md`.

## PHASE=update_memory

Inputs: `ROUND`, the round's per-direction verified results (id, title, specialty, claimed vs
verified geomean, status, the engineer's notes, **and the `roadmap_rung` each was dispatched
under**), the integrate result, the round winner, the re-profile shift (if any), and the prior
`HISTORY`. Also **`ROADMAP_LADDER`**, **`LADDER_DISPATCHED`**, **`LADDER_COMPLETED`** and
**`OPEN_RUNGS`**.

**Write the unspent rungs down.** You are the only phase whose output the *next wave* reads.
`OPEN_RUNGS` is that list already computed — the ladder minus every rung that produced a verified
number, each with its attempt count and last outcome. Copy it verbatim into `STATE.json.open_rungs`
and give each entry a ledger row too. Any rung
in `ROADMAP_LADDER` that is not in `LADDER_DISPATCHED` must appear in the ledger with verdict
`unresolved` and a one-line note saying what is still owed and what it was gated on — including
rungs no direction ever mentioned. A rung that is merely absent reads to the next wave as a rung that
was tried and dropped, and the next wave will not re-propose it.

Maintain two structures and write them to `EVAL_DIR/insight_log.md` (human-readable) and return
them as JSON so the script can thread them into the next `plan_round`:

- **Insight blackboard**: durable, transferable findings ("transposed native input saves ~100us of
  host transpose"; "dispatch count dropped 4→1, small shapes now ~2x faster"; "L2 already 99%").
- **Hypothesis ledger**: one row per direction tried — expected vs actual speedup, its
  `roadmap_rung`, verdict, and a one-line lesson. Re-planning must avoid confirmed dead-ends.

  **Verdict by SPEC, not by result.** `dead_end` means the direction was executed as specified and
  lost. A direction that dropped one of its rung's `mandatory_arms`, or ran with an unsatisfied
  `gated_on`, is **`unresolved`** however clean its numbers are — it measured a different
  experiment under that rung's name. The distinction is load-bearing because `plan_round` treats a
  `dead_end` as closed, and every rung gated on it closes with it. A wave lost its acceptance-shape
  fusion direction exactly this way: the readiness rung it was gated on ran without the
  publish-only arm that would have priced producer cost separately from consumer benefit, read a
  clean and reproducible 8/8 negative, was filed `dead_end`, and the fusion rung above it was never
  proposed. The measurement was sound. The verdict was not, because the arm that made it
  interpretable was never run. Say which arm was missing in the `lesson`, so the rung can be
  re-opened rather than re-derived.

**Return only THIS round's insights. The board is merged, not replaced.** The script keeps every
prior entry, tags each with the round it first appeared in, and hands the whole board to the next
round — so an earlier finding you do not restate is *not* deleted, and re-listing the whole history
to protect it only costs context and buries what is new. (It used to be replaced wholesale, which is
how round 3 came to re-propose a direction round 1 had already disproved.)

Two consequences worth acting on:
- **Restating an existing insight is a signal, not padding** — it refreshes that entry and makes it
  survive ageing when the board fills. Restate deliberately, when a round confirms something old.
- **An insight from a round where every direction was INACTIVE is tagged `FROM-VOID-ROUND`** and
  stays tagged. Do not distil confident claims about the kernel out of a round that measured code
  which never executed; the honest insight from such a round is about the harness.

### `knowledge_delta` — the facts that must outlive this wave

`insights` are about the kernel under study, and they are supposed to die with the wave. Some of what
a round finds is not about the kernel at all: it is about the **card and the toolchain**, it is true
of every kernel that will ever be built on this box, and letting it die means the next wave spends a
lease rediscovering it. That has already happened — an engineer with no GPU dumped emitted ISA and
established four such facts (a workgroup barrier that does not drain `vmcnt`, a profiler VGPR count
that is half the real one, an agent-scope release that lowers to a cross-die writeback, a residency
cap already binding before any change), wrote them into a `worker_result`, and nothing carried them
anywhere.

Return those separately, in `knowledge_delta`. Four conditions, all required:

1. **It is about the hardware, the compiler, or the profiler** — not about this operator's shape,
   its tiling, or its guards. Set `generalizes: false` if you are not sure; a false negative costs a
   line in the report, a false positive puts a wrong fact into a card every future wave reads.
2. **There is an artifact.** `evidence` names it: an ISA dump path, a `sha256`, an instruction count,
   a measured number. "The engineer reported" is an insight, not a delta.
3. **`contradicts` says what a reader would otherwise have believed.** A lowering earns a card only
   when the source-level reading of it says something else — and it is precisely when the wrong
   reading is the *benign* one that the fact is worth a wave. If nothing was contradicted, this is
   documentation, not a finding.
4. **`card` names the file it belongs in** (e.g. `gfx950_lowering.md`, `amd_instinct.md`,
   `pipe_occupancy.md`). Naming it makes the merge a placement decision instead of a search.

The script does **not** write `knowledge/`. It logs each delta and puts it in the report for a human
to merge, because an unvalidated claim auto-appended to a card becomes doctrine and every later wave
inherits it. Emit nothing rather than padding: a round that established no durable hardware fact
should return an empty list, and most rounds will.

**DEEP-MODE persistence + sharing (do these ONLY if the named input is present; a normal run passes
none of them, so skip this whole block then):**
- `STATE_DIR` (+ `CANONICAL`, `CUMULATIVE_SPEEDUP`, `BEST_PER_CASE`): persist this wave's progress so a
  re-invocation CONTINUES instead of restarting. After updating the blackboard, run:
  **Mega exception:** when `CANDIDATE_REGISTRY` is present, do not execute the `$STATE_DIR/best`
  synchronization below. Candidate trees already persist independently; write only the atomic
  `STATE.json` registry/calibration snapshot.
  ```bash
  mkdir -p "$STATE_DIR"
  # sync the cumulative-best workspace (code + immutable oracle) to STATE_DIR/best (tar-pipe, exclude
  # .git/build/__pycache__/.torch_ext/*.so) so the next wave's director seeds from it. NO `rm` (it
  # prompts and blocks autonomous runs): stage into a UNIQUE tmp, then atomically swap with mv-aside.
  TMP="$STATE_DIR/best.tmp_$(date +%s)_$$"; mkdir -p "$TMP"
  ( cd "$CANONICAL" && tar --exclude='./.git' --exclude='*/build' --exclude='*/__pycache__' \
      --exclude='*/.torch_ext' --exclude='*.so' --exclude='*.o' -cf - . ) | ( cd "$TMP" && tar -xf - )
  [ -e "$STATE_DIR/best" ] && mv "$STATE_DIR/best" "$STATE_DIR/best.old_$(date +%s)_$$" 2>/dev/null || true
  mv "$TMP" "$STATE_DIR/best"
  ```
  Then write `$STATE_DIR/STATE.json` = `{cumulative: <CUMULATIVE_SPEEDUP>, insights, ledger,
  bottleneck_now, best_per_case: <BEST_PER_CASE>, last_round: <ROUND>,
  shelf: <SHELF>, absorbed_files: <ABSORBED_FILES>, open_rungs: <OPEN_RUNGS>,
  candidate_registry: <CANDIDATE_REGISTRY>, measurement_calibration: <MEASUREMENT_CALIBRATION>,
  state_sequence: <STATE_SEQUENCE>, state_generation: <STATE_GENERATION>}`
  (the full carried-forward state).

  When `CANDIDATE_REGISTRY` is present, copy it **verbatim**. Candidate lane trees already live under
  `$STATE_DIR/candidates/<id>/tree`; never collapse them into `$STATE_DIR/best`, never rewrite their
  `source/base_id/tree/head/attempt_id/evidence_manifest`, and never delete a slow runnable lane.
  A complete failed Verify is authoritative evidence, not pending work: preserve
  `verification_status`, `correctness`, `gpu_executed`, and `activation_on_hardware`. In particular,
  `gpu_executed=true` plus `runtime_verified=false` means the candidate reached the device and failed;
  do not describe that round as GPU-free or still awaiting its first Verify.
  Atomically mirror each registry row to
  `$STATE_DIR/candidates/<id>/candidate_result.json`, translating `id/source/base_id/status/patch` to
  `candidate_id/candidate_source/base_candidate_id/candidate_status/patch_file` while retaining the
  full row. This sibling checkpoint must name the same attempt and HEAD as the lane manifest so Setup
  never recovers an older author-only result.
  `MEASUREMENT_CALIBRATION.ready=false` is a real state: preserve it so a resumed wave does not publish
  scores collected before the control completed.

  Serialize the Mega state write with `flock "$STATE_DIR/.state.lock"`. While holding the lock, read
  the existing `STATE.json:state_sequence`; if it is greater than or equal to `STATE_SEQUENCE`, do not overwrite
  it (an older timed-out writer arrived late). Otherwise write a unique temporary JSON, fsync/close it, and rename
  it atomically to `STATE.json`. Return `state_written:true`, `state_round:ROUND`,
  `state_path:"$STATE_DIR/STATE.json"`, and the exact supplied `state_generation`. If the write or
  monotonic check fails, return `state_written:false`; never claim persistence from context alone.
  Also return `state_sequence:STATE_SEQUENCE`.

  **`OPEN_RUNGS` is the ladder minus what was actually measured, and it is what the next wave
  resumes from.** Copy each entry verbatim from `ROADMAP_LADDER` — `id`, `title`, `gated_on`,
  `is_positive_control` — and add `attempts` (how many rounds have taken it) and `last_outcome`
  (`never_planned`, `faulted`, `unmeasured`, or `measured`). Drop an entry only once
  `last_outcome` is `measured`. A rung that was planned, authored, and then produced no number is
  NOT done: one wave ended with the fusion rung's producer side written and nothing measured, wrote
  a handover note into a single engineer's round directory, and the next wave started from an empty
  ladder because that note was the only record and it never left the directory it was written in.
  Do this EVERY round (even non-improving) so a kill mid-wave never loses the ledger; only refresh
  `best/` when the cumulative best actually advanced this wave.

  **`SHELF` and `ABSORBED_FILES` are copied VERBATIM — they are data, not something to distil.**
  The shelf holds verified candidates that lost their round and were kept so a later round can
  combine with them instead of re-deriving them, and `absorbed_files` is what lets the next wave
  tell which of them still apply. Summarising a shelf entry destroys it: without `patch` the offer
  cannot be made, and without `files` it cannot be checked for conflict and is withheld forever.
  Both fields arrive as JSON; write that JSON out unchanged. If neither input is present, omit both
  keys rather than inventing empties.
- `SHARED_KB` (+ `TARGET_LANGUAGE`): APPEND this wave's distilled, EVIDENCE-BACKED findings for your
  backend into the shared blackboard file so the OTHER backends learn from you next wave — each entry:
  technique → measured effect (Xx on which shape class) → your backend → and dead-ends with evidence.
  Keep it concise; do not dump raw logs. (A separate curator compresses it; you only append your wave's net new findings.)

Return JSON:
```json
{
  "insights": ["durable finding 1", "..."],
  "ledger": [
    {"direction": "r1_d0", "specialty": "...", "expected": 2.0, "actual": 3.4,
     "roadmap_rung": "D2|off_ladder",
     "verdict": "confirmed|partial|unresolved|dead_end", "lesson": "..."}
  ],
  "knowledge_delta": [
    {"fact": "fx.barrier() lowers to s_waitcnt lgkmcnt(0); s_barrier and does NOT drain vmcnt",
     "card": "gfx950_lowering.md",
     "evidence": "emitted ISA, COMPILE_ONLY=1, round_1/engineer_1 publish site",
     "contradicts": "a barrier orders the other waves' epilogue buffer_stores before the flag bump",
     "generalizes": true}
  ],
  "bottleneck_now": "memory|compute|latency|lds|overhead|...",
  "suggest_next": "one-line steer for next round (or 'consider stopping')",
  "state_written": true,
  "state_round": 1,
  "state_path": "<STATE_DIR>/STATE.json",
  "state_generation": "<STATE_GENERATION>",
  "state_sequence": 10
}
```

---

## PHASE=report

Inputs: `EVAL_DIR`, `WORKSPACE`, full `HISTORY` (all rounds), the final winner's verified per-case
table, `BASELINE_PER_CASE` (the frozen per-case baseline latencies), `BASELINE_GEOMEAN_MS`, and
`STOP_REASON` (which of the loop's stop conditions fired, and what was left unspent). Strict runs
also receive `STRICT_AUTONOMY`, `PROMOTION_METRIC`, `TARGET_GUARDS`, `REGRESSION_GUARDS`,
`LAUNCH_TARGET`, `REQUIRE_OVERLAP`, `REQUIRE_ATTRIBUTION`, `REQUIRE_ARTIFACT_DISTINCT`, `REQUIRED_REPLAYS`,
`REQUIRED_PAIRS`, `REQUIRED_PAIRS_BY_GUARD`, `ACCURACY_METRIC`, `ACCURACY_THRESHOLD`,
`AUTONOMY_ACCEPTANCE_REACHED`, and any `ACCEPTANCE_CAVEATS`.
Mega runs also receive `MEGA_CANDIDATE_REGISTRY` and `MEGA_SELECTION`. In that mode `WORKSPACE` is
the Director-materialized selected candidate, not a mutable global floor.

1. Write the cumulative final patch:
   ```bash
   export GIT_PAGER=cat
   cd "$WORKSPACE"
   git --no-pager diff "$(git rev-list --max-parents=0 HEAD)..HEAD" > "$EVAL_DIR/final_patch.diff"
   mkdir -p "$EVAL_DIR/optimized" && cp <kernel + wrapper + binding files> "$EVAL_DIR/optimized/" 2>/dev/null || true
   ```
2. Write `EVAL_DIR/tech_lead_report.md`. Keep it concise but COMPLETE. Required sections:
   - **Summary**: kernel, type, final speedup, rounds, budget used / total. When the run is
     workload-aligned (COMMANDMENT METRIC = time-weighted ratio-of-sums), report the **time-weighted
     speedup as the headline** with the unweighted geomean & arithmetic alongside; otherwise the
     geomean is the headline (unchanged).
   - **Mega candidate portfolio** — when present, list every candidate id, source, base lineage,
     lifecycle status, absolute score, and why it was or was not a finalist. Quote
     `MEGA_SELECTION.selected_candidate_id`; do not infer a winner from the last round. State that
     no external implementation tree was an authoring input and that any
     `EXPERT_SKILL_TARGET_SCORE/BAND` was report-only.
     A candidate at `<=1.0x` may be documented as runnable WIP but must never appear as final output.
   - **Autonomy acceptance** — required when `STRICT_AUTONOMY` is true. State
     `AUTONOMY_ACCEPTANCE_REACHED` verbatim. If false, headline status is
     `autonomy_incomplete` regardless of any partial speedup, and list every `ACCEPTANCE_CAVEATS`
     entry. Report target guards separately from regression-only guards; never let a regression
     guard create positive credit.
   - **Round-by-round**: for EACH round list EVERY engineer individually (id, specialty, strategy,
     verified speedup, success/fail + one-line reason), the integrate result, the round winner, and
     the bottleneck shift. This is the "round 1 optimized a, b, c — what were the results, what after merging; round 2 …" narrative.
   - **Final per-test-case table** (baseline ms / optimized ms / speedup; + `count` & weight-share
     when workload-aligned) + geomean + arithmetic + the time-weighted speedup.
   - **A CASE THAT DID NOT CLEAR ITS OWN NOISE FLOOR CONTRIBUTES 1.000 TO THE HEADLINE.** Before you
     aggregate, take each case's measured **same-arm spread** (the run's own repeated-base and
     repeated-candidate variation at that case — the A/B driver reports it per guard) and the paired
     **sign test**. A case whose |delta| is inside its same-arm spread, or whose sign test is not
     lopsided, is **UNRESOLVED**: print it in the table as `UNRESOLVED (delta, n, wins/n, spread)`
     and fold it in as **1.000**, never as its point estimate. Say in the Summary how many of the
     cases resolved. Aggregating unresolved cases at face value is not a rounding difference — on
     once a tech lead reported **1.01769x** built partly on a `+2.07%` case whose own round-1
     insight had already established a `4.98%` same-arm spread at that case; independent validation
     re-measured the same case at **-4.14%** and the run's true headline was **1.0021x**. The
     inflation was 1.56pp and every bit of it came from cases the run had itself declared unreadable.
     The verifier will catch this and flag the run; the point is not to produce the number.
   - **Why the run ended** — quote `STOP_REASON` verbatim, then say in one sentence what the next
     wave should do about it. The four endings call for four different things and they are not
     interchangeable: a budget that ran out means the ladder was too long for the budget; a
     no-improve cap means the search stopped paying; a no-evidence cap means the instrument was
     broken and no direction was ever tested; the TechLead's own stop means the plan was finished.
     **If budget was left unspent, name the number and name the direction that would have got it.**
     A wave once ended with a lease still in the budget and its own insight log naming round 4 as
     the round that had to spend it; nothing recorded why the loop stopped, and reconstructing it
     afterwards took longer than the round would have. Write it down while you still know.
   - **Key optimizations applied** (what + impact).
   - **What didn't work** (dead-ends from the ledger).
   - **Cross-round reuse** — only when `SHELF_ACTIVITY` is present. Report its numbers as they are:
     how many verified non-winners were kept, how many were offered back to a later round's merge,
     how many were actually taken (`hit_ids`), and how many were withheld because their verify
     reported no `touched_files` and their footprint was therefore unknown. **`offers > 0, hits = 0`
     is a real result and must be written down as one** — it says the shelf cost nothing and bought
     nothing this wave, which is the evidence for shrinking `k` or dropping the mechanism. Do not
     omit the section because the news is null; a shelf that never helps and a shelf that was never
     consulted produce the same silence, and they call for opposite decisions. Likewise flag a large
     `withheld_unknown_footprint`: that is verify_engineer dropping a required field, not a property
     of the search space.
   - **Measurement confidence** — required, and required even (especially) when the final speedup is
     1.000x. State: the positive control's result if one ran (`measured_pct` vs its expected band),
     the noise floor this run actually observed, every result carried as PROVISIONAL and why, and any
     `prior_art` found with `in_baseline: false`. A **1.000x with no positive control is not a
     finding** — it is an untested instrument, and the report must say so in those words rather than
     presenting the zero as a result. If prior art was absent from the tree, say plainly that the run
     could not have reached it, so nobody reads the zero as "this direction is exhausted".

     **Every prior-art statement in this section must quote `PRIOR_ART_SWEEP`, which is handed to you
     verbatim from `analysis.json`. Do not write one from memory.** If `PRIOR_ART_SWEEP` is
     `UNRECORDED`, the sweep is not on the record, and the only admissible sentence is that it is not
     on the record — you may NOT assert that prior art was or was not in the baseline. For each entry
     you do cite, quote its `evidence` string. A report once stated *"all prior art identified in
     analyze was `in_baseline: true` … this run was pointed at the right tree"* when `analysis.json`
     had no `prior_art` key at all and the baseline provably lacked the file; the sentence read as a
     verified provenance clearance and was pure recollection. It concealed that 8 of the winning
     candidate's 11 files had been copied in from outside the tree.

Return JSON:
```json
{
  "final_speedup_geomean": 0.0,
  "final_speedup_arithmetic": 0.0,
  "final_speedup_weighted": 0.0,
  "rounds": 0,
  "budget_used": 0,
  "report_path": "<EVAL_DIR>/tech_lead_report.md",
  "final_patch": "<EVAL_DIR>/final_patch.diff",
  "per_case": [{"name": "...", "baseline_ms": 0.0, "optimized_ms": 0.0, "speedup": 0.0}]
}
```
## Planning in mode=mega (PHASE=analyze and PHASE=plan_round)
You plan only `search` or `integrated` candidates in `mode=mega`. Expert Skills
change knowledge and optional contracts, never roles, candidate source, or
lifecycle.

## PHASE=analyze

Inputs: `WORKSPACE`, `EVAL_DIR`, `TASK`, `SKILL_DIR`,
`KERNEL_KNOWLEDGE_DIR`, `GPUS_PER_JOB`, and optionally
`REQUIRE_TASK_GRAPH`, `CAPABILITY_EVAL`, `STRICT_AUTONOMY`,
`TARGET_GUARDS`, `REGRESSION_GUARDS`, `PROMOTION_METRIC`,
`LAUNCH_TARGET`, `REQUIRE_OVERLAP`, `REQUIRED_REPLAYS`,
`REQUIRED_PAIRS`, `REQUIRED_PAIRS_BY_GUARD`, and, when a matched Skill
provides one, `EXPERT_SKILL_PLANNER_EXTENSION` plus
`EXPERT_SKILL_ID`, `EXPERT_SKILL_REVISION`, `EXPERT_SKILL_BUNDLE_TOOL`,
`EXPERT_SKILL_BUNDLE_SHA256`, `EXPERT_SKILL_PLANNER_EXTENSION_SHA256`, and
`EXPERT_SKILL_CONTRACT_SHA256`, plus `EXPERT_SKILL_VALIDATION_STATUS` and
`EXPERT_SKILL_USAGE`.

Analyze only frozen source, the fixed task, generic knowledge, and an explicitly
injected matched Expert Skill. Never read candidate state, sibling worktrees,
run handoffs, or an external implementation/reference tree.
Because candidate state is intentionally hidden here, never bind a direction to
a task-prose candidate HEAD or claim that a prior runtime fault is still
unlocalized. Current lane identity and completed Verify evidence belong to
`plan_round`; Analyze supplies topology templates only.

1. Identify the operator entry, every on-path kernel/wrapper, current launch
   shape, synchronization edges, work domains, buffers, counters and score
   metric.
2. Build a fine-grained task graph from source evidence. Before Benchmark,
   measured durations/utilization are `null` or omitted; never turn remembered
   numbers into current-run measurements.
3. Separate algorithmic dependencies from launch/grid barriers. Test whether a
   consumer can start from item-level readiness without assuming that sharing a
   compute engine makes overlap impossible.
4. Map the complete modifiable production-source set. Emit
   `baseline_operator_map`: bind each semantic role to the supplied baseline's
   actual file+symbol, inputs/outputs, math, layout, and synchronization.
   Existing kernels are implementation references, not mandatory call sites.
   For each fused region choose `reuse`, `extract_shared`, `inline`,
   `rewrite_equivalent`, `rewire`, or `extend` according to the target schedule.
5. Produce complete runnable candidate directions. Full and profitable partial
   fusion are both legal; diagnostics are controls inside a candidate turn, not
   candidate outputs.
6. Emit `mega_plan_ir` version `mega-plan-v2`. It is the machine-readable
   lowering authority; prose never replaces it. A matched Skill may populate
   operator-specific IDs and `parameters`, but no operator name is built into
   the schema.
   `owned_subdomain` is a direct `work_domains[]` field; never place it under
   that domain's `parameters`, because contract paths and downstream relation
   checks address `work_domains[id=...].owned_subdomain`.
   When the target guards fall in different regimes on the regime map, the
   regimes need their own structures. Add `target_by_bucket`, keyed by each
   target's capacity (e.g. `"64"`, `"8192"`), with one complete `target` per
   bucket derived from that bucket's measured regime, and keep `target` for a
   direction that names no bucket. A Skill's structure applies only to the
   buckets its evidence covers; do not impose it on a bucket in another regime.
7. When `EXPERT_SKILL_PLANNER_EXTENSION` is the canonical Skill file, read its
   embedded YAML and require `schema_version=expert-skill-planner-extension-v1`, matching
   `revision`, and `plan_version=mega-plan-v2`. Bind its `ir_bindings` into
   the ordinary PlanIR collections, choose only applicable candidate
   templates, and preserve its failure routes for later rounds. Never copy
   an extension-only field into the core schema: put domain-specific values
   under the relevant `parameters` object. If `primary_loop` declares the
   truthful scalar `queue_selection`, preserve it and its `carried_state`
   exactly; do not invent a global `queue_priority`. Extensions that declare
   `queue_priority` keep the existing behavior. Before use, run
   `EXPERT_SKILL_BUNDLE_TOOL EXPERT_SKILL_ID --emit-bundle` and require all
   three supplied SHA-256 identities and the supplied validation status to
   match. For an experimental Skill, require `auto_apply:false` and
   `explicit_pin_modes` to contain `EXPERT_SKILL_USAGE`. Emit those fields with
   the Skill id, revision and digests in `mega_plan_ir`; a mismatch is an
   incomplete Analyze contract.
   In `plan_round`, a path ending in `planner_guide.md` is intentionally the
   compact routing projection: follow it together with the already-derived
   `MEGA_PLAN_IR` and current `contract_failures`; do not require it to repeat
   the YAML extension or full implementation contract.
8. Write `analysis.json`, `codebase_context.md`, and `roadmap.md` under
   `EVAL_DIR`. `analysis.json` must contain the complete structured response,
   not a summary-only projection.

Return the ordinary analysis schema with this lowerable IR shape:

```json
{
  "kernel_type": "source language",
  "kernel_file": "primary frozen source",
  "entry_point": "operator entry",
  "modifiable_files": ["on-path production source"],
  "bottleneck_guess": "memory|compute|latency|overhead|unknown",
  "roadmap_summary": "source-derived summary",
  "baseline_operator_map": [{
    "role": "semantic role",
    "file": "baseline-relative production file",
    "symbol": "source-defined function/class method",
    "kind": "host|kernel|numerical_body|epilogue|state",
    "semantics": "math, quantization and routing behavior",
    "inputs": ["typed/layout input"],
    "outputs": ["typed/layout output"],
    "layout": "memory/layout contract",
    "synchronization": "ordering/publication contract",
    "action": "reuse|extract_shared|inline|rewrite_equivalent|rewire|extend",
    "target_role": "role that will call the reused body",
    "proof": "source signature/dataflow evidence"
  }],
  "candidate_directions": [{
    "id": "direction",
    "title": "complete runnable direction",
    "specialty": "compute|memory|distributed|host_runtime",
    "candidate_id": "stable lane id",
    "candidate_source": "search",
    "base_candidate_id": "frozen_baseline",
    "focus_files": ["production source"],
    "prompt": "implementation and measurement objective",
    "target_shape": {
      "launches": 1,
      "stages_fused": ["region_a", "region_b"],
      "require_overlap": true
    },
    "target_topology": {
      "launch_count": 1,
      "included_regions": ["region_a", "region_b"],
      "included_queues": ["queue_a"],
      "capabilities": ["item_level_overlap"],
      "require_overlap": true,
      "parameters": {}
    }
  }],
  "prior_art": [],
  "task_graph": {},
  "resource_timeline": {},
  "mega_plan_ir": {
    "plan_version": "mega-plan-v2",
    "expert_skill_id": "matched id or null",
    "expert_skill_revision": "matched revision or null",
    "expert_skill_bundle_sha256": "matched bundle digest or null",
    "expert_skill_planner_extension_sha256": "matched extension digest or null",
    "expert_skill_validation_status": "validated|experimental|null",
    "expert_skill_auto_apply": false,
    "expert_skill_explicit_pin_modes": ["authoring", "candidate_validation"],
    "target": {
      "launch_count": 1,
      "required_regions": ["region_a", "region_b"],
      "required_queues": ["queue_a"],
      "required_capabilities": ["item_level_overlap"]
    },
    "work_domains": [{
      "id": "items", "unit": "tile", "extent": "runtime expression",
      "index_type": "i32",
      "owned_subdomain": {
        "unit": "subtile",
        "extent_per_claim": "compile-time expression",
        "linear_index": "claim * extent + subtile"
      }
    }],
    "regions": [{
      "id": "region_a", "role": "producer",
      "work_domain": "items", "engine": "engine id"
    }],
    "buffers": [{
      "id": "payload", "role": "intermediate", "element_type": "dtype",
      "capacity": "symbolic expression", "address_space": "global",
      "format": "layout/transport", "producers": ["region_a"],
      "consumers": ["region_b"], "lifetime": "generation",
      "alias_group": ""
    }, {
      "id": "final_output", "role": "output", "element_type": "dtype",
      "capacity": "symbolic expression", "address_space": "global",
      "format": "layout/transport", "producers": ["region_b"],
      "consumers": [], "lifetime": "generation", "alias_group": ""
    }],
    "counters": [{
      "id": "ready", "element_type": "i32",
      "capacity": "symbolic expression", "scope": "agent|system",
      "lifecycle": "per_launch|monotone", "reset_owner": "owner or none",
      "generation": "generation expression", "producers": ["region_a"],
      "consumers": ["region_b"], "publish": "operation", "wait": "condition"
    }],
    "queues": [{
      "id": "queue_a", "work_domain": "items", "claim_unit": "tile",
      "owner": "workgroup", "shards": 1, "stride_bytes": 64,
      "chunk_policy": "expression", "ready_when": "condition", "priority": 0
    }],
    "events": [{
      "id": "edge", "producer": "region_a", "consumer": "region_b",
      "scope": "agent|system", "counter": "ready",
      "publish": "operation", "wait": "condition"
    }],
    "abi": {
      "entry_point": "compiled entry",
      "arguments": [{
        "id": "payload", "type": "pointer<dtype>", "role": "input",
        "source": "runtime owner", "consumers": ["region_a"], "optional": false
      }],
      "parameters": {}
    },
    "resources": {
      "arch": "target architecture",
      "workgroup": {"wave_size": 64, "wave_count": 1, "thread_count": 64},
      "local_memory": {
        "total_bytes": 1, "limit_bytes": 1, "allocation_rule": "sum|max",
        "allocations": []
      },
      "registers": {
        "vgpr_max": null, "sgpr_max": null,
        "scratch_bytes_max": null, "source": "awaiting emitted artifact"
      },
      "occupancy": {
        "compute_units": 1, "grid_blocks": 1,
        "min_workgroups_per_cu": 1,
        "requires_full_grid_residency": false
      },
      "engines": [{"region": "region_a", "pipe": "engine id"}],
      "parameters": {}
    },
    "schedule": {
      "primary_loop": {
        "kind": "unified|phased",
        "carried_state": ["state"],
        "queue_priority": ["queue_a"],
        "progress_invariants": ["why work cannot starve or deadlock"]
      },
      "policies": {},
      "parameters": {}
    },
    "compiler_constraints": [{"id": "shape", "rule": "MUST/MUST NOT rule"}],
    "evidence_requirements": {
      "activation": "observable",
      "accuracy": "metric and threshold",
      "launch_count": "measurement",
      "liveness": "replay contract",
      "performance": "paired score"
    },
    "known_unknowns": []
  },
  "kk_operator": null,
  "kk_language": "source language",
  "kk_refs": []
}
```

Before returning, mechanically require non-empty `modifiable_files`,
`candidate_directions`, task-graph nodes/edges, resource-timeline pipes, and
all required MegaPlanIR collections (`counters` may be empty only when no event
uses counter-based synchronization). Every queue references a declared work
domain; every region references one; every event/counter producer and consumer
is declared; every `buffers[].producers` and `buffers[].consumers` entry is a
declared region id — a terminal output buffer that the host returns out-of-graph
MUST use `"consumers": []` (an empty array), NEVER a non-region sentinel such as
`host_return`, `host`, or `output`, which the plan-IR validator rejects as an
unknown consumer; ABI buffer IDs and capacity expressions agree with source-derived
work domains.

When an Expert Skill is supplied, inspect its PlanIR assertions before
returning. Every `schedule.policies` key referenced by those assertions MUST be
present with the exact required semantic value; never return an empty policies
mapping for a pinned Skill. These values are the machine-checkable bridge from
the Skill to Author and structural Verify, not optional roadmap prose.

## PHASE=plan_round

Inputs include `ROUND`, `BUDGET_REMAINING`, `PROFILE_SUMMARY`,
`CURRENT_BEST_PER_CASE`, `HISTORY`, `MEGA_CANDIDATE_REGISTRY`,
`MEASUREMENT_CALIBRATION`, `ROADMAP_LADDER`, `OPEN_RUNGS`, `TASK_GRAPH`,
`RESOURCE_TIMELINE`, `MEGA_PLAN_IR`, guards, score configuration, and optional
`STRUCTURAL_ONLY`, plus `BASELINE_OPERATOR_MAP` and `MEGA_STALL` (`rounds` without new runtime
evidence, and its `limit`). A Skill-enabled run may additionally provide
`EXPERT_SKILL_PLANNER_EXTENSION`, Skill identity, and the bundle/component
digests listed for Analyze.

Plan exactly one complete candidate direction:

1. Continue recoverable WIP before opening a duplicate lane. The controller binds every round to
   the active WIP lane, so changing course needs one of two explicit, reversible exits (never a
   silent rename):
   - `rewind_head` + `rewind_reason`: roll the SAME lane back to an earlier commit of its own history
     (e.g. the last commit that still had the required work-unit/publication structure). The old
     HEAD is tagged, not lost.
   - `park_candidate_id` + `park_reason` with a NEW `candidate_id`: freeze the active lane (status
     `parked`) and start a structurally different lane from `frozen_baseline` or a scored parent.
     A parked lane is resumed later by naming it as `candidate_id` (parking the then-active lane
     in the same direction).
   Use an exit only for a structural reason stated in the reason field (see 11); never to escape a
   bug that is merely unlocalized.
   To keep pushing a direction that is right but unfinished, name it again: put the essential task
   (what to change or measure, and why, in one sentence) in `title` and its files in `focus_files`.
   While a WIP lane exists the Author's `prompt` also carries the lane state (and some orchestrator
   versions replace your prompt with that state entirely), but `title`, `focus_files`,
   `graph_refs` and `roadmap_rung` always reach the Author.
2. Consume `contract_failures` structurally. Order categories:
   `plan` → `correctness` → `abi` → `lifecycle` → `resource/compiler` →
   `schedule` → `performance`. Required failures are blockers; each carries a
   `tier`: `semantic` failures (a broken behavioral invariant) are routed like
   runtime blockers, `surface` failures (spelling/plumbing of names) never
   outrank runtime evidence. `STRUCTURAL_CONTRACT_POLICY` is authoritative: when
   it is `advisory`, no contract failure keeps a coherent checkpoint off the card,
   even if the TASK text calls the contract a preflight gate. If a matching
   `failure_routes` entry exists in the Planner Extension, use its
   `repair_intent`, checkpoint, focus files and proof requirement; do not
   replace the structured route with a prose guess.
3. Derive implementation from the task graph and MegaPlanIR. Consume
   `BASELINE_OPERATOR_MAP`: use the supplied implementations as concrete
   references and choose reuse, extraction, inlining, or equivalent rewriting
   to fit the fused schedule. Preserve observable math, dtype/layout and routing
   semantics unless current-run correctness validates an intentional change. A matched Skill is an
   evidence-qualified prior at its declared validation status, not a special lane.
4. Preserve the operator-neutral `target_topology` fields. A partial terminal
   must declare `rung_deviation`; it remains a complete runnable operator. A terminal at or under
   the plan's launch count is refused before authoring unless its `included_regions`,
   `included_queues` and `capabilities` contain every id in `MEGA_PLAN_IR.target.required_regions`,
   `required_queues` and `required_capabilities`, spelled exactly; copy those ids verbatim every
   round (add your own after them), including when you continue a lane. When
   `MEGA_PLAN_IR.target_by_bucket` exists, set the direction's `bucket` to the capacity it
   changes and satisfy that bucket's target instead.
5. Keep any verified above-baseline candidate as fallback. While budget remains,
   continue toward the configured Skill target; budget exhaustion is a normal
   stop.
6. Under `STRUCTURAL_ONLY=1`, finish the declared target topology without GPU
   claims and stop only at a current-revision contract pass.
7. When a `performance` blocker is actually a graph-replay **liveness** failure —
   the fused kernel deadlocks or is reaped as a hang under capture+replay and the
   round retreats to a coarse cross-rank barrier that serializes the stages —
   treat *diagnosis* as the blocker, not another speculative overlap rewrite.
   Before spending a round on another readiness/arrival edit by guess-and-check,
   require a host-readable diagnostic first: on spin-timeout each stuck consumer
   writes `{observed, target}` (its counted arrivals against its expected
   `topk*generation`) into a host-visible scratch slot, and the readiness wait is
   bounded (cap iterations → dump → exit cleanly) instead of infinite. This turns
   an information-free hang into a one-shot classification in a single run —
   coverage/accounting (target advanced past what was published, e.g. a per-
   generation counter not re-armed across the replay boundary) vs visibility
   (published but not observed) vs under-publish — and a minimal replay-only smoke
   (smallest guard, capture + two replays, no stage re-captures) makes the
   diagnostic loop seconds rather than a full round. A round that lands this
   instrumentation is progress even with no speedup; the fast overlap the Skill
   describes only becomes reachable once the deadlock is *located*, not guessed.
8. Do not regress a landed, replay-safe partial win while chasing overlap. If the
   stage1 per-bucket tuned tile schedule is already wired (dispatch rules
   populated, its isolated time at the Skill's target), keep it wired across
   resumes and rungs — the coarse-barrier base plus the tuned tile table is the
   fallback to protect, and the remaining gain is the stage overlap that (7)
   unblocks. `PROFILE_SUMMARY.analysis_result` may reorder directions only when it
   is `ready`, its evidence is complete, its confidence is medium/high, and its
   input is this lane's `PROFILE_SUMMARY.candidate_evidence` (same candidate id and
   HEAD). An `awaiting_measurement`/low-confidence result may only choose the NEXT
   MEASUREMENT, never a code direction; a baseline-only route comparison is not a
   fused-vs-baseline delta.
9. Suspect your implementation before the Skill's contract. The Skill is a
   deconstruction of a known-working reference, so when your implementation of a
   Skill-specified invariant deadlocks or misbehaves, the null hypothesis is that
   *your realization of it is wrong*, not that the invariant is wrong. You MUST
   NOT replace a Skill-specified contract — e.g. never-reset, epoch-scaled arrival
   counters with a monotone `topk*generation` target — with a home-grown
   alternative (a per-generation reset, a parity/double-bank ABA scheme, an
   "absolute" retargeting) until step 7's host-readable `{observed, target}`
   evidence pinpoints the *invariant itself* as violated. A symptom like "the
   cumulative count is off by ±1..2 per token" is evidence of a **non-idempotent
   producer** (a per-n-block arrival bump not gated to a single wave, or missing
   its system-release fence ordering — so redundant waves double-count), NOT of a
   brittle target: fix the producer's idempotency/fence and keep the contract.
   Abandoning a proven contract on a deadlock you have not yet localized is the
   failure this rung exists to stop; record the localized cause in `notes` so the
   next round inherits the conclusion instead of re-litigating it.
10. Judge progress against the frozen denominator, not a moving self-reference.
    The headline speedup is the fused candidate's rank-max over the **frozen
    scattered baseline** rank-max on the same machine, which is fixed and needs no
    re-measurement. Do not treat a prior candidate's own scattered fallback arm
    (the same tree run with the activation switch off, which regresses when the
    fused path is broken) as the denominator, and do not re-open a "machine got
    slower vs the code regressed" debate from that arm's number — a scattered arm
    that reads far above the frozen baseline is the candidate's own regression, not
    a stale baseline. If a paired base other than `frozen_baseline` is used for
    incremental A/B, still report the frozen-relative number so the direction is
    chosen against the fixed target. The controller re-bases any score whose paired
    base drifted >5% from the frozen row and records `denominator_mismatch`; a lane
    carrying it has a shared-code regression (or ran the wrong tree) that is its
    first blocker.
11. Judge the ARCHITECTURE by its ceiling, not by the current end-to-end score. Fusion
    only removes waiting (launch gaps, tails, cross-rank barriers); it never removes
    work (GEMM compute, data movement, atomics). Read the lane's
    `component_breakdown` (per-component busy vs wait time, standalone or ablation
    measurements) and `hot_path_counters`:
    - Construction phase (the fused structure is not complete yet): never park or
      rewind because of a low e2e score; a correct-but-slow checkpoint is expected.
      Check only correctness and the Skill's blocking invariants.
    - A component whose WORK is slower than its frozen counterpart (e.g. a copy,
      an epilogue, a publish path) is a component defect: fix that component; do not
      abandon the architecture for it.
    - Large WAIT with baseline-level work means overlap is unfinished: keep building.
    - Rewind or park only when (a) the lane's committed structure violates a blocking
      invariant that cannot be restored incrementally (e.g. the work unit was
      coarsened), or (b) work plus unavoidable wait already exceeds the target
      latency even with perfect overlap. When the breakdown is missing, the next
      direction is the measurement (ablation: disable one component, re-time), not a
      rewrite.
12. `MEGA_STALL.rounds >= MEGA_STALL.limit` means the lane produced no new runtime
    evidence for that many rounds. The next direction must produce evidence on the
    banked HEAD (bounded on-card smoke, the bounded `{observed,target}` diagnostic of
    rule 7, or an ablation), not another GPU-free authoring batch. At twice the limit
    the controller stops the wave.

Return the ordinary `PLAN_SCHEMA` with at most one `search|integrated`
direction; the optional direction fields `rewind_head`/`rewind_reason` and
`park_candidate_id`/`park_reason` carry the exits of rule 1. Return `stop:true`
only when no WIP is recoverable and no distinct evidence-backed direction
remains.
