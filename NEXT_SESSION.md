# Crucible — Open Problems & Next Build Priorities

> This document is a handoff for the next engineering session.
> Read ROADMAP.md first for full architectural context.
> These are the gaps that matter most, in priority order.
>
> **STANDING RULE (added 2026-07-03, keep this at the top forever):** the section immediately
> below — CURRENT STATE — is the only part of this file guaranteed to be current. It must be
> REPLACED (not appended to) at the end of every session, before that session ends. Everything
> under "SESSION LOG" further down is a dated archive: useful for history/rationale, but NOT to
> be treated as the current open-items list. This rule exists because a stale, pre-session-N
> snapshot of this file has already been fed as live context to a later session at least once
> (2026-07-03) — the fix is a summary block that gets overwritten, not just more appending.
> If you are reading this file and it does NOT have a CURRENT STATE section immediately below,
> or that section's "last updated" commit/date looks old relative to `git log -1`, treat it as
> untrustworthy and re-derive open items from the SESSION LOG archive and a live repro instead.

---

## CURRENT STATE — last updated cont.88, 2026-07-17, commit `3f59fb8` (REPLACE THIS EVERY SESSION)

**cont.88 ran the A/B the cont.87 pause asked for. Result: the cont.82 extraction failure is
MODEL-bound, not prompt-bound — and Bonsai fixes it.**

Fixture = the frozen cont.82 evidence (`audit-traces/p4/t9.evidence.txt`, contains `z.ipv4();`
verbatim at line 20) + "Write a Zod schema that validates an IPv4 address" + the verbatim
`GROUNDING_SYSTEM`. **Only the model differs.** Harness: `audit-traces/p7/ab_evidence_copy.mjs`.

| arm | copies z.ipv4 (code) | EXECUTES | latency |
|---|---|---|---|
| Apple FM | **0/3** | **0/3** (jsonSchema 2/3, handRegex 3/3) | 38.5s |
| Bonsai-27B no-think | **3/3** | **3/3** | **45.5s** |
| Bonsai-27B think | **3/3** | **3/3** | 413.6s (9x cost, **zero gain**) |

The FM latches onto the `@vee-validate/zod` **distractor [S3]** over the primary zod docs [S1] and
writes JSON-Schema + a hand-rolled octet regex. Three sessions of prompt work never fixed this
because prompting cannot.

**Latency verdict is BETTER than cont.87c implied:** no-think Bonsai answers in **45.5s**, inside
the FM answer path's existing 25–60s range. The 4.3 tok/s / 15–19s-per-tool-call figure still
stands for *agentic loops*, but the *answer* path is not latency-blocked. **Always run no-think**
(`chat_template_kwargs:{enable_thinking:false}`).

### THE NEXT DECISION (in priority order)

1. **Blocker #1 is now the ONLY thing between this and a real % move — and Bonsai does NOT fix it.**
   Retrieval fetches the WRONG docs (`executed:false` 4/4 live, [[crucible-execution-verifier]]);
   code-shaped + lowercase-library prompts bypass grounding entirely. A 27B handed ip-num docs for
   a zod question still fails. **Fix retrieval/routing next, not the engine.**
2. **Then wire the sidecar** behind the FM's seam (`llama-server` HTTP, `--jinja`, no-think) and
   re-run the *live* answer path — the A/B used a frozen fixture, so it proves extraction, NOT the
   end-to-end pipeline.
3. Open: tool-calling ACCURACY (BFCL 66.03) is still unmeasured; running Bonsai alongside the
   Crucible server is unproven (6% system memory free during generation).

**Build preserved at `.crucible/prismml-bin/` (24MB, gitignored) — do NOT rebuild** (`/tmp`
scratchpads get cleaned; the first build was lost that way). Start:
`.crucible/prismml-bin/llama-server -m .crucible/models/Bonsai-27B-Q1_0.gguf --jinja -ngl 99 -c 4096 --port 8080`

**Gotchas that each faked a result this session** (all fixed in the harness): Bonsai is a REASONING
model (`content` empty until thinking completes → text is in `reasoning_content`); undici's 300s
`headersTimeout` kills non-streaming calls >5min; and the verdict metric must be scored on CODE
only (prose said `z.ipv4()` while the code said `z.string().ipv4()` — which, verified, genuinely
works in zod 4.4.3).

---

## ⏸ PAUSED 2026-07-16 (cont.87 end) — DIRECTION CHANGE: Apple FM → Bonsai 27B

**User paused the Apple FM path** — more debugging overhead than value. Next engine: **Bonsai 27B**
(PrismML, released 2026-07-14, quantized Qwen3.6-27B, Apache 2.0, llama.cpp Metal + MLX), wired
behind the same interface the FM used so it can be A/B'd.

### READ THIS BEFORE PULLING ANYTHING — the 5.9GB number is not the footprint

Web-verified 2026-07-16 (the model post-dates the Jan-2026 training cutoff — do NOT answer from
memory about it):

| | ideal weights | **deployed** | **peak @4K** | peak @10K | tool-calling |
|---|---|---|---|---|---|
| Ternary (1.71-bit) | 5.9 GB | **~7.2 GB** | **8.4 GB** | 8.7 GB | 74.01 |
| 1-bit (1.125-bit) | 3.9 GB | ~3.9 GB | **5.2 GB** | 5.6 GB | 66.03 |
| FP16 baseline | — | ~54 GB | — | — | 80.00 |

HF ternary card verbatim: *"8 GB RAM/VRAM is marginal; the 4K context peak of 8.4 GB leaves minimal
headroom"*; recommends **16+ GB**. **8.4 GB peak exceeds the entire 8 GB machine** before macOS
takes ~3 GB. **Ternary does NOT "comfortably fit" — 5.9 GB is the IDEAL weight size, not deployed.**

**Both variants warn against this exact workload.** Ternary card: *"not yet optimized for
long-horizon, multi-file agentic workflows requiring sustained reasoning chains."* 1-bit card:
*"agentic coding…is not yet a strong target of this release."*

**UNVERIFIED:** "1-bit drops tokens in agent loops past 10 turns" — could NOT be sourced.
MarkTechPost: "identifies no documented failures in multi-turn agent loops." 1-bit HF card: "No
token-dropping warnings are mentioned." Do not treat as fact.

### The REAL ceiling (re-measured cont.87b on an IDLE machine — the earlier finding was WRONG)

**Hardware: MacBook Neo, Mac17,5, Apple A18 Pro, 8GB — PHONE-CLASS silicon, not M-series.** Bonsai's
laptop guidance ("M4 Pro and newer") does not describe this box; its *iPhone* guidance does. PrismML
demos 1-bit on an iPhone 17 Pro (A19 Pro, same family one gen newer) at ~11 tok/s, and a Mac has **no
~6GB per-app iOS sandbox** — so 1-bit has MORE headroom here than on the phone it ships on.

**The ceiling is Metal's working set = 5.33 GB, NOT 8 GB** (`llama.getVramState()` on an idle box —
this is what node-llama-cpp budgets against).

| | peak @4K | vs the 5.33 GB budget |
|---|---|---|
| 1-bit | 5.2 GB | **fits — ~2.5% margin** |
| Ternary | 8.4 GB | **impossible — 1.6× the budget** |

**CORRECTION: the cont.87 claim "phi-3.5-mini CANNOT LOAD — context 4096 too large for available
VRAM" was WRONG.** Re-measured on an idle machine: **phi-3.5-mini (2.23GB) loads in 3.1s @ctx4096;
gemma2-2b (1.59GB) in 2.8s.** The original failure was a DIRTY MACHINE — orphan servers holding VRAM.
**Re-measure model-load limits on an idle box and check orphans FIRST.** A VRAM failure here is far
more often a dirty machine than a real ceiling. This also retracts "phi-3.5-mini, the catalog's best
default escalation target, is unusable on this machine" — it is usable.

### MEASURED cont.87c — 1-bit pulled and tested. IT RUNS. Memory was never the problem.

`Bonsai-27B-Q1_0.gguf` (3.54 GiB) → `.crucible/models/` (gitignored). Loads and serves on the A18 Pro.

**The "drops tokens past 10 turns" claim is NOT REPRODUCED.** 14-step forced chain (each `unlock()`
returns the code needed for the next call — no shortcut possible): **15/15 valid tool calls, 0
malformed JSON, 0 invalid codes**, completed the chain and reported the answer. No cliff at turn 11 —
turns 11+ averaged **16.9s** vs 23.4s for the first five (turn 1 carries prompt processing).
Harness: `scratchpad/toolloop.mjs`.

| measured @ctx4096 | value |
|---|---|
| Metal VRAM used | **3.85 GB of 5.33 GB budget** (1.49 GB free) — better than the card's 5.2GB peak |
| generation | **~4.3 tok/s** (card claims ~11 tok/s on iPhone 17 Pro / A19 Pro) |
| prompt eval | ~19 tok/s |
| **per tool call** | **~15–19s** → 15-turn loop = **~5 min** |
| system memory free during run | **6%** — co-residency with the Crucible server is UNPROVEN |

**THE REAL BLOCKER IS LATENCY, NOT MEMORY.** 4.3 tok/s makes agentic loops minutes long. The answer
path already costs 25–60s.

**Integration cost: `Q1_0` is NOT upstream llama.cpp.** Needs the PrismML fork
(`github.com/PrismML-Eng/llama.cpp` — Q1_0_g128; Metal kernels present). **node-llama-cpp 3.19.0
CANNOT load it.** Build: `brew install cmake`; `cmake -B build -DGGML_METAL=ON -DLLAMA_CURL=OFF`;
`cmake --build build -j6 --target llama-server`. Run as an HTTP sidecar with **`--jinja`** (required
for tool calling). Not in-process.

**Caveat:** this proves multi-turn STABILITY, not tool-calling ACCURACY (BFCL 66.03 is separate; the
chain used one trivial tool).

### Revised recommendation

**1-bit runs; ternary remains impossible** (8.4GB peak vs the 5.33GB budget). The decision is no
longer memory — it is whether **~4.3 tok/s / 15–19s per tool call** is acceptable. That is a product
call and the only thing between this and shipping.

Headroom: 1.49GB spare @ctx4096 → dspark drafter (+1.79GB) does NOT fit; vision tower (+0.63GB) does.
`iogpu.wired_limit_mb` can raise the Metal working set if needed (risky at 8GB, but real).

If latency is acceptable → wire `llama-server` as an HTTP sidecar behind the FM's seam and A/B
against the real failure: **will a 27B model COPY an identifier out of clean evidence where the ~3B
FM refuses?** (cont.82). That is the one thing this pivot can actually fix.

### Caveat worth surfacing (not to bury)

cont.87 MEASURED that the model was **not** the top blocker: retrieval fetches `ip-num` /
`ip-address@npmjs` instead of zod.dev, and code-shaped prompts skip grounding entirely. **A 27B
model still gets handed the wrong docs.** The pivot DOES target one real measured failure — the ~3B
FM won't copy an identifier out of clean in-context evidence (cont.82) — which a 27B model
plausibly fixes. But blocker #1 is retrieval, and no engine swap touches it. ROADMAP's north star
also says correctness comes from the loop, never "needs a bigger model" — flagging the tension; the
call is the user's.

---

## CURRENT STATE (last updated 2026-07-16 cont.87 — **THE ORACLE NOW EXECUTES (`da813cb`). It killed the gaming class regex could not reach. But its MEASURED LIVE REACH IS ZERO: `executed:false` on 4/4 live runs. The blocker is no longer the oracle — it is RETRIEVAL. Do not extend the verifier; make it reachable.**

### cont.87 — built the execution verifier, then measured that it never runs

`src/CrucibleEngine/reasoning/executionVerify.ts` (`npm run vgr:execverify`, 23/23). The answer
path's first oracle that RUNS the code instead of pattern-matching names.

**Principle — a STRUCTURAL error is INPUT-INDEPENDENT:**
- `ipv4Schema.validate is not a function` → throws for EVERY input → the code is broken.
- `ZodError: invalid ip` → throws for SOME inputs → the code is WORKING.

So reject only when EVERY generic probe dies structurally. No input synthesis, no per-question test
data, no library knowledge — universal, not a per-request band-aid.

**Differential on the REAL captured artifacts (name-match → EXECUTION):**

| artifact | name-match | EXECUTION |
|---|---|---|
| FM laundered `extend(ipv4Schema,{...})` | CERTIFIED | **VIOLATIONS** (`extend is not a function`) |
| qwen object-literal `.safeParse` | CERTIFIED | **VIOLATIONS** (`safeParse is not a function`) |
| correct canonical zod | CERTIFIED | CERTIFIED |

`extend` is not a real zod export — execution kills the exact laundering hole cont.86b left open,
and the catch is not bought with false rejects.

`certifyAnswer()` is now the SINGLE oracle for BOTH the shipped badge (groundedAnswer) and the
repair search (faithfulRepair) — they must agree, or repair optimizes against a weaker gate than
the one that ships. It MERGES exec+name verdicts (exec-only shadowed the fabricated identifier →
the search stopped accumulating negative info; vgr:faithrepair caught it with 7 FAILs). The exec
repair hint quotes the verbatim runtime error — un-gameable by name-dropping, since the next
candidate is re-executed.

Gate: vgr:execverify 23/23 (both directions pinned), vgr:apifaith 71/71, vgr:faithrepair 67/67,
bench:all 1164/1164 (+23), tsc delta 0. Live-verified on clean tree `d7e29aa` (no `+dirty`).

### THE FINDING — the gate has never opened

**4/4 live runs: `executed: false`.** The oracle is correct and wired, and has never actually
executed on live traffic. Measured blockers, in priority order:

1. **Code-shaped prompts bypass grounding entirely.** "Using zod, show the code to validate an
   IPv4 address" → answered in **PYTHON regex**; groundedAnswer never ran.
2. **Retrieval fetches the WRONG library.** Live hosts across runs: `ip-num`, `ip-address@npmjs`,
   `deepwiki`, `docs.astro.build`. **Never zod.dev.** An evidence-relevance gate is the blocker.
3. Evidence-documented library not installed → honest abstain (cannot execute).

Read it, do not assume: `CRUCIBLE_DUMP_FAITH=<path>` in the **server** env writes
`.verdict.json` carrying `executed`; the `answer_certify` debugBus event reports it per request.

**So the % did NOT move.** Same trap as cont.84's unreachable gate: benches green, gate never opens.

### NEXT CRUCIAL ITEMS

1. **Evidence-relevance gate + retrieval routing** — the top blocker for BOTH correctness and the
   new verifier's reach. A zod question must retrieve zod.dev, not ip-num. Abstain (do not
   synthesize) when the evidence never mentions the asked-about subject.
2. **Route code-shaped prompts through grounding** — "show the code" currently skips the grounded
   answer path entirely, which is how a zod ask gets answered in Python.
3. **Then re-measure execution reach** (`executed:true` rate). Only after it is non-zero does
   extending the oracle mean anything.
4. **Then** re-open the second-proposer seat with `qwen2.5-1.5b` (loads, ~10-22s, emits real code;
   `phi-3.5-mini` and `gemma2-2b` CANNOT LOAD on this 8GB machine — VRAM).

---

### cont.86b — the finding that reframes the whole line of work

Asked to try a code-tuned GGUF in the second-proposer seat, the screen surfaced something much
bigger. **Read a "certified" artifact instead of the verdict:**

```js
const { base64, cidrv4, cuid, email, extend, ipv4, string, … } = require('zod');
const ipv4Schema = { type:'object', properties:{ ip:{ type:'string', pattern:'^(25[0-5]|…' } } };
const validateIpv4 = (ip) => ipv4Schema.validate(ip);
```

JSON Schema with a hand-rolled regex — the *exact* substitution the verifier exists to catch —
**CERTIFIED**. `escalatedRepairHint` hands the model the documented surface; the FM pastes the list
into a decorative import, so every identifier is provably documented. **Repair converted an honest
UNVERIFIED into a false green badge.** cont.86's "FM certified 4/4" was 4/4 certifications of
broken code — the number was reported without reading the artifacts. Do not trust it.

**Fixed (`3752be6`), two independent defects, BOTH required:**
1. `verifyEvidenceUsage` abstained on ANY import. Its premise ("that failure imports nothing at
   all") was falsified by repair — repair is what puts the import there. Now: **use is a CALL,
   never an import.** The express-vs-zod foreign-import abstain is preserved.
2. `verifyApiFaithfulness` returned `certified` the instant no per-identifier violation was found,
   **never consulting the whole-answer check**. Fixing (1) alone would have been INERT — a dead
   feature behind a green bench (the cont.84 lesson, nearly repeated). Provenance is necessary,
   not sufficient. `vgr:apifaith` 59 → **71**; `bench:all` **1141/1141**.

**STILL BROKEN — measured after the fix.** The FM's next artifact calls ONE documented API
decoratively (`extend(ipv4Schema, {…})`) and certifies again:
`answer calls documented APIs (extend) — it used the evidence` → abstain → `certified`.
**One documented call launders an entire JSON-Schema answer.** That "ANY overlap certifies"
asymmetry is deliberate (cont.79h: a false reject is worse) and is now the remaining hole.

**THE LESSON:** every regex tightening closes one path and the generator finds the next. You cannot
regex your way to correctness. The doctrine already says the oracle must be deterministic and
EXECUTABLE — the code path executes candidates; the answer path judges them by pattern-matching
names. **That is the gap, and it is the next thing to build.**

### The second-proposer question, answered

- `phi-3.5-mini` (3.8B, the catalog's "best default escalation target") — **cannot load**:
  "context size of 4096 is too large for the available VRAM". Same for `gemma2-2b`.
- `qwen2.5-1.5b` — **loads, ~10-22s, emits real code, CERTIFIES** where MiniCPM only narrated. It
  passes the screen MiniCPM failed.
- **But its code is broken too** (`const s = { type:'object', properties:{…} }` then
  `s.safeParse(…)` — an object literal has no `.safeParse`; it throws). The verifier certified that
  as well.
- `qwen2.5-3b` ("best code understanding of the set") is **not downloaded** (~1.9GB).

**So the seat stays empty, on purpose.** Seating a second proposer now would only find
certifiable-broken candidates faster. **Fix the oracle before adding proposers** — with a verifier
that cannot tell correct from broken, every proposer A/B measures a meaningless number.

### cont.86 — the standing instruction, executed and then MEASURED

The long-orphaned standing instruction (seat MiniCPM5-1B alongside the Apple FM in every repair
loop) is now implemented in `faithfulRepair.ts` and was live-verified reachable at `e1057fe`
(t17 emitted "Bringing in a second on-device model (MiniCPM)"; the loop rotated afm → minicpm →
afm). Then it was A/B'd on the real captured draft+evidence pair, N=4 per arm:

| arm | certified | avg latency | MiniCPM-earned |
|---|---|---|---|
| FM only | 4/4 | **11.9s** | — |
| FM + MiniCPM | 4/4 | **29.7s** | **0** |

**MiniCPM abstained on every call.** Across 5 calls — the prose-shaped repair hint AND a
code-shaped positive prompt built to `miniCpmHarness`'s own documented convention — it narrated
instead of emitting code, deterministically (identical 2878-char output every run).

**The detail that decides it:** it wrote `zipv4()` for `z.ipv4()` sitting verbatim in the
evidence. That is the *same* cont.82 "won't copy an identifier out of clean evidence" failure as
the FM. A second proposer only pays for its latency if it fails **independently** — this one does
not. So it ships OFF (`CRUCIBLE_FAITH_ALT_MS=0`; set to `25000` to re-enable). The premise of the
standing instruction is intact and the mechanism is built — the *engine* is what's wrong.

**Caveat on those numbers, stated plainly:** the A/B's system prompt is a SIMPLIFIED stand-in, not
the live `GROUNDING_SYSTEM`. The relative MiniCPM result is sound (same prompt in both arms, and it
abstained under two different prompt shapes), but **4/4 is not the live certify rate — live is still
0**. Live t18 (clean tree, `e98ad97`) shipped a JSON-Schema answer, honestly badged UNVERIFIED.

### What shipped this session (committed, benches green, tsc delta 0)

1. **Second-proposer rotation** — `faithfulRepair.ts` (`e1057fe`). `completeAlt` is optional and
   injected; absent → byte-for-byte the cont.84 single-proposer search.
   - **Rotation keys off an ATTEMPT COUNTER, never `history.length`.** A whiffing proposer returns
     null; `search()` retries the SAME slot free of charge *without growing history*, so
     history-keyed rotation re-selects a dead engine forever and starves the FM. Verified
     load-bearing: keying on history makes the alt monopolize 6 of 7 slots, FM 3 calls → 1.
   - Attribution (`Candidate.source` → `FaithfulRepairResult.proposedBy`) — this is what made the
     feature falsifiable; without it "MiniCPM earned 0" is unknowable.
   - Adapter uses the RAW pool completer, not `miniCpmAnswer` (its prose wrapper injects
     "2-5 sentences" and sabotages code output).
   - `vgr:faithrepair` 41 → **67**. `bench:all` **1129/1129** across 35 suites.

2. **Defaulted OFF on the measurement** (`e98ad97`) — see the table above.

### NEXT CRUCIAL ITEMS (cont.86b — this list is the current one; §5 further down is archive)

1. **EXECUTE the answer path's code — the oracle, not another proposer.** This is now the only
   item that matters, and everything else is downstream of it. `htmlRuntimeVerify.ts` and the code
   path already execute candidates; the answer path judges by regex and the FM games it. Extract
   the answer's code block, run it in the existing sandbox against the question's own claim
   (`z.ipv4().parse('1.2.3.4')` succeeds, `parse('999.1.1.1')` throws), and certify on BEHAVIOUR.
   That kills the whole gaming class at once — a JSON-Schema object literal throws on `.parse`,
   and no amount of documented name-dropping survives it. **Do not tighten another regex.**
   Note the honest limit: only executable answers can be certified this way; the rest must abstain,
   which is correct (abstain means abstain) and strictly better than a gameable green badge.
2. **Then, and only then, re-open the second-proposer seat.** `qwen2.5-1.5b` is the live candidate
   (emits code; MiniCPM does not). The mechanism is built and benched (`vgr:faithrepair` 67/67);
   A/B it with `audit-traces/p6/ab_minicpm_experiment.ts`. A proposer A/B measured by a gameable
   verifier is a meaningless number. **Also: `phi-3.5-mini` and `gemma2-2b` cannot load on this
   machine (4096-ctx VRAM) — the catalog's "best escalation target" is unusable here.**
3. **Evidence-relevance gate** — do not synthesize when the evidence never mentions the subject.
3. **Capitalization / code-shape routing** — MEASURED AGAIN this session: "Using zod, how do I
   validate an IPv4 address? Show the code." is classified `promptType: coding`, bypasses grounding
   entirely, and answers a **zod** question in **Python with a hand-rolled regex** (t16). Lowercase
   library name + "show the code" = the verifier never runs. This is most real prompts. Universal fix.
4. **A live gate-reachability assertion.** Three dead/inverted features in three sessions.
5. **Code-aware `GROUNDING_SYSTEM`** — still a prose prompt that code asks get routed into.

### cont.85 — the fix asked for, plus the worse half of it nobody had seen

`§1` below has the full account. The short version: cont.84 recorded the false certify's cause as
the page title — **that was wrong**. It was the member rule `\.\s*(\w+)`, whose `\s*` crosses a
prose sentence boundary (`addresses.\nZod v4`). Fixing it surfaced the real problem: the same
function ALSO false-REJECTED `import { z } from 'zod'` (a `length > 1` floor meant `z` could
never be documented), so the repair loop was being pointed at correct code — the cont.79h
failure mode, live, behind a green bench. `vgr:apifaith` 48 → 59; `bench:all` 1103/1103.

**The transferable lesson (now a METHOD rule):** a verifier has two failure directions. cont.84
measured only the one it went looking for. When you find a false certify, feed the verifier the
KNOWN-CORRECT answer in the same breath and assert it certifies.

### What shipped (all committed, benches green, tsc delta 0)

1. **Repair is a search** — `reasoning/faithfulRepair.ts` (`4f0883c`). Reuses the existing VGR
   `search()` rather than adding a second loop; the mapping is just: candidate = an answer,
   verifier = `verifyApiFaithfulness`, spec.context = the evidence.
   - The draft enters as candidate 0 marked `modelFree` → costs no budget, and competes with its
     own repairs under one verifier.
   - A repair replaces the draft ONLY on a strict verifier-measured improvement. Ties → draft
     (violation count is a PROXY, not ground truth).
   - An abstaining "repair" can never win (deleting the code escapes judgement ≠ certification).
   - K exhausted → ship the draft UNVERIFIED and report the ceiling.
   - `escalatedRepairHint` accumulates identifiers already proven absent.
   - `npm run vgr:faithrepair` 41/41, scripted model, ZERO model calls. In `bench:all`.

2. **The repair gate was dead code** (`c27c015`) — the find that matters most this session.
   The gate was `remaining() > 4000` where `remaining()` is the RETRIEVAL budget:
   `DEFAULT_BUDGET_MS` = 14s, but `SYNTH_TIMEOUT_MS` = 30s and a real run takes 32–71s. So
   `remaining()` is tens of seconds NEGATIVE when the verifier rules → **the branch could never
   open**. Measured at `4f0883c` on a clean tree: gate fired, badged UNVERIFIED, emitted ZERO
   `api_faithfulness` events. **cont.83's "repair attempted, failed to certify" was only ever
   true because that server had `CRUCIBLE_GROUND_BUDGET_MS=90000` in its env.** On defaults it
   had never run once. Fix: repair gets its OWN clock (`CRUCIBLE_FAITH_BUDGET_MS`, default 60s,
   0 disables) — the same precedent `SYNTH_TIMEOUT_MS` already sets in that file.
   **This is the grounding-dead class again: wired code, green benches, a gate that never opens.**

3. **`CRUCIBLE_DUMP_FAITH`** (`c0455a5`) — env-gated dump of (evidence, answer, verdict) at the
   gate. Point it OUTSIDE the repo (e.g. the scratchpad) or the dump dirties the tree and your
   next boot banner reads `+dirty`. Not optional: a hand-reconstructed evidence block gave 306
   chars vs the real path's 2984 and a different verdict.

### LIVE, on a clean tree (banner `db5073c`, no `+dirty`, default env)

Identical prompt ("Write a Zod schema that validates an IPv4 address"), same commit, **different
outcomes run to run** — retrieval ranking varies, and it decides which failure you see:

- **t11 — the search works.** Gate fires on the JSON-Schema substitution (`ignored-evidence`) →
  repair 1 ignores the docs → repair 2 fabricates `toTypedSchema` **again, despite the escalated
  hint naming it as already-rejected** → ships UNVERIFIED honestly, K spent.
  **Detection→recovery is now MEASURED, not assumed: escalating negative feedback does not stop
  this model re-proposing a name it was just told is absent.**
- **t12 — the verifier FALSE-CERTIFIES.** Answer: `import { Zod } from 'zod'` +
  `Zod.Schema<IPv4Address> = {...}` object literal + hand-rolled regex — a total fabrication
  (zod exports no `Zod`; the real API is `z.ipv4()`). Verdict: **`certified`, green badge.**

### §1 FIXED (cont.85, `3192b64`) — the vocabulary bug fired in BOTH directions

**cont.84's recorded cause was WRONG.** `Zod` does NOT enter from the page title "Defining
schemas | Zod" — measured against the real captured evidence, the title never enters. The
culprit is the member rule `\.\s*(\w+)`, whose `\s*` spans a **sentence boundary**:
`...email addresses.\nZod v4` parses as a member access. Same path admitted `Perfect` from
`instantly. Perfect for learning`, `Alternative`, `Install`, `It`.

**The half nobody had noticed is the worse half.** `add()` dropped identifiers of length ≤ 1, so
`z` could never be documented — meaning `import { z } from 'zod'`, the canonical zod import,
with `const ipv4 = z.ipv4();` sitting in the evidence, was reported as a **fabricated
identifier**. Measured on t11 evidence, pre-fix, the verifier was exactly inverted:

| answer | pre-fix | post-fix |
|---|---|---|
| `import { Zod }` (total fabrication) | **certified** | violations |
| `import { z } from 'zod'` (canonical, correct) | **violations** | certified |

So every zod answer the repair loop opened on was being told to "fix" correct code — the
cont.79h failure mode, live and unnoticed, behind a green bench.

**Fix, at the harvester** (universal — every consumer shares this vocabulary): the dot binds
tight (no whitespace either side, so prose cannot match while chained `\n  .min()` still does);
dotted access harvests the namespace **root** too (`z` in `z.ipv4()`); the length floor is gone
(single-char namespaces `z`/`_`/`$` are the norm for this import class). Dropping the floor and
harvesting roots only ADD to the vocabulary — the safe side of the asymmetry.

Surviving prose noise is DELIBERATE: `foo (v4)` still reads as a call (the `\b(\w+)\s*\(` rule
keeps its `\s*`), because tightening it would drop `function foo (a)` from real docs and
manufacture false rejects. Over-inclusion costs a missed check; under-inclusion costs a false
reject. Do not "finish the job" here without a bench proving the false-reject direction.

`vgr:apifaith` 48 → **59** (11 new: both directions on REAL t11 evidence, sentence-boundary,
chained-call, lodash single-char guards; each fails pre-fix). Live-verified on a clean tree
(`3192b64`, no `+dirty`): t14/t15 — gate fires, K=3 escalating repairs, none certify, honest
UNVERIFIED. Both rejects **earned** (answers were JSON-Schema literals with zero zod API against
evidence containing `ipv4`). The named-import class is not reproducible on demand live —
retrieval variance picks the shape — which is why the bench pins it with captured evidence.

### §2 Retrieval fetched evidence that cannot answer the question

t12's evidence block contains **zero** occurrences of `ipv4` (`grep -c ipv4` = 0) — the fetched
zod pages were the general schema docs, not the IP-address section, even though `search()`
ranks `zod.dev/api?id=ip-addresses` **first**. So on that run no model could have written
`z.ipv4()` faithfully. Grounding proceeded and badged green anyway. **A grounded answer whose
evidence lacks the asked-about API is not grounded — it is decorated.** Consider gating on
"evidence mentions the subject of the question" before synthesizing.

### §3 Capitalization routing (unchanged from cont.83, still open)

`"zod schema"` → no grounding; `"Zod schema"` → grounds. Lowercase package names are what users
type, so the verifier is inert for most real prompts. Universal fix only (ground-by-default vs a
case-insensitive structural signal) — a package-name table is BANNED.

### Bench state
`vgr:faithrepair` 41/41 · `vgr:apifaith` **59/59** · `ground:bench` 41/41 · `vgr:retrieval` 28/28
· `vgr:decompose` 35/35 · **`bench:all` 1103/1103 across 35 suites** · tsc delta 0 (443
pre-existing under `tsconfig.server.json`; measure the baseline with `git stash -u` — a plain
`git stash` leaves new untracked files orphaned and inflates it). **`tsconfig.json` is a
project-references shell: `tsc -p tsconfig.json` reports 0 errors and checks NOTHING. Always use
`tsconfig.server.json`.**

### METHOD (cost this session real time — read before citing any live run)
- **Boot banner `+dirty` is the tell.** It fires on untracked files too — trace dumps you just
  wrote count. Point dumps outside the repo. NOTE `audit-traces/p4/.token` is TRACKED, so
  re-minting it dirties the tree; mint to the scratchpad instead.
- **Verify the exit code, not the tail.** `npm run <bench> | tail -1` prints nothing for benches
  whose summary is `N/N passed`; three different summary formats are in use.
- **Check the dump's mtime against the run window.** A dump file left from the previous run reads
  exactly like a fresh result (t15 nearly got reported from t14's dump).
- **Never diagnose from a reconstructed evidence block.** Dump from the real path.
- **A green badge means "nothing I check is broken."** t12 was the proof: certified ≠ correct.
- **A verifier has TWO failure directions.** cont.84 reported only the false certify and the
  false reject sat undetected in the same function — when you find one, test the other by
  construction: feed it the KNOWN-CORRECT answer and assert it certifies.

## PRIOR STATE (last updated 2026-07-16 cont.83 — **WEB GROUNDING WAS 100% DEAD ON COMMITTED CODE for 3 sessions. Fixed (1c8bc46). API-faithfulness verifier built and LIVE (2ec8b3a): it DETECTS the fabrication; repair does not yet recover the answer.**

### 1. The headline: every faithfulness diagnosis since cont.82 was made against code that never ran

`d6d02d1` ("Phase 2a: fix the grounding routing gate", cont.81b) deleted
`return { block, sources, titles }` from `gatherEvidence` in `answer/groundedAnswer.ts` and added
nothing back. The function is typed `Promise<Evidence | null>` and fell off the end → `undefined` →
`answerWithWebGrounding`'s `if (!ev)` bailed → **grounding returned null on EVERY query**. Search
ran, pages were fetched, evidence was assembled, then discarded one line before the return.

Why nobody noticed for three sessions:
- The sessions that "verified grounding" ran a **dirty working tree** that still had the line
  (`c1f04e5+dirty` grounded fine at 16:45). The 16:50 commit dropped it and **was never live-run**.
  All of `audit-traces/p2` — the traces that produced the evidence-faithfulness diagnosis — came
  from that dirty tree.
- `tsc` is silent: `strict:false`, no `noImplicitReturns`. A missing return on a non-void function
  is not an error here. **Do not trust tsc to catch this class.**
- cont.82's own handoff claimed "confirmed on current code" — its last trace (`t4-rf2`, 16:47)
  **predates the 16:50 commit**. The claim was never true.

Measured, same prompt/server/daemon: before → `"No usable web sources"` (0 sources); after →
grounded in 3 sources, cites `zod.dev/api?id=ip-addresses`. Traces in `audit-traces/p3`.

**METHOD (this is the recurring killer — it has now bitten three sessions running):** the boot log
prints `running commit <sha>+dirty`. **Read it, and compare the server's start time to your edit
mtime, before citing ANY live run.** cont.82 recorded this rule and still shipped a false claim.
`+dirty` means the tree ≠ the commit: a green live run proves nothing about what you committed.

### 2. API-faithfulness verifier — BUILT, LIVE, and honest about its limit

`reasoning/apiFaithfulness.ts` (`npm run vgr:apifaith`, 48/48, in `bench:all`). Pure, model-free.
The VGR thesis applied to the answer path: stop asking the model to be faithful, CHECK it.

Two checks:
- **per-identifier** — named imports / namespace members bound to a package the evidence documents,
  rejected when the identifier appears nowhere in it. Catches the live `import { Schema } from 'zod'`
  and `require('zod').validate()`.
- **whole-answer** (`verifyEvidenceUsage`) — code that neither imports nor calls ANY documented API.
  This is the **dominant live failure** (JSON Schema substituted for the library). It has no bad
  identifier to point at, so the per-identifier check alone reported `abstain` and did nothing. The
  live run is what surfaced this; the bench alone would not have.

**Soundness rules — do not loosen these without a live false-reject measurement.** Only provable
library references are judged. Bare `foo()` and members of locals (`schema.parse()`) need type
inference we don't have → never judged. Everything ambiguous → `abstain`: thin evidence,
undocumented package, shell fence, trivial snippet. The whole-answer check fires ONLY on
import-free code — the bench caught a real false reject during development (express code judged
against zod docs read as "ignored the evidence"). cont.79h stands: a false reject is worse than a
missed check, because it teaches the repair loop to "fix" correct code.

Q10 from the last handoff is **closed**: prose `ipv4()` and code `z.ipv4()` normalize to the same
bare name, so a docs table certifies a namespaced call (benched).

Wiring in `groundedAnswer`: verification is free → runs on every grounded answer; only a real
violation spends a model call. A repair is accepted **only if the verifier certifies it** (swapping
one fabrication for another is not progress). On failure we deliberately do NOT return null — the
caller's fallback is a *parametric* answer (more fabrication, no citations) — we ship the grounded
draft badged **UNVERIFIED**. The previously unconditional `verify: passed: true` would have stamped
a green badge on an answer just proven fabricated (the cont.79h failure); it is now conditional.

### 3. What is STILL broken — the number does not move yet

**LIVE, on working grounding:** "Write a Zod schema that validates an IPv4 address" → grounds 3
sources → **cites zod.dev** → **emits JSON Schema anyway** → gate fires → repair attempted → **repair
does NOT certify** → ships UNVERIFIED. Detection works. **Recovery does not.** The user-visible
answer is still wrong; it is now *labelled* wrong instead of badged green. That is strictly better
and still not a correct answer.

So cont.82's core finding SURVIVES, and is now measured on genuinely-working code rather than a
dirty tree: **the ~3B FM will not copy an identifier out of clean in-context evidence.** One
repair retry does not fix it.

### 4. SECOND live bug found, NOT fixed — grounding routing is capitalization-dependent

`namesExternalLibrary` (`retrieval/retrievalLayer.ts:170`) detects libraries via **capitalized**
proper nouns and skips any token containing a digit (the IPv4 carve-out). Measured:

    namesExternalLibrary("Write a zod schema that validates an IPv4 address") === false   → NO grounding
    namesExternalLibrary("Write a Zod schema that validates an IPv4 address") === true    → grounds
    namesExternalLibrary("Use zod to validate an email")                      === false
    namesExternalLibrary("Use Zod to validate an email")                      === true

Users type lowercase package names constantly (`zod`, `express`, `numpy`, `react`). For them the
grounding lane is **silently closed**. This is why the first live run of this session didn't ground
and briefly looked like a verifier bug.

**Do NOT fix this with a library-name lookup table** — that is a memorized template and is banned
(see `crucible-no-templates-universal-fix`). The honest options are (a) let retrieval decide rather
than a lexical guess (the ground-by-default north star, which cont.81 measured as NOT actually
implemented for code-shaped prompts), or (b) a case-insensitive structural signal. This is a real
design decision, not a patch — it was left alone deliberately rather than scope-crept.

### 5. Next crucial items

1. **Make repair actually recover the answer.** Detection is done; the loop still fails. The VGR
   answer is not "one retry with a hint" — it is **search**: K candidates, keep any that certifies
   (`keepK.ts` already exists), and escalate the hint each round. If K attempts still fail, that is
   the honest measured ceiling of the FM on this task and belongs in the report.
2. **Capitalization-dependent routing (§4)** — the verifier is inert for lowercase library asks,
   which is most real prompts. Universal fix only.
3. **Code-aware system prompt** on the grounded path. `GROUNDING_SYSTEM` is still a PROSE prompt
   ("120-250 words", "do NOT append an Example section") that code-shaped prompts get routed into.
   Proven necessary-but-insufficient in cont.82's A/B; pairs with #1 and is cheap.
4. **A live regression bench for grounding itself.** A one-line deletion killed the entire feature
   and 968-check `bench:all` stayed green, because no check asserts "grounding returns evidence"
   (cont.80b: the suite is model-independent BY DESIGN). One live check that asserts sources > 0
   would have caught this in seconds.
5. Code path fetches source, not READMEs. App-build path (Task 3's class, untouched, biggest lift).
6. Re-run Phase 1's five tasks — still the only thing that moves the number.

### 6. Percent to goal — **~38%, unchanged**

The grounding fix is large (it restores a whole feature that was dead), but it restores capability
that the last three sessions' reports *already assumed was working*, so it corrects the books rather
than adding to them. The verifier detects the dominant fabrication and refuses to certify it, which
removes a false-green badge — real, but the answer the user reads is still wrong. Nothing here
changes how a session feels yet. **Do not inflate on "verifier shipped".**

Run: `npm run vgr:apifaith` (48/48) · `vgr:bench` 208/208 · `ground:bench` 41/41 ·
`retrieval:bench` 18/18 · `vgr:retrieval` 28/28 · `conversational:bench` 108/108 · tsc delta 0
(443 pre-existing project-wide, unchanged by this session — note cont.82's "tsc 0" claim was
scoped to server.ts only and reads as stale).

Live repro recipe: `audit-traces/p3/fire.sh <name> "<prompt>"` (needs a JWT cookie — see
`crucible-local-auth-testing`), or drive `answerWithWebGrounding` directly, which is faster and
bypasses server routing entirely (the probe that isolated all of this).

---

## PREVIOUS STATE (2026-07-13 — MODIFY/CREATE + RENAME path hardened end-to-end; answer engine gains consensus premise verifier; 441/441)

**This session (10 commits cfede63→5d35906, branch crucible-northstar-sessions) — the offline modify/create/refactor loop and the answer engine each closed their remaining verification holes, most surfaced by LIVE /api/chat testing that the deterministic benches structurally can't (they feed clean f(x)===y lines).**

- **Whole-tree signature propagation — aliased-import hole fixed** (cfede63): reconcileCallSites used the export name even when a sibling did `import { pad as p }`, so `p(…)` call sites were missed → broken aliased call shipped. `importedLocalNames` resolves aliases.
- **Embedded worked-example extraction + entry-from-examples** (e21a96f): examples inside prose ("For example pad('hi',5) returns '   hi'") + multi-per-line were dropped → VGR got 0 examples and abstained on ordinary modifies; entry was misread from stray prose ("takes **only**(s,width)"). Now scans embedded `call SEP literal` pairs; `entryFromExamples` infers entry from the demonstrated call.
- **Retry-until-certified, single + multi-file** (e95d545, 71981dd): the on-device proposer certifies an ordinary modify ~50% per attempt; bounded (CRUCIBLE_VGR_ATTEMPTS=3) abort-aware retry lifts it to ~88%+. Pure upside — VGR abstains honestly, so retry never ships a wrong write. Live 4/4.
- **Multi-file gold-path harvest fix** (fcf0373): declared-in-prose fns weren't seeding `extractSpecExamples` → weak-FM exhaustion; seed with `detectDeclaredFunctions` → live-certifies "create two files" in one attempt.
- **Behavioral example gate** (3bf9689): the agent-loop fallback shipped `unverified` when a project had no test script; now runs the request's stated examples against the written files via `verifyMultiFileCode`. examplegate:bench 4/4.
- **Consensus-vote premise corrections** (c2fe8f0): the first consensus verifier on the ANSWER engine — `checkPremiseGrounding` samples K=3 votes, ships a correction only on a strict majority that agrees on the DISPLACED fact (ignoring shared question subject). Kills the lone-hallucination World-Cup class. premise:bench 8/8.
- **Whole-tree RENAME refactor** (e75f0bf, 77b053e): deterministic (0 model calls) `planRenameTree` renames def + importer specifiers + call sites, alias-preserving, all-or-nothing (abstains on bare-value use / collision / re-export barrel), each rewrite compile-verified. `rename` added to isCodeEditTask. Live-confirmed 3-file rename, project tsc-clean.
- bench:all **441/441** across 13 suites (registered the 2 new suites, 5d35906); prove:all 251/251; tsc clean throughout.

**⚠ TYPECHECK DISCOVERY (cont.66n, 882389d):** `tsc -p tsconfig.json` checks NOTHING (files:[] + unbuilt
refs). The REAL typechecks are `npx tsc -b` (app project = `npm run build`) and `npx tsc -p
tsconfig.server.json --noEmit` (server.ts + src/CrucibleEngine/** + src/server/**). server.ts is in NO
build ref and bundle:server uses esbuild, so it carries ~486 PRE-EXISTING type errors nobody sees; it's
only validated by tsx-runtime benches. AFTER editing server.ts / src/CrucibleEngine, run the
server-config check and grep for YOUR files. New src/server/*.ts must be excluded from tsconfig.app.json
and included in tsconfig.server.json (done). This surfaced a real latent bug: server.ts:4507/4550
`withStaticPrefix('string')` (needs an array) threw on every multi-part-answer section, swallowed by
try/catch → empty sections; fixed by passing the plain string (callModel already applies the preamble).
A future cleanup could get server.ts to zero type errors and add tsconfig.server.json to CI.

**server.ts decomposition STARTED (3758ffc, cb04397, be826c7, 94187c0, d0e6181)** — pattern: extract a self-contained
cluster into a new `src/server/*.ts` module (pure or encapsulated-state), leave a THIN wrapper in
server.ts so every call site is unchanged (minimal diff = merge-safe vs the parallel session), and add
a committed bench. Done so far: `src/server/jwt.ts` (HS256 sign/verify + cookies, now constant-time, jwt:bench 9/9),
`src/server/textVector.ts` (paraphrase-cache token-cosine, textvector:bench 7/7), `src/server/latency.ts`
(LatencyTracker + percentile, latency:bench 6/6), `src/server/util.ts` (withTimeout +
estimateMessageTokens + conversationTitle, util:bench 11/11). Live auth re-verified after the crypto
change (200/401/401). Continue with more pure/cohesive clusters the same way; leave the hot
request-handler bodies (the real contention surface) alone. bench:all now 477/477 across 17 suites.

**MOVE-function refactor primitive built but NOT wired (357fece)** — `planMoveTree` in emitPlan.ts moves
a self-contained function between files (repoints/splits importers, re-imports into source if still
used, all-or-nothing, compile-verified; abstains on non-self-contained defs / collision / re-export).
Left unwired on purpose while the parallel type-debt session owns server.ts. TO WIRE: add a ~20-line
pre-VGR block mirroring the rename short-circuit (detectMove + gather siblings via collectProjectTsFiles
+ write primary+propagated + emit tool_call/verify/final), and add 'move' to isCodeEditTask's editVerb
regex. vgr:bench 160/160.

**NEXT (open):** wire planMoveTree (above) once server.ts is free; continue server.ts extraction (cache cluster state, conversation persistence, token
estimation) — LOW risk while it stays "extract pure helper + thin wrapper + bench"; broaden
answer-engine consensus beyond premise checks; behavioral verification for non-example
creative/interactive code (still outside any gate). RENAME limits: only named function exports,
bare-value uses abstain, transitive re-export chains abstain (not chased).

---

**cont.68d (commit d8d7f0c, branch crucible-northstar-sessions) — HTML game verifier + a STALE-NOTE correction.**
Investigated the standing "#1 gap: HTML/canvas behaviorally unverified" and found it STALE: a real
Electron-backed runtime verifier (`agent/htmlRuntimeVerify.ts` + `htmlVerifyMain.cjs`) has been WIRED
into the live build path since the 2026-07-07 trust audit — `synthDriver.ts` calls
`validateHtmlGame(html) ?? await runtimeVerifyHtml(html)` at the emit gate. It loads the artifact
offscreen in bundled Electron and rejects (with FM-repair hints) on: runtime JS errors, no/blank
canvas, blank-until-keypress, NaN/undefined/Infinity readouts, keyboard-registered-but-never-fired,
FROZEN (not self-animated AND input-inert), and INVERTED left/right controls (ink-centroid probe).
Electron gate confirmed working on this Mac; `__html_invariant_bench.ts` was 4/4. ADDED one new
invariant: **terminal-state-on-load** — a game that reads "game over"/"you lose"/"you died" from frame
0 (FM initialized `gameOver=true`, or spawned the player already colliding) is rejected. Snapshotted at
LOAD, before the harness's synthetic key bursts, so a legitimate game-over the harness itself triggers
can't false-trip it; loss/over phrases only (never "win" — appears in instructions). New bench case
(draws+animates+takes input exactly like the GOOD game but reads GAME OVER on load) → rejected; html
invariants **5/5**, `bench:all` 413/413, tsc clean. Corrected the stale note in the memory index +
`crucible-contextual-understanding-fix` so future sessions don't re-chase a closed gap.

**cont.68c (commit 32041c5, branch crucible-northstar-sessions) — SEMANTIC recall closes the lexical gap.**

**cont.68c (commit 32041c5, branch crucible-northstar-sessions) — SEMANTIC recall closes the lexical gap.**
Lexical recall (`selectMemory`) matches shared salient TOKENS, so a back-reference sharing no words
with its target ("that pastry ingredient stock thing" → a turn about "bakery … flour and sugar
inventory") scored 0 and dropped under budget. NEW `buildRecallContextAsync` (`answer/conversationMemory.ts`)
adds a bounded, best-effort SEMANTIC supplement: when the lexical pass is THIN (vague/back-reference
query — few salient tokens, or almost nothing matched), it embeds the query + the older turns lexical
missed (on-device MiniLM via `masterpiece/corpus/embed`, cached, ≤120 candidates scanned, ≤3 added)
and pulls in the closest by cosine (floor **0.22** — measured: related 0.24–0.37, unrelated ~0). The
well-specified-query fast path pays ZERO embedding cost (early-return before any embed); ONNX-
unavailable degrades to the hash fallback (≈lexical, no regression); `CRUCIBLE_SEMANTIC_RECALL=0`
disables. `answerEngine` awaits it. **LIVE-VERIFIED with the cached ONNX model:** lexical drops the
bakery turn, semantic recovers it, an unrelated "champions league" query does NOT false-pull it.
`memory:bench` +3 (→18), `bench:all` **413/413**, tsc clean. This closes the semantic half of TOP-NEXT
item (2). NOTE: the misnamed `state/semanticIndex.ts` is a CODE-symbol index, not text embeddings —
the real embedding stack is `masterpiece/corpus/embed.ts` (ONNX all-MiniLM-L6-v2, cached on this Mac).

**cont.68b (commits 30a1e0b, 13d3308, branch crucible-northstar-sessions) — two TOP-NEXT items closed:**

- **(item 3) Lighter `definition` sub-intent — latency win on simple "what is X".** A bare
  definition ("what is a hash map", "define recursion", "what does idempotent mean") was classified
  `explain` by the EXPLAIN regex and decoded the full ~1100-token intuition→detail→example budget
  (~19s on the weak FM, measured cont.67). NEW `'definition'` `AnswerIntent` in `answer/answerEngine.ts`:
  `isDefinitionAsk()` fires BEFORE the explain branch on a bare term-definition shape, but is gated
  OFF by an explanatory expander (`how/why/works/example/difference/…` → the user wants depth → stays
  `explain`) and by entity-fact lookups (`capital of X`, a mid-sentence proper noun → stays on the
  web-grounded `lookup` path). Short **384-token** budget + a concise 2-4 sentence prompt (definition
  first, then one concrete example, stop). Fully contained — `AnswerIntent` is consumed nowhere but
  `answerEngine.ts` (the agent-side `intent` is unrelated). `answer:bench` +6 (→133), `bench:all`
  **410/410**, tsc clean. DETERMINISTICALLY verified (classification + budget + prompt wiring); the
  latency drop follows mechanically from the token cap (Apple FM latency ∝ output tokens) — NOT yet
  re-measured live under the current 2-server daemon contention.
- **(item 2a) Long-horizon recall threaded into the web-grounding path.** `answerWithWebGrounding`
  (`answer/groundedAnswer.ts`) took only the last 4 verbatim turns — a grounded follow-up lost the
  turn-1 anchor + relevance-retrieved older turns the DIRECT path already folds in. `GroundOpts` gains
  `recallBlock`; it is appended to `GROUNDING_SYSTEM` as the same authoritative "earlier in this
  conversation" block; `answerEngine` passes `recall.recallBlock` through. tsc + `bench:all` 410/410.
  LIVE-UNVERIFIED (string fold on the network+FM path; needs a real grounded follow-up run).

**PRIOR (cont. 68, commit 5b6074b) — LONG-HORIZON CONVERSATION MEMORY: turn 500 recalls turn 1; layered on cont.67's web gap-closing + streaming + canonical-title ranking**

**cont.68 (commit 5b6074b, branch crucible-northstar-sessions) — user asked for two things: (a) long-conversation memory (remember message 1 at message 100/500) and (b) large coherent outputs for complex builds without truncation/hallucination.**

**BUILT + LIVE-VERIFIED (a) — long-horizon conversation memory (the primary ask):**
- `answer/conversationMemory.ts` NEW. The strict answer path was pre-slicing history to the last 6
  turns (forgets everything older); other callers dumped the whole log (overflows the FM window,
  silently truncating the middle). Neither recalled an early fact late in a long chat. Fix bounds
  arbitrary-length history to the model window by SELECTING turns (no summarization → no per-turn FM
  calls, no hallucinated summary): **recency** (last K verbatim) + **anchor** (turn 1 always kept —
  sets topic/task/persona) + **relevance** (older turns scored by salient-token overlap, retrieved).
- **Two channels** the weak FM handles far better than one giant chat log: `buildRecallContext()`
  returns `recentTurns` (verbatim immediate thread) + a `recallBlock` string of the older selected
  turns, folded into the SYSTEM PROMPT as a labeled "Earlier in this conversation (facts the user
  told you — authoritative)" block — the same evidence-block pattern the FM reliably reads for web
  grounding. Plus a recall-grounding directive in the base prompt so "what's my name" quotes the
  user's fact instead of answering with the assistant identity.
- `server.ts` strict call site now passes FULL history to answerQuery (the memory layer bounds it),
  not a blind `slice(-6)` that stripped turn 1. (`histSlice` still bounds the coarser
  solveNonCodeTurn fallback — that path was not the recall path.)
- **LIVE-VERIFIED on real /api/chat:** 120-turn convo → "My name is Sam … app called DoughTrack"
  (turn-1 recall); 200-turn convo → "Postgres HYENA schema" (turn-42 recall); empty-history 2+2
  still clean. New `memory:bench` 15/15 in `bench:all` → **390/390 across 10 suites**, tsc clean.
- DEBUG SEQUENCE (don't relearn): fixed 3 layered bugs live — (1) FM answered with its own identity
  ("I'm Crucible") → recall-grounding prompt line; (2) FM parroted/refused a raw multi-turn history
  → switched to the system-prompt evidence-block channel; (3) THE real blocker: server pre-sliced to
  6 turns so turn 1 never reached the memory layer (debug showed total:6 for a 120-turn payload).
  Lesson: always check what history the SERVER actually forwards, not just the module in isolation.

**(b) large coherent outputs — BUILT + LIVE-VERIFIED (commit 00bfb5b):** for CODE builds the
anti-truncation mechanism already existed (multi-file VGR synthesis: per-file compile/behavior-
verified units). For long PROSE/single-response builds, `answer/longOutput.ts` NEW adds
truncation→CONTINUE. The Swift daemon can't signal truncation (hardcodes `finish_reason:"stop"`,
omits `completion_tokens` even when cut at 10 tokens — probed live), so `detectTruncation()` reads
the OUTPUT with HIGH-PRECISION signals only: an unbalanced ``` fence, or near-budget output that
doesn't end on a sentence/structure boundary. answerEngine's direct path runs a bounded
continuation loop (explain/reason/converse; `CRUCIBLE_LONG_CONT=0` disables, `LONG_CONT_ROUNDS`
caps at 3): resume "from exactly where it stopped", `stitchContinuation()` de-dupes repeated
overlap, streams as it goes; a safety net closes any still-open fence when rounds are exhausted.
LIVE-VERIFIED: a "thorough B-tree index" build fired 2 continuations → 8051 chars (vs ~4400
single-budget); "what is a hash map" finished in budget → 0 continuations (no false extension).
`longout:bench` 14/14. HONEST LIMIT: a HUGE build can still outrun 3 rounds (the B-tree one did —
the fence-close net kept it renderable); latency of a continued answer is high (~4min for the
B-tree under 2-server contention) but only paid when truncation is actually detected.

---

## PRIOR STATE (cont. 67 — AGENTIC WEB GAP-CLOSING + TOKEN STREAMING + CANONICAL-TITLE RANKING)

**cont.67 (commits 1a4bf8b→a124a3d, branch crucible-northstar-sessions) — NORTH-STAR REFRAME by the user:** parity closes by **web lookup/understanding/retrieval in real time**, NOT by memorizing or by adding models. The brain's job is metacognition — know what it doesn't know and close the gap the way a person does: look it up. Follow-up-abstain / 0-output / weak-explain are ONE bug: gap → dead-end instead of routing to research.

**Built + live-verified (via direct answerQuery calls + retrieval tests; real FM + real web):**
1. **Retrieval core rebuilt** (`src/CrucibleEngine/retrieval/retrievalLayer.ts`). SERP scraping is DEAD (confirmed live: DuckDuckGo html+lite → HTTP 202 anti-bot, Bing/Mojeek → JS-shell, SearXNG → 403/429). Replaced with **domain-routed keyless STRUCTURED APIs**: coding → StackExchange (+ npm for packages), factual → Wikipedia REST search. Browser-UA; salient-token relevance gate (drops off-topic backends whole — a React query no longer surfaces "Firefighting"); `encyclopedicQuery()` strips "how does…work" so Wikipedia ranks the right noun; eager-caches SO answer bodies + fuller wiki extracts so `fetch()` returns real content. **7/7 burst queries relevant (was 3/6, all coding broken).**
2. **Web-grounded answering** (`answer/groundedAnswer.ts`, wired into `answerQuery`). search → parallel fetch (per-fetch cap) → cited evidence → FM synthesizes a grounded answer with inline [S#] citations + a sources footer; emits live "searching/reading/grounding" steps; returns null → parametric fallback when the web is empty. Fixed a real bluff: a React-concept question that used to hallucinate now pulls StackOverflow.
3. **Metacognitive gap-gate** (`shouldResearch()` in answerEngine). Only specialized/technical/recent/proper-noun-heavy queries hit the web; general/basic answer directly (**~3-4s** fast path). Live 5/5 correct routing.
4. **`fmComplete` maxTokens** (Apple FM latency ∝ output length); **stateless `completeLocalModel`** + `warmModel` (fixes a latent session-history leak in `callLocalModel`); **MiniCPM harness** (`agent/miniCpmHarness.ts`, `miniCpmAnswer()`) — simple-prompt + reasoning-strip + retry + fallback, 4/4 clean.
5. **TOKEN STREAMING end-to-end (8d1db55)** — the #1 latency fix. Apple FM is decode-bound (~24ms/token), prefill ~1.2s, so streaming is the right lever. Added SSE streaming to the Swift daemon (`local-inference/crucible-fm-daemon.swift`, recompiled + redeployed via `launchctl kickstart -k gui/$UID/com.crucible.fm-daemon`; uses `session.streamResponse`; backward-compatible). Chain: `fmReact.fmStream()` → `groundedAnswer` onToken → `answerEngine` streams synthesis deltas + `result.streamed` → server finalizes with `replace:result.streamed`. **Verified end-to-end on a live PORT=3011 instance:** daemon first-token 0.66s; grounded `/api/chat` streamed 41 delta frames + replace-finalize + sources footer over real SSE.
6. **Council-skip for grounded answers (6adce2d)** — the cont.66k-widened council ran extra peer FM calls after every strict turn (~60s on top of a streamed answer). Grounded answers already carry cited sources → skip council when `usedRetrieval` (90s→54s turn).
7. **Direct-path streaming + fact routing (92963b6)** — the common (non-grounded) answer now streams too (first token ~0.8s, total ~2.7s). And factual lookups (`intent === 'lookup'`) route to the web: the weak FM fumbled "capital of Australia" into a clarify-request; it now grounds to "Canberra" from Wikipedia. `streamed` threaded through the abstain returns so a critic-rejected streamed draft is replaced not appended.

**HARD FINDINGS (don't relearn):** weak Apple FM CANNOT introspect its own gaps (LOOKUP-protocol → refusals; 1-5 confidence → noise) → deterministic heuristic gate. MiniCPM5-1B stochastically leaks plain-text CoT and is NOT better/faster than Apple FM for synthesis → answer path stays on Apple FM + web; harness makes MiniCPM available for agentic roles (not yet wired). Two concurrent server instances share ONE FM daemon (concurrency-1 fmQueue) → test latencies are INFLATED; don't trust absolute ms when another chat's server is running.

8. **Source ranking tightened (339493d)** — rankResults now weights TITLE matches 2x, strips query stopwords, and keeps only sources within ~40% of the top score (drops the tangential long tail). Live: useEffect + rust now pull 3 on-topic SO threads each (was a mediocre single pick).
9. **Deferred council (87c7706)** — the display-only council debate was AWAITED before the final synthesis(done:true), so the client showed "still streaming" through the whole ~15-25s debate. Now the answer's synthesis(done:true) is emitted FIRST, then the council runs and its `local_debate` card streams in after. Verified: parametric turn marks the answer done 45s before [DONE]; council ran in that gap. Answer completion no longer gated by the council.

10. **Canonical-title ranking preference (this session)** — closes TOP-NEXT item (2). `rankResults`
    (answer/groundedAnswer.ts) now subtracts a small, capped penalty for each title CONTENT token the
    query never asked for, so within one salient-overlap tier the base entity article beats its
    derivatives. LIVE-VERIFIED against real Wikipedia: "who wrote Dune" raw order was
    `Dune: Part Three | List of Dune characters | Dune: Part Two | Dune (novel)…` (base novel 4th) →
    ranked top-1 is now **Dune (novel)**; "who wrote Hamlet" → **Hamlet** (the play) first. Parenthetical
    disambiguators ("(novel)"/"(film)") are stripped before counting extras (they're not extra
    specificity); authorship verbs ("wrote/by/author") are in a TITLE_STOP set so they neither score
    nor penalize. Penalty is fractional/capped (max −1.5 vs ±2 per matched salient token) so it only
    reorders WITHIN a tier — a genuinely more-relevant page still wins; the 40% keep-threshold now keys
    on RAW overlap so a verbose-but-on-topic corroborator isn't dropped for title length. New
    `npm run ground:bench` (8/8, deterministic/offline) added to `bench:all` → **370/370** across 9
    suites, tsc clean.

11. **Intent-aware disambiguator tie-break (b437b08, this session)** — closes TOP-NEXT item (4), the
    canonical-title residual. When a query carries a CREATION VERB, same-base disambiguator ties now
    resolve by work type: `rankResults` gives a tiny capped bonus (0.25, < the 0.5 penalty step so it
    only reorders exact ties) to the page whose parenthetical matches the verb's class. "who **wrote**
    Dune" → Dune (novel) over Dune (franchise); "who **directed** Dune" → Dune (film) over Dune (novel).
    Verb→class map (INTENT_DISAMBIG): wrote/authored→novel/book/poem/play; directed→film; painted→
    painting; composed→opera/symphony; sang/recorded→song/album; sculpted→sculpture. Inert without a
    creation verb (stable-sort order preserved). ground:bench 8/8→**11/11**, bench:all **373/373**, tsc
    clean.

12. **Items 1-4 all closed (this session, commit a51337a + latency run):**
    - **(1) Single-server latency re-verified** on a fresh PORT=3011 instance (auth via minted JWT,
      SSE timestamps for first-token / answer-done / stream-end). ISOLATED numbers: direct/explain
      "hash map" firstToken **2.0s**, answerDone 19s (~4800 chars — the explain cap is generous by
      design); lookup "capital of Australia" firstToken **2.3s**, answerDone **7.0s** (659 chars);
      "boiling point" 4.5s/11.4s (970 chars); grounded "useEffect" 2.6s/31.5s. **CONTENTION is the
      inflator, worse than 2x:** the SAME capital lookup measured **68.7s** while the other chat's
      3001 server was actively hitting the shared FM daemon, then **7.0s** isolated (~10x). Streaming
      confirmed working single-user (first token 2-4.5s across all paths). HONEST GAP: explain-intent
      answers are still long/slow (19s) — a simple "what is X" classified `explain` decodes ~1100
      tokens; consider a lighter "definition" sub-intent.
    - **(2) MiniCPM agentic consumer wired** — `corroborateFact` (answer/factConsensus.ts) now adds
      MiniCPM (GGUF pool) as an independent-architecture voter, distinct from the ONNX registry
      voters and sharing no confabulation bias with Apple FM. `isMiniCpmAvailable()` (new, in
      miniCpmHarness.ts) gates it to a no-op when the model isn't downloaded / runtime missing;
      `CRUCIBLE_MINICPM_VOTER=0` disables. LIVE-CONFIRMED on this Mac (the answer:bench jumped
      0.9s→44s from real GGUF inference before I set the flag off in the bench to keep its
      NO-model-calls contract).
    - **(3) Direct-path length caps** — `maxTokensFor(facets)` in answerEngine.ts caps output per
      intent (lookup 320 / converse 448 / explain 1100 / reason 1536) and the converse system prompt
      was tightened against padding. Live effect visible: lookups now 659-970 chars (were running to
      ~500 verbose tokens). Reason/explain keep their room so a chain never truncates.
    - **(4) Exact-base tie-break** — a title whose content tokens equal the salient entity exactly is
      the canonical article (+0.15, below the 0.25 intent bonus). Closes the bare-same-base residual.
    ground:bench 11→13, bench:all **375/375**, tsc clean.

**TOP NEXT ITEMS (cont.68b):** (1) **latency is the dominant complaint** — a normal answer is ~44s
and a continued build ~4min under 2-server FM-daemon contention. The unstarted big lever: run a launchd
LaunchAgent for the backend so two chats don't share one FM daemon (the 68s-vs-7s root). Secondary:
make the verification lanes (factConsensus/explainCheck/MiniCPM voter/council) opt-in or PARALLEL —
today they serialize extra FM calls per turn (note: they are already intent-gated so usually only ONE
fires; the `definition` sub-intent from 68b now skips them entirely for basic defs). ALSO: re-measure
the definition-intent latency live once the daemon is dedicated (68b verified it deterministically,
not on the wire). (2) **semantic recall:** the memory layer is LEXICAL salient-token overlap — a purely
semantic back-reference ("that thing we discussed") won't retrieve (embedding index
`state/semanticIndex.ts` is the upgrade). [68b closed the recall-into-grounding half — LIVE-UNVERIFIED,
worth a real grounded-follow-up run.] [68c CLOSED the semantic-recall gap — token-less back-references
now retrieve via MiniLM embeddings, live-verified.] Long-output continuation can still outrun 3 rounds
on a huge build (raise the cap for code-gen intents, or detect "still growing" and extend). (3)
HTML GAME builds ARE behaviorally verified (Electron htmlRuntimeVerify wired into synthDriver; 68d
hardened it + corrected the stale "unverified" note). The REMAINING HTML gaps: (a) NON-game interactive
HTML (calculator/form/dashboard/data-viz) has NO behavioral verifier — the runtime gate is game-shaped
(needs canvas + arrow keys); (b) smaller game-verifier gaps with higher false-positive risk (score-
responds-to-gameplay, off-playfield/no-bounds, collision-dead). [DONE: definition sub-intent 68b,
semantic recall 68c, terminal-state-on-load invariant 68d.]

---

**PRIOR — cont.66k (a99e75c) — four user-reported vision gaps closed in one pass:**

1. **Voice CONVERSATION mode (ChatGPT-style):** mic click enters a hands-free loop — listen
   (WebAudio VAD, 1.5s-silence auto-stop) → whisper transcribe → send → reply spoken via
   /api/tts `wait:true` (server resolves AFTER `say` playback so the client knows when to
   re-open the mic) → re-listen. Visible state overlay (breathing orb, Listening/Transcribing/
   Thinking/Speaking + exit ×) floats above the composer; chat populates behind. Two empty
   listens auto-exit. Right-click = one-shot dictation. Overlay DOM-verified in authed preview
   with a stubbed silent stream. UNVERIFIED: a real spoken multi-turn on this Mac (needs a
   human mic).
2. **Attachment contextual awareness:** agent/attachmentContext.ts — /api/chat now folds real
   file CONTENT into the message (text ≤24k/file inlined, images OCR'd on-device via Apple
   Vision swift shell-out, binaries honestly declared, 48k total cap). LIVE-VERIFIED: chat
   answered the launch code from an attached notes.txt; screen-region OCR extracted real text.
3. **Image upload 413:** 25 MB file × ~1.37 base64 inflation blew the route's 25mb JSON cap →
   raised to 40mb. (The visible upload-failure note from 66j is what surfaced this.)
4. **Council/ensemble visibility:** debate gate widened (code|reasoning → +factual, +any turn
   ≥60 chars; classifier's 'speed' default had been starving the council). LIVE-VERIFIED:
   local_debate shipped 3 voices (answer-engine, minicpm5-1b, track-s-fm) unanimous 0.97.

**cont.66l (4280397) — user live-test follow-ups (voice mode CONFIRMED WORKING by user):**
(a) ROUTING POISON fixed — foldAttachmentContext runs at intake, so detectAgentTask matched the
attached file's CONTENT (any .ts attachment contains '.ts' → agent hijack; user's "what can you
tell me about this file?" went to the agent loop). detectAgentTask now strips from the attachment
note/ATTACHED FILE CONTENT marker; live-verified with an agent-baiting .ts file — stays on chat
path, answer analyzes the file. NOTE the pattern: ANY routing regex that sees the folded message
is poisonable — classifyIntent/buildTurn/matchMeta not yet audited for the same. (b) Attachment
chips now render inside the sent user bubble (Round.attachments[] → MessageList), so attachment
turns are visually distinct; preview-verified chip + content-aware answer + COUNCIL card 3/3 in
one turn.

**cont.66m-b FULL PARITY MAP (no code; user asked for the complete picture, not next-sessions):**
Parity = PRODUCT of pillar floors, not sum of peaks. Pillar scores: synthesis 60% (certified but
narrow triggers + pure-fn-only shapes), modification 25% (scratch-scale only; tests-as-oracle
unbuilt = the research bet that decides the ceiling), agent 40%, conversation 30% (follow-up
abstain + NO long-context story at all), knowledge 25% (corpus coverage is a content-acquisition
project, unscoped), latency 20% (needs stream-then-certify architecture, not tuning), multimodal
30% (no true image understanding; MiniCPM-V-class unexplored), verification moat 45% of own
ambition (effectful code + open-QA unverified; two consensus engines unmerged), robustness 30%
(bench-vs-live class needs adversarial live harness + routing regression corpus; server.ts ~8k-line
monolith is a velocity risk), product 50% (no iOS). THREE TRUTHS: (1) 100% general parity
unreachable on 3B — honest target: EXCEED frontier on verifiable coding (certified>plausible),
"good enough" elsewhere; asymptote ~70-80% felt parity. (2) The distribution has never been
measured — build a 200-real-prompt corpus as the north-star metric; all % are vibes until then.
(3) Tests-as-oracle for repo modification is the bet that moves B 25%->70%. TIERS: 1=floors
(the 5 triage items, ->~50-55%); 2=structural: convo-length scaling, repo-scale modify, live
harness, server split, consensus merge, agent-path attachments (->~65%); 3=ceilings: offline
knowledge corpus, effectful-code verification, vision model, 200-prompt benchmark, iOS
(->70-80%); 4=DECLARED out of reach: frontier knowledge breadth, 100k contexts, taste on
unverifiable tasks — abstain-and-say-why is the UX for these.

**cont.66m AUDIT (no code): parity recalibrated 88% -> ~35-40%** — old % tracked milestone
completion, not distribution coverage (user-felt sessions). Live probes: follow-up turn "which
of those…" -> "I cannot answer that question" (strict-abstain kills multi-turn continuity —
reproduced, #1 user-felt gap); kebab-case ask = 34s AND missed the VGR path (prose-shaped
example not extracted — flagship triggers too narrowly); user-reported second-message-0-output
NOT reproduced server-side (rapid turns fine, debug history clean) — PRIME SUSPECT: 66k council
gate widening puts a 3-voice debate on the shared FM queue nearly every turn -> turn-2
starvation under real load; secondary: client convLiveRound/reconnect. RANKED FOCUS: (1) kill
follow-up-abstain class, (2) repro+fix 0-output under council load, (3) replace regex routing
stack with learned router spine (retires the recurring hijack/starve bug class), (4) per-turn
latency budget w/ progressive certification, (5) VGR prose-example triggers. Feature freeze
until 1-3 closed.

Open follow-ups: real-mic voice-mode multi-turn CONFIRMED by user (66k item closed); barge-in
(speak to interrupt TTS); attachment content should also flow on the AGENT path (only /api/chat
folds it today); OCR swift first-call latency (~1-2s) could be precompiled; audit remaining
routing regexes for folded-content poisoning (same class as (a)).

**cont.66i (68eb42a, 60db198, ea409fa) — four shipped items this session:**

1. **Game-repair loop hardened (68eb42a):** (a) proposer DIVERSIFICATION — alternate Apple FM ↔
   MiniCPM5 (council GGUF, isGgufRuntimeAvailable-guarded) across repair attempts, each seeing the
   other's rejection feedback (breaks the single-model oscillation that dead-ended 6/6). (b) VISIBLE-
   READOUT invariant in htmlRuntimeVerify — verify-copy wraps canvas fillText/strokeText, rejects a
   game whose readout is "Score: NaN"/undefined/Infinity. First game-STATE invariant beyond aliveness;
   directly attacks the cont.66h "runs but logic buggy" ceiling. html:bench 2/2, tsc clean. NOTE: this
   is a start on the behavioral-verifier gap, NOT its closure — physics/movement still unverified.
   **UPDATE cont.66j (5d8844a): SECOND behavioral invariant added — INVERTED-CONTROLS.** The Electron
   harness now drives a Left-only then Right-only burst and measures the horizontal ink centroid each
   phase (CENTROID probe in htmlVerifyMain.cjs); correct L/R controls end the player mass further right.
   Common-mode motion (scrolling obstacles/gravity) drifts both phases the same way and cancels in the
   left→right difference, so only key-driven player motion survives. Rejects ONLY a strong reversal
   (≥18% of canvas width) with a min-ink guard → fail-open (games not using L/R show ~0 delta and pass).
   html:bench now 4/4 on the real Electron gate, stable across repeated runs, tsc clean. STILL OPEN:
   this covers horizontal-direction correctness only; vertical/jump physics, collision, and game-over/
   terminal-state reachability remain syntax-verified. The centroid difference is the reusable primitive
   for the next physics invariant (e.g. gravity = downward centroid drift with no input).

2. **Compound-request routing fix (60db198):** THE user-reported agent bug — "close firefox, then
   youtube X, then brightness 0" executed ONLY the youtube clause. Root cause: resolveSearchAndSelect
   ran BEFORE the compound bail in resolveLocalIntent and fired on any youtube mention, collapsing the
   whole request to one search-and-play. Fix: gate search-select on absence of hard sequencing
   (then/after that) + foreign-action guard on the extracted subject. Now defers to the loop →
   needsPlan() → runPlannedTask decomposes all steps. __intent_bench +3 regressions, all legit
   search-select cases still green.

3. **File upload UI (ea409fa):** the sandbox file-view backend had no upload path. Added POST
   /api/sandbox/upload (base64, 25 MB, basename-sanitised, collision-safe) + composer paperclip button,
   multi-file input, attachment chips; send folds a workspace note into the server message. Live-verified
   write/read/traversal-guard via curl.

4. **On-device voice mode (ea409fa):** whisper.cpp local STT (voiceTranscribe.ts: MediaRecorder→ffmpeg
   16k wav→whisper-cli) + full voice loop (mic dictate + auto-speak replies via existing /api/tts).
   GET /api/voice/status + POST /api/voice/transcribe; reports needsModel when the stack isn't installed.
   Composer mic button (click=dictate, right-click=toggle voice loop) + Settings "Voice" section with
   live per-dep status + install commands. **VOICE ROUND-TRIP NOW VERIFIED (cont.66j, 2026-07-12):**
   stack installed on this Mac (brew whisper-cpp + ffmpeg, ggml-base.en.bin 148MB at
   .crucible/whisper/). Real end-to-end proof: macOS `say` → opus webm → `transcribeAudio()` returned
   `{ok:true, text:"Crucible runs entirely on device without the cloud."}` (exact match, 0 cloud calls);
   `voiceStatus().ready === true`. The whisper.cpp STT path is no longer just plumbing — it transcribes.
   **cont.66j (5fda872): both user-reported composer dead-ends FIXED + authed composer screenshotted.**
   (a) Mic→Settings forever: packaged server cwd = Electron userData, MODEL_PATH missed the repo-
   installed model → voiceTranscribe resolves env→cwd→code-dir (model also copied to userData);
   live-verified authed ready:true + real transcription over HTTP. (b) Uploads silently no-oped on any
   failure: bare relative fetch without apiFetch/API_BASE + swallowed errors → now apiFetch(API_BASE)
   with a visible dismissible failure note; /api/tts + /api/voice/transcribe aligned. Verified in the
   authed preview (JWT-cookie trick): simulated file selection → chip renders; composer screenshot
   confirms (+)/attach/mic/send layout. app/ rebuilt+committed. NOTE: user should re-test in THEIR app
   (vite HMR picks it up in dev; packaged app needs the new bundle).

---

### Prior state — cont. 66h (REFINEMENT TURNS FIXED + 66f/66g LIVE-CONFIRMED)

**cont.66h (4cb3677) — closed the "lower-severity" half of the negotiation-loop failure AND
live-FM-confirmed both cont.66f and cont.66g (which shipped deterministic-only).**

**1. Mid-negotiation refinement turns (the FM role-play hole) — FIXED + LIVE.**
- Symptom: BEFORE a greenlight, the refinement turns ("a simple fps game?", "battle royale",
  "can it be something different?", and bare acks like "thanks, that helps") fell to the weak FM,
  which role-played a planning assistant ("create a Board Game… use Unity or Unreal Engine") and
  built nothing. cont.66g's resolveBuildTurn only handled the greenlight; refinements passed through.
- Fix (`buildNegotiation.ts` + `server.ts`): resolveBuildTurn now also returns action **'clarify'**
  for a refinement turn while a build is established in PRIOR history and NOT yet a greenlight —
  named genre → confirm + honest on-device downscope + invite a one-word go-ahead; contentless
  "different?" → concrete options; **bare ack** ("thanks/cool/got it") → a warm "just say go" nudge.
  server.ts ships the clarify text via an EARLY deterministic short-circuit (like the counting gate,
  before any agent/task machinery — sidesteps the dangling-`running`-status issue that clarifyBuild's
  post-startTask gate has). Conservative: never hijacks a fresh turn, an unrelated aside, or a real
  request that merely opens with an ack word. conversational:bench 67→**87**, tsc clean, bench:all 362/362.
- LIVE-CONFIRMED on real /api/chat: the three refinement turns + "thanks, that helps" all return the
  deterministic reply instead of FM role-play (was: "…use Unity or Unreal Engine").

**2. Whole-tree signature propagation (cont.66f) — LIVE-FM-CONFIRMED (was deterministic-only).**
- Scratch project (`greet.ts` imported+called by `main.ts`), real /api/chat modify. RECONCILE path:
  greet(name,greeting)→greet(name) certified (24 cases, 1 model call, differential consensus); main.ts's
  2-arg call trimmed to `greet('World')`; both compile (clean `tsc -p`) + run → "Hello, World!".
  REFUSE/all-or-nothing path: combine(a,b)→combine(a,b,c) that caller.ts can't absorb → whole edit
  downgraded to a fresh `src/combine.ts`; mathx.ts + caller.ts **byte-identical** (sha unchanged) — no
  partial corruption. Both TreeEmit branches behave live exactly as the bench claimed.

**3. Greenlight → runnable artifact (cont.66g) — LIVE-FM-CONFIRMED end-to-end.**
- Full negotiation history + "i trust you, do your thing" → build_negotiation_resolved → honest
  downscope thought ("a full battle royale is beyond on-device… a browser mini-game you can play
  right now") → agent_start → single-file-HTML target → wrote `game.html` (self-contained canvas app).
  Executed under a DOM/canvas harness: 300 loop frames + simulated input, **zero runtime throw** — it
  genuinely opens and runs.
- **HONEST CEILING (the real next gap):** the artifact RUNS but its game LOGIC is buggy (weak-3B-FM
  raw HTML/JS): `if(enemies.length===0) gameOver=true` trips frame 1 so enemies stop spawning; bullets
  accumulate dx/dy but never apply them (don't move); `gameOver` never sets `dead` (no game-over
  screen); only left/right despite the WASD spec. It's **syntax-verified but behaviorally unverified** —
  there is NO deterministic verifier for interactive/canvas-game behavior the way VGR has one for pure
  functions. This is the doctrine frontier: "correctness from the loop" hasn't reached interactive artifacts.

**NEXT (in priority order):**
1. **Behavioral verification for HTML/canvas builds** — the biggest quality gap. Options: headless
   execution smoke (no-throw + key invariants like "score increments on hit", "player stays in bounds")
   as an emit-gate; or a small metamorphic battery for game state. Ship only artifacts that pass.
2. **Ordinal option-picking** in negotiation ("the first one", "the second") — currently only genre
   names/connectives are caught; an ordinal reference to the offered list falls through to the FM.
3. **Fix clarifyBuild's dangling `running` status** (startTask flips it before the clarify gate, no
   completeTask on early return) — latent multi-turn suppression; the 66h refinement handler dodges it
   by short-circuiting early, but the first-turn clarifier still leaves the session `running`.

---

## PRIOR — cont. 66f (WHOLE-TREE SIGNATURE PROPAGATION)

**cont.66f (fdbf641) — whole-tree signature propagation shipped (mission item 1, remaining bulk of modify-path).**
- planEmit only reconciled call sites INSIDE the modified file. A signature change to an exported
  function also breaks callers in OTHER modules. New `planEmitTree` (emitPlan.ts) scans sibling
  files that import `entry` from the target path, mechanically trims the safe cases (trailing-param
  removal), and — all-or-nothing — refuses the WHOLE edit (downgrades to a fresh `src/<entry>.ts`,
  every existing file untouched) when ANY importer can't absorb the change.
- Specifier resolution (`importsEntryFrom`/`resolveSpecifier`) means a same-named import from a
  DIFFERENT module is never touched; an importer that also shadows the name forces a downgrade.
- Wired into server.ts single-file VGR write block: bounded project TS walk (`collectProjectTsFiles`,
  cap 400, skips deps/build) gathers siblings only on a modify-shaped request with a target file;
  propagated edits are written + streamed as their own tool_call/tool_result cards.
- vgr:bench 135/135 (+6 whole-tree cases: cross-file trim, non-importer untouched, required-param
  downgrade, defaulted-param no-op, wrong-specifier skip, shadow downgrade). tsc clean.
- **NOT yet live-FM-confirmed** — deterministic bench only; next session should run a real /api/chat
  modify against a scratch project with a cross-file importer (recipe in [[crucible-retrieval-gate-fix]]).

---

## PRIOR — cont. 66e (LIVE-FM ORACLE-CLOSURE CONFIRM + prose-extraction fix)

**cont.66c (0cdb3d2 → ae93e56) — all three modify-path increments shipped + consensus unified, everything live/bench-verified.**

**1. Modify-path increments (mission item 1) — DONE, LIVE-VERIFIED.**
- **Type-annotation grafting** (emitPlan.parseSignature/graftAnnotations): untyped certified code
  inherits the original definition's param/return annotations positionally (arity-equal only).
- **Call-site arity reconciliation** (findCallSites/reconcileCallSites): esbuild's compile gate does
  NOT typecheck arity, so signature changes are reconciled deterministically — trailing-param removal
  trims call-site args mechanically; unabsorbable changes downgrade to a fresh file, never a silent break.
- **Modify inside MULTI-file requests** (emitPlan.mergeCertifiedSource + multiFile.mergeCertifiedFileSet
  + server branch): collisions on a modify-shaped request are structurally merged (same-named decls
  spliced with graft+reconcile, new ones appended, named imports unioned), all-or-nothing, and the
  MERGED graph is re-verified by execution before any write. Non-modify collisions still refuse.
- **Root cause of live multi-file abstains found+fixed**: detectRequestedFiles turned a bare basename
  re-mention ("main.ts imports greet") into a PHANTOM third requested file; the coverage gate then
  demanded a root-level main.ts whose ./greet import could never resolve → every search exhausted.
  Also: modify-shaped multi-file requests now thread CURRENT file contents to the proposer as grounding
  (opts.context → spec.context) — edit real code, not reinvent blind.
- LIVE /api/chat: 2-file modify (greet.ts + main.ts) certified in 1 model call, merged into BOTH
  existing files (unrelated code preserved, welcome spliced in place), merged graph re-executed.
  vgr:bench 129/129. LESSON (recurring): FM variance means one live run isn't enough — when VGR
  abstains the agent loop still ships junk "oracle-verified" per-file writes (its oracle typechecks
  files in ISOLATION so cross-file imports always fail: "Cannot find module './greet'"). That agent-loop
  oracle gap is now the visible next hole.

**2. research:bench sweep after the premise-gate change: 9/10 correct, 1 honest abstain, 0 wrong.**

**3. Consensus unified**: extractClaimKey/keysAgree moved to agent/consensus.ts (one system-wide
definition; factConsensus re-exports). consensus.agrees now falls back to claim-key comparison for
terse answers ("Paris." vs "The capital is Paris" now cluster). answer:bench 127/127, debate:bench 34/34.
(factConsensus still calls localModels/orchestrator for ensemble voters — that part is live, not dead.)

**cont.66d (52c22ce) — agent-loop oracle cross-file blindness FIXED.**
Root cause was two-fold: (a) the oracle staged only relevance-ranked contextFiles (top-5
searchIndex), so a sibling the candidate actually imports could miss the cut and every candidate
failed Gate A with "Cannot find module './x'"; (b) universal.ts never passed projectPath to the
oracle, so the node_modules symlink never happened on the agent-loop path either. Fix:
oracle.stage() now resolves the staged files' relative-import closure against the real project
(transitive, TS resolution order .ts/.tsx/index.ts/.js, candidate content always wins, never
escapes the root) and copies exactly what the code needs; universal.ts threads projectPath into
oracleOpts (pureCode already did). Proven by direct repro (candidate main.ts → ./greet → ./shout,
no contextFiles: rejected before, behavioral-certified after) + vgr:bench 129/129. Residual gap:
a candidate importing a sibling that does not exist yet anywhere (not staged, not on disk) still
fails Gate A — that is a write-ordering question in the agent loop, not an oracle one.

**cont.66e (6437919) — LIVE-FM CONFIRM DONE + a real prose-extraction bug it surfaced, fixed.**
Fired the real /api/chat agent-loop task (new src/main.ts importing the existing ./greet ->
./shout chain, no contextFiles) against a scratch project. First run STILL failed — but NOT
with "Cannot find module" (the closure fix held); it failed on TS1005 ')' expected inside the
oracle's OWN __derived__/spec.test.ts. Root cause: extractSpecExamples (synth/derive.ts) grabbed
the entire English request sentence as a "worked example" because the prose contained a `name(`
token and a "returns" separator, then embedded that prose verbatim into the generated test — a
self-inflicted typecheck failure rejecting EVERY candidate before the import closure was ever
exercised. Fixed with isCallShaped(): the LHS must be a single call expression (identifier chain
+ balanced parens to the last non-space char). After the fix + server restart, the SAME task
certifies "tsc clean" in 1 offline cycle, writes correct main.ts, run() -> HELLO WORLD!.
vgr:bench 129/129. LESSON (again): the deterministic bench feeds clean `f(x)===y` example lines,
so it never exercises prose-extraction — the live FM path is the only place this class shows up.
NOTE: had to restart the port-3001 backend (plain `tsx server.ts`, no hot-reload) to pick up the
src edit; many stale server.ts processes were running (parallel-session hazard).

**Next, in order:**
1. **Signature-change propagation across the TREE** (call sites in OTHER files — single-file
   reconciliation shipped; whole-tree is the remaining bulk of mission item 1).
2. **Consensus-vote premise corrections** (≥2 independent FM verdicts before a premise 'correction').
3. **Decompose server.ts (8.2k lines)** — coordinate with cloud session first.


---

### cont.66 — CODEBASE AUDIT + DEAD-CODE SWEEP (earlier today)

**cont.66 (d0730b5) — import-graph audit of the whole repo, then the dead-code sweep it justified.**
Audit: ~96k LOC / 942 files; 632 are path-loaded synth skills (NOT dead despite zero imports);
227 real modules reachable from entry points (server.ts, main.tsx, electron.cjs, modelRegistry.ts).
Deleted 1,871 LOC with zero import-graph reachers: old localModels stack
({router,gate,policy}.ts, strengthen/, its two benches — superseded by agent/localModelRouter +
debate/consensus), parked decompositionDag.ts + nodeExecutor.ts, unwired Tier-2 apply-layer
(contextAssembly.ts, apply/applyLayer.ts, synth/{mockInjection,triage}.ts), scratch test.ts.
KEPT synth-taxonomy.ts (has npm script synth:taxonomy). Verified: tsc clean, vgr:bench 114/114,
synth:prove 4/4. capabilityRouter.ts header fixed: classify() IS live (answerEngine +
agent/localModelRouter import it); only its routing half is parked. NOTE: agent/
strengthenCandidates (live, used by debate.ts via consensus.ts) is a DIFFERENT module from the
deleted localModels/strengthen — don't confuse them.

**Next, in recommended order (from the audit):**
1. **Retrieval-routing gate** — highest correctness-per-effort. retrievalLayer.ts is fully wired,
   but answerEngine.classifyFacets' EXTERNAL_FACT gate failed to fire on "who won the 2018 World
   Cup" → wrong parametric answer ("Brazil"). Fix the classifier that decides WHEN to ground.
2. **Multi-file editing of EXISTING codebases** — mission item 1's real gap: VGR does greenfield
   synthesis well but can't yet make verified surgical cross-file edits in a large existing tree.
3. **Unify consensus** — answer/factConsensus.ts still rides the old localModels/orchestrator;
   fold it (and eventually VGR differential consensus) onto agent/consensus.ts.
4. **Decompose server.ts (8,119 lines)** — the /api/chat handler breeds control-flow bugs
   (both cont.65b bugs were size-enabled). Contended with the cloud session — coordinate first.

---

### cont.65b — CONTEXTUAL UNDERSTANDING fix

**cont.65b (8cbe6d7) — fixed the context-blindness the user caught.** "test" → FM invented
"help you with your test!", which poisoned the persona (identity became "a study assistant"; a
joke request role-played AS the user); "build me a game" free-associated off stale session
history and shipped the recycled greeting as "AGENT COMPLETE ✓ verified · 0 tools". Fix (system
owns deterministic answers): `answer/conversational.ts` matchMeta (greeting/identity/capability =
fixed canonical text, un-poisonable, FM-offline-safe) + clarifyBuild (bare "build me a game" →
option-rich clarify; "build me a snake game" → null → real builder). answerEngine: meta
short-circuit + system prompt with identity/most-recent-message-anchoring/anti-roleplay.
server: build-clarifier gated on `hadActiveTaskBefore` (KEY: startTask flips session→running
before the check, so a live status read is useless). intentClassifier: creation verbs →
complex_task. `npm run conversational:bench` 56/56, answer:bench 127/127, LIVE-VERIFIED in browser.
Open gap surfaced (separate): "who won the 2018 World Cup"→"Brazil" (wrong) — parametric-recall/
retrieval gap, not this fix. See [[crucible-contextual-understanding-fix]].

---

### cont.65 — COUNCIL DEBATE ensemble + MiniCPM5-1B seated

**cont.65 (6c0336b) — the co-equal on-device council is LIVE, end-to-end, in the default (strict) chat path.**
User directive executed: two-plus independently-trained on-device models as PEERS that debate — not
primary/backup — fully in-process (node-llama-cpp, no Ollama/HTTP).

- **`agent/debate.ts` — `runDebate()`:** blind proposals → cross-examination/revision → deterministic
  verdict via shared `agent/consensus.ts` (oracle arithmetic > consensus vote > honest plurality).
  Seeded proposals (a caller's already-computed draft joins without re-inference), per-peer timeouts,
  unanimity early-exit, errored-rebuttal-keeps-proposal. `npm run debate:bench` 34/34, scripted peers.
- **MiniCPM5-1B seated (the cognitive-core pick):** catalog entry (Apache-2.0, 688MB Q4_K_M,
  sha256-pinned, `.crucible/models/minicpm5-1b-q4_k_m.gguf` DOWNLOADED on this Mac), loads + infers
  in-process. `<think>` scratchpad stripped at pool level. LIVE: proposes in ~5–15s warm.
- **8GB-device fix that makes the council real:** Apple FM peer rides OUTSIDE the GGUF RAM budget
  (it lives in the OS model service) + macOS freemem floor (total*0.25) — budget-1 devices now seat
  a genuine 2+ voice council instead of degrading to solo (first live run WAS solo; fixed).
- **Strict-path integration (production default):** the answer engine's verified draft is seated as a
  council voice; MiniCPM + FM cross-examine it; `local_debate` SSE ships the transcript. DISPLAY-HONEST:
  the shipped text is never overruled by a lexical vote (answerQuery's deterministic critics outrank the
  council) — agreement/dissent is surfaced, not hidden. Gated to code/reasoning domains.
- **UI council card (chat):** on local replies, a collapsed `COUNCIL — 3 of 3 voices agree · 97%` chip
  expands to per-voice verdict/agreed/dissented/revised marks with struck-through abandoned positions;
  same section renders in the ensemble process trail (`CouncilDebateSection`, MessageList.tsx).
  LIVE-VERIFIED in the browser (3-voice unanimous: answer-engine + minicpm5-1b + track-s-fm, 15.4s).
  `app/` bundle rebuilt + committed.
- Benches: debate 34/34, strengthen 13/13, answer 127/127, tsc clean.
- **HONEST LIMITS / NEXT:** (1) no live *disagreement→revision* observed yet (all live runs were
  unanimous; the rebuttal path is bench-proven only — force a disagreement live). (2) Non-strict routed
  path debates GGUF-vs-GGUF — RAM-risky on 8GB; council there leans on the FM peer. (3) Council verdict
  does not yet feed VGR coding tiers (differential consensus and the council are separate consensus
  machineries — consider unifying). (4) Head-to-head telemetry MiniCPM vs FM (win-rate per domain) not
  aggregated — needed before any "promote to primary" decision.

---

### cont.64 (below) — cognitive-core doctrine + converge telemetry

**cont.64 — two things this session:**

1. **DOCTRINE shift (foundational, user directive): the COGNITIVE CORE (Karpathy).** DOCTRINE.md now
   has a §"The cognitive core (the model we actually want)". The endpoint is NOT a large model that
   knows everything — it is a **very small on-device core (~1B params, self-trained/distilled if
   needed) stripped of encyclopedic knowledge, holding only powerful, well-optimized REASONING + the
   ability to LOOK THINGS UP.** Facts live in retrieval (corpus/index/web via our tooling), never in
   weights. Baked-in factual recall = unverifiable, stale, hallucination-shaped debt — the same
   failure as a preloaded answer, one level down. Direction of travel is **smaller + reasoning-denser,
   not bigger**; the ~3B FM is a stepping stone. Binding: prefer the smallest core that still reasons;
   treat baked knowledge as debt; invest disproportionately in reasoning + retrieval infra;
   self-train only to sharpen reasoning / shrink the core, never to memorize more. New forbidden
   framing: "NOT knowledge baked into weights." **This shapes every future build decision.**

2. **Converge-epochs telemetry (0970e88).** `CodingRequestResult.converged?:{epochs,modelCalls}` set by
   tryConverge; both server call sites record `convergedEpochs` in debug history + emit `vgr_converge_win`
   (event + streamed thought) when `epochs>1`. **To flip converge default-ON:** run real coding traffic
   with `CRUCIBLE_CONVERGE=1`, grep history for `vgr_converge_win`; ≥1 genuine win + no regression ⇒ flip.
   The question that gates the default is now answerable from data, not a lucky live catch.

### cont.63 (below) — converge WIRED + live-validated on /api/chat

**cont.63 (83f13c7) — converge is now callable live and observable; validated no-regression.**
- Both server.ts VGR call sites (`~3086` file-emit, `~3564` synthesis) pass
  `converge: process.env.CRUCIBLE_CONVERGE === '1'` (default OFF) and forward iterate()/search
  thoughts to the SSE stream (`"VGR · …"`). Previously `emit` was unwired, so iterate's per-epoch
  convergence thoughts never reached the client — a live convergence run was invisible.
- **Live-FM validated** on a standalone converge server:
  `CRUCIBLE_CONVERGE=1 PORT=3007 CRUCIBLE_VGR=1 JWT_SECRET=converge-test-secret npx tsx server.ts`,
  mint a `crucible_session` JWT cookie (see auth-testing memory), POST `/api/chat`. `converge:true`
  certifies correctly with ZERO regression on tier-1 (scoreWord/rle w/ examples) and no-example
  tier-2/3 (titleCase differential, normalizeSlug property).
- **NOT yet observed:** an actual epoch>1 convergence live (forcing a weak-FM stall on demand is
  stochastic). No-regression is proven; default stays OFF until epoch>1 is seen.
- **Bug fixed (surfaced by the live run):** the file-emit branch hardcoded "(N cases passed)";
  property/metamorphic certs carry `cases:null` → it printed "0 passed" (reads as "nothing
  verified"). Now: "general invariants held — property/metamorphic certification".
- vgr 114/114, iterate 12/12, coderesearch 11/11.
- **NOTE:** emitted files land in the per-session workspace `projectPath`, not the repo root.

### cont.62 (below) — iterate() WIRED into the coding path

**cont.62 (549ec0d) — the convergence loop is now in the request path, not just a primitive.** cont.61
built `iterate()` but nothing called it. This session wired it into coding:
- **`reasoning/codeResearch.ts` — the doctrine-sound code-domain `ResearchFn` (2 channels).**
  - **Channel 1 (always safe):** each epoch is a fresh `search()` with empty history, so the rich
    per-case feedback the last epoch earned is otherwise lost at the epoch boundary. Ch1 distils the
    best failure's signals into a "known failing behaviour" note appended to `spec.context` — guides the
    proposer, can never change ground truth. Returns null when nothing is NEW (no manufactured progress).
  - **Channel 2 (sound verifier-tightening):** on a stall over a THIN case set, derive fresh cases by
    DIFFERENTIAL CONSENSUS (≥2 independently-written impls agree by execution) and merge the new ones —
    independently-justified ground truth, never a model guess. Fires only while cases ≤ threshold.
  - `mergeCodeAcceptance` unions cases by (entry,args); **existing value WINS a collision** (research
    never silently rewrites a trusted expected value).
- **`iterateCodeTask` (solve.ts)** drives proposeCode/verifyCode through `iterate()` with the code
  research fn + merge. **Opt-in `converge` mode** on `solveCodingRequest` tiers 3/4 (differential,
  model-invents) is a **pure ADD** — a non-solve falls straight through to today's single-shot +
  poisoned-case recovery, so it can only certify MORE, never regress. Wired in solve.ts, NOT server.ts.
- **`__code_research_bench.ts` (npm run vgr:coderesearch) 11/11**: merge semantics, ch1 grounding +
  null-on-stale, ch2 differential tightening (injected sampler, dedup, correctness), and an END-TO-END
  `iterateCodeTask` solve over the REAL `verifyCode` that only converges once ch1 carries the prior
  epoch's counterexample forward. vgr 114/114, iterate 12/12, tsc clean.
- **HONEST LIMITS:** (1) ch2 tightening only bites AFTER a stall — it cannot reject a degenerate that
  SOLVES a thin spec at epoch 0 (that protection lives at tier-3 differential spec derivation, not
  here); ch1 is the real in-loop convergence win. (2) `converge` is **deterministic-only so far —
  UNVERIFIED on live-FM `/api/chat`** (default OFF). NEXT: a live-FM run with `converge:true`, then flip
  the default; Python verifier; answer-domain `iterate()`.

---

## PRIOR STATE (cont. 61 — ITERATE convergence loop)

**cont.61 (902c4fd) — `iterate()`: the outer convergence loop the doctrine was missing.** `search()`
is BOUNDED (abstains on a fixed budget/patience). `reasoning/iterate.ts` sits ABOVE it and turns a
single search into "iterate until correct (or as-correct-as-reality-allows)":
- **Progress-gated, not fixed-budget.** Runs search() as one EPOCH; keeps spending epochs *while the
  best verdict score strictly improves* (escalating beam+calls). Climbs across epochs a single search
  would abstain on.
- **Research injection on stall.** When an epoch fails to improve, an optional `ResearchFn` folds
  grounding into the next epoch — SAFE for the proposer (append `spec.context`) and, only with
  independently-justified data, TIGHTENING for the verifier (merge `spec.acceptance`, e.g. a derived
  counterexample). "Sound or nothing" — never inject a case the model merely believes.
- **Deterministic termination.** Stops on exactly one of: certified pass · no-progress-after-research
  for `stallLimit` epochs · reality budget (wall-clock / global model-call ceiling / epoch cap / abort).
  The model NEVER decides to stop — "indefinite" only while provably improving.
- **`__iterate_bench.ts` (npm run vgr:iterate, 12/12)** proves all 4 exits + climb-across-epochs +
  sound-acceptance verifier-tightening, deterministically (mock proposer/verifier, no FM). tsc clean,
  vgr:bench still 114/114.
- **NOT yet wired live.** iterate() is a proven reusable primitive; nothing calls it in the request
  path yet. NEXT: a code-domain `ResearchFn` (retrieve reference material / derive counterexamples) and
  wrap `solveCodingRequest`'s model-invents tier in iterate() — deserves its own live-FM cycle (mocks
  miss proposer/prompt reality, per cont.57f). Do NOT edit the contended server.ts merge region; wire
  inside solve.ts.

---

## PRIOR STATE (cont. 60 — DOGFOODING: coding-quality overhaul; canonical 0-API refs; 341/341)

**cont.60 — dogfooded via real /api/chat and fixed the coding path (benches were 322/322 GREEN while
live coding shipped buggy unverified code — always dogfood).** A plain "write a TypeScript function …"
was NOT detected as an agent task, so it skipped the whole VGR block and shipped RAW FM code (a buggy
slugify: trailing + doubled hyphens, comment claiming the correct output).
- **VGR coding PRE-GATE** (server.ts, non-agent flow): every code-impl/edit request — ALL triage tiers
  (a coding ask classifies 'full', so the first gate wrongly excluded it) — runs `solveCodingRequest`
  and ships only execution-certified code INLINE; else falls through unchanged. Skips non-JS/TS
  languages (VGR is JS/TS-execution only) and is time-boxed (`CRUCIBLE_VGR_PREGATE_MS`=40s) so a
  non-certifiable function fails fast to the FM. twoSum 88s→19s certified; Python 35s→19s skip.
- **CANONICAL reference library** (`metamorphicSpec.canonicalImpl`): a detected class
  (slug/trim/sort/reverse/dedupe/max/min/sum/average/flatten/filter/case) ships a KNOWN-CORRECT impl
  certified against its own invariant with **ZERO model calls** — slugify 102s+wrong → 0.1s+correct.
- **Weak property families no longer certify**: `string-transform`/`object-transform` had only trivial
  invariants (returns-a-string, idempotent) → false confidence; now `null` → fall to strong tiers.
- **Strong STRING invariants** (slug/trim/upper/lower) + **counterexample-carrying `check()` signals**
  (report concrete input→output + fix hint so a weak 3B converges) + **metaGate** (a strong invariant
  is ground truth — differential/model-invented may never ship a candidate it rejects; closes the
  shared-systematic-bug hole live) + **over-fire guards** (word-order reverse ≠ char reverse; sort-by-key
  ≠ default sort). vgr:bench 114/114, bench:all **341/341**.
- **NEXT / biggest coding gap:** PYTHON (and Go/Rust) are raw-FM passthrough — VGR execution-certifies
  JS/TS only. A python-subprocess verifier + Python canonical refs would extend the certified path to
  the most-requested language. Also: latency (canonical is instant but the turn is ~16-19s of pipeline
  overhead — worth profiling the non-VGR stages).

---

## PRIOR STATE (cont. 59c — FATAL chat-freeze fixed; retrieval grounding provenance; 322/322)

**cont.59c (897070c) — FATAL FIX: chat froze after one query.** The new answer-side verification lanes
(fact consensus / explain spot-checks / recompute setups) fire 3-7 serialized FM calls per answer, but every
`fmComplete` call enqueued at priority:'high' with the strict 600s ceiling — so leftover HIGH verification
calls from query N tied with query N+1's draft on the concurrency-1 fmQueue, and any call nearing 600s blocked
ALL later queries ("starts okay, stops after one query, infects the chat"). FIX: `fmComplete` now takes
`{ timeoutMs, priority, signal }`; `answerEngine` runs every OPTIONAL lane through a bounded `verifyComplete`
— priority:'normal' (a fresh request's HIGH draft always preempts leftover verification) + 30s ceiling
(`CRUCIBLE_VERIFY_TIMEOUT_MS`; a wedged optional call is abandoned, the draft still ships) + honors the request
signal. `server.ts /api/chat` builds a turn `AbortController` that fires on client disconnect → passed to
`answerQuery` so a give-up stops the fan-out; plus an orphan-server sweep at boot (lingering `server.ts`
instances were hammering the single FM bridge). Repro (6 sequential mixed queries): ALL return, queue drains
to depth 0, 0 failures. LESSON in [[crucible-answer-engine]]: on a concurrency-1 single-session FM, every new
multi-call lane MUST be lower-priority + short-timeout than the primary draft.
Also landed: **retrieval grounding provenance** — `solveNonCodeTurn` now reports a `NonCodeMeta` (via
dag/dag-abstain/react/direct); a DAG answer is stamped provenance-grounded, while an FM ReAct/direct
FALLTHROUGH (parametric knowledge wearing a retrieval label) is routed through the normal fact-consensus /
explain verification lanes instead of shipping unchecked. bench:all **322/322**.

---

## PRIOR STATE (cont. 59b — ALL answer intents verified incl. explanations; 318/318)

**cont.59b (same session, continued) — the remaining cont.59 levers all landed:**
- **Unit conversion** (`answer/unitConvert.ts`): Tier 1 parses "<n> <unit> to <unit>" deterministically and
  answers from an exact factor table with ZERO model involvement (samples:0 provenance → "no model
  involved"); Tier 2 = K model-extracted setups + quorum on the CONVERTED value for odd phrasings.
  Affine temperature handled; ambiguous unit homonyms (in/single letters) don't gate. LIVE: FM said
  96.5604, table corrected to 96.56064 km/h.
- **Multi-fact lookups** (factConsensus): list-shaped asks corroborate the claim SET — every draft claim
  needs a resample-set quorum AND the claim count must match an asked count ("three largest").
- **Explain spot checks** (`answer/explainCheck.ts`): THE last unverified lane. Checkable sub-claims
  (years/measures/attributions) extracted deterministically, each judged in isolation by K decorrelated
  verdicts; majority-refuted claims get a named caution appended (flags, never rewrites; split/unsure
  never flags). LIVE: 3 claims, 6 verdicts. CRUCIBLE_EXPLAIN_CHECK=0 disables.
- **Metamorphic live gap FIXED**: bare "sort" now uses a NUMERIC battery (string inputs only when prose
  says strings/alphabetical) — the FM's correct (a,b)=>a-b no longer fails the relation and falls to
  differential (which had certified the shared NaN misordering). Live `arrange` → metamorphic, 1 call.
- bench:all now **322/322** across 8 suites (explain-check upgrade: conversion-shaped claims are judged by
  the exact unit table ±1% BEFORE any FM verdict — machine refutation overrides model verdicts; lever (c) DONE). Every answerQuery intent (reason/lookup/explain/converse-adjacent
  compute, dates, conversions) has at least one verifier lane.

**Next levers (cont.59b ranking):** (a) grounding-entailment for RETRIEVAL answers (usedRetrieval currently
bypasses all new lanes); (b) conversation-history-aware verification (follow-ups re-verify against prior
turns); (d) compound conversions ("mpg to L/100km", currency excluded); (e) coding side: codec-roundtrip
metamorphic for custom-named encode/decode pairs; differential shared-bug reduction via forced-diverse
prompts (ask one impl in a deliberately different paradigm).

---
### (superseded cont.59 summary below, kept for rationale)

**Read [`DOCTRINE.md`](./DOCTRINE.md) before anything else.** It supersedes all older framing.

**cont.59 (2de180b) — four fronts landed, all live-verified where a live path exists.**
1. **Calendar recomputation** (`answer/dateTime.ts`): date-offset / weekday / days-between questions get the
   wordProblem treatment — model proposes a strict-JSON setup, MACHINE does UTC calendar arithmetic (leap
   years, rollover-rejection), K-setup quorum or abstain. Self-contained (explicit-date) questions only;
   "today"-anchored asks are refused (volatile lane). Contradicting dates are SPLICED out of the prose
   (question givens preserved). LIVE-VERIFIED: FM asserted "June 1, 2026", machine certified April 17, 2026,
   final reply clean.
2. **Constraint critics** (`answer/constraints.ts`): the question's own constraints (asked-unit family,
   percent∈[0,100], probability range, count integrality/non-negativity, part-of-whole ≤ N) deterministically
   REJECT a recomputed value — the shared-wrong-setup honest limit of recomputation now has a guard. A
   violating quorum value is never stamped "machine-verified".
3. **Short-factual consensus** (`answer/factConsensus.ts`): lookups — the last unverified lane — get K
   independent resamples; claim-key extraction excludes entities the question already mentions; quorum stamps
   verified, no quorum appends an explicit unverified note (verified:false). Installed non-FM localModels
   (ONNX registry) join as genuinely independent ensemble voters — first live consumer of the dormant
   ensemble subsystem; zero voters on an uninstalled machine (identical behavior). LIVE-VERIFIED (Canberra,
   100% agreement). Gate off with CRUCIBLE_FACT_SC=0.
4. **Coding-ladder depth**: `metamorphicSpec.ts` gained 8 reference-oracle relation classes detected from
   prose (dedupe/max/min/sum/average/deep-flatten/filter even|odd|positive) — reference computed INSIDE the
   assertion, complete by construction; compound-problem guard (subarray/pair/digits/…) and two-class
   ambiguity guard refuse rather than guess. `differentialSpec.ts` gained a DETERMINISM guard: one impl is
   re-run over the battery, changed outputs are dropped, mostly-unstable output aborts derivation
   (randomness can never become ground truth). vgr:bench 93/93 incl. live PART B.
5. **`npm run bench:all`** (`src/CrucibleEngine/__bench_all.ts`): runs all 8 deterministic suites, appends
   per-suite counts to `.bench-history.jsonl` (gitignored), exits nonzero on any failure OR a pass-count
   shrink vs the previous entry — the monotonic never-regress rule finally has a cross-session enforcer.
   Baseline 285/285 (286 after the splice check). Run it before every handoff.

**Next levers (cont.59 ranking):** (a) rate/ratio + unit-conversion problems that don't reduce to plain
arithmetic ("how fast in km/h if 60 mph" — needs a conversion-table evaluator, same setup/quorum shape);
(b) apply the consensus oracle to EXPLAIN-intent answers (currently zero verification on explanations —
hardest, highest-value open gap); (c) multi-fact lookups ("list the three largest…") where claim-key
extraction only captures one claim; (d) more reference-oracle classes (count-occurrences, string
normalizers) + codec-roundtrip metamorphic for custom-named encode/decode pairs; (e) live `arrange`
request routed via differential, not metamorphic (bench-verified detection, but the live ladder took the
differential path — worth one debugging pass over solve.ts ordering).

---

**cont.58 (ff616d3) — word-problem recomputation: the FIRST deterministic verifier on the ANSWER side.**
The coding side had a rich verification ladder; open Q&A had none — the largest north-star gap. The answer
engine's arithmetic critic only fixed equations the model WROTE OUT; a bare stated answer ("the train travels
140 miles") had no equation to check, and self-consistency voting certified a shared arithmetic bias.
`answer/wordProblem.ts` applies the doctrine to answers: the model PROPOSES the SETUP (translate the problem
to ONE arithmetic expression), the MACHINE evaluates it (`evalArithmeticExpr`, whitelisted, never evals
identifiers → un-foolable arithmetic), and K independent extractions must reach a QUORUM on the value or it
abstains (`recomputeWordProblem` → null). `applyRecomputation` corrects a mismatched stated number in place,
confirms a correct one, or appends an Answer line. Wired into `answerQuery` for non-retrieval computation
questions. `answer:bench` **55/55**; live-verified (60mph×2.5h→150 miles, $3×7→21 dollars, 12×8→96 cm²).
Extended (72d0b4d): (1) multi-step step-DAG fallback (`recomputeMultiStep`/`evalSteps`) for irreducible
problems; single-expression stays the fast workhorse since the model nests; (2) safety guard — never
overwrite a time-of-day answer with a bare quantity; (3) broadened `needsComputation` so discount/percent/
"what is the total|cost|price" actually route to recomputation (disambiguated from volatile lookups by
operand count). Live: `answerQuery` now emits "Verified by independent recomputation: 40*(1-0.25)=30 dollars".
**Next answer-side levers:** (a) KNOWN ISSUE — reason-intent step-by-step prompt overruns the token cap →
correct compute answers get a 'truncated' flag + repair round (verbose/slow); since the machine value is
known, append a clean "Answer: <verified value>" and/or tighten the reason prompt (the machine, not the shown
work, certifies). (b) non-arithmetic verifiers (unit/magnitude sanity, constraint-satisfaction). (c) date-time
and rate/ratio problems that don't reduce to arithmetic. (d) short-factual self-consistency + abstention for
lookups (currently a single FM call).



**cont.58 (f7c8dab) — metamorphic relations from spec text (the un-foolable tier).** Built on top of the
differential work below. The name-gated property whitelist misses any function DESCRIBED in prose but named
custom (`arrange` "ascending order", `flipOrder` "reversed"). `reasoning/metamorphicSpec.ts`
(`deriveMetamorphicSpec`) detects the relation-CLASS from the DESCRIPTION and certifies against a COMPLETE
metamorphic relation set — sort = {permutation ∧ ordered}, reverse = {position-map} — checked by execution
with zero expected values. This is the tier ABOVE differential: a true invariant CANNOT be satisfied by a
systematically-wrong output every sample shared, so it directly patches differential's documented shared-bug
hole (a descending sort that value-consensus over all-descending samples would wrongly certify is REJECTED by
the ordered-ascending relation). Wired as **path 2.5** (after name-property, before differential); direction
(asc/desc) read from prose; guards against non-sequence idioms ("reverse engineer", topological sort).
`vgr:bench` **80/80**; live-verified (real FM certifies custom-named `arrange` via the metamorphic path in 4
calls, no examples/no model-invented values). **The full ladder is now: 1 user-examples → 2 name-property →
2.5 metamorphic-from-spec → 3 differential-consensus → 4 model-invents-both → 5 abstain.** Next metamorphic
levers: extend the complete-relation catalog (codec roundtrip pair when named custom; filter as a *partial*
constraint combined with differential; idempotent-normalizer classes).

**cont.58 (a5e2bff) — the ceiling that was removed.** The strong property-verifier path only fired when the
entry function NAME matched one of ~40 hardcoded families (`sort`, `gcd`, `reverse`, …); every arbitrary
function fell to the weak "model invents both the input and the expected output" path or abstained. Widening
the whitelist one family per commit never reaches open-ended requests. `reasoning/differentialSpec.ts`
(`deriveDifferentialSpec`) closes this the doctrine-sound way — N-version differential testing: the SYSTEM
fuzzes inputs (shape-hypotheses + edge cases, no input bias), K independently-FRAMED implementations
(iterative/recursive/functional/built-in) are executed on them, and where a quorum of ≥2 DISTINCT-fingerprint
impls agree on an output, that (input→output) becomes derived ground truth; the final candidate is certified
against it by execution. No name gate → reaches ARBITRARY functions. Wired as **path 3** of the
`solveCodingRequest` ladder (1 user-examples → 2 named-property → 3 differential → 4 model-invents-both →
5 abstain), INSIDE the function, so it is live on `/api/chat` with **zero `server.ts` edit** (no merge
contention) and FM sampling routes through `fmQueue` (no contention). `vgr:bench` **69/69** (was 62);
live-verified with the real on-device FM (titleCase 6 cases, repeatStr 8 cases w/ arity-2 inferred, both
certified; countVowels2 honest-abstains). HONEST LIMIT (file header): a systematic bug shared across ALL
samples can still poison a case → named properties remain preferred (a true invariant can't be fooled).
**Next in-lane levers:** (a) metamorphic-relation properties derived from spec text (idempotence, monotonicity,
length-preservation) to lift more functions into the un-foolable property tier; (b) tighten differential
coverage for the countVowels2-class near-misses (2/3 quorum); (c) apply the same differential oracle to the
**answer engine** — open-ended Q&A still has no deterministic verifier, the largest remaining north-star gap.

---


**The reframe (this session):** After an audit, the project's true north star was made explicit and
wired into all top-level literature: **correctness comes from the LOOP, not the oracle.** An
unreliable ~3B on-device model + a sound deterministic verifier + search = a system more reliable
than the model. We do NOT need more parameters (8GB Mac → ~3B ANE model is the permanent, correct
ceiling). We do NOT ship memorized/preloaded answers (answer-specific critics like the clock-arith
splicer are now classified as debt to delete, not progress). The model only PROPOSES; deterministic
ground truth certifies; the loop explores/prunes/backtracks/abstains.

**Shipped this session:**
- **`DOCTRINE.md`** — the authoritative north-star doc. All future sessions anchor here.
- **`src/CrucibleEngine/reasoning/`** — the reference implementation (VGR):
  - `types.ts` (Candidate/Verdict/Proposer/Verifier/TaskSpec/SearchResult),
  - `search.ts` (deterministic propose→verify→backtrack **beam engine** — model never touches control flow),
  - `codeVerifier.ts` (**executes** candidates vs acceptance cases → high-information actual-vs-expected feedback; zero model),
  - `codeProposer.ts` (the ONLY place the model lives; threads prior-failure feedback into the next guess),
  - `solve.ts` (`solveCodeTask()` public entry), `README.md` (module literature).
- **`npm run vgr:bench`** — 11/11 green. Proves: single-shot ships a wrong answer, the loop rejects it
  via execution and certifies the correct one, a non-converging proposer ABSTAINS, spec extraction's
  consensus filter drops model-contradicted cases, a single USER example forms a trustworthy spec, and
  the LIVE on-device FM solves novel tasks through the loop.
- **LIVE-WIRED + PROVEN on real `/api/chat` traffic (behind `CRUCIBLE_VGR=1`, default off):** fired a
  real coding request against the running server → `VGR-certified src/slugify.ts (1 executed case passed,
  no external model)`; the emitted file behaviorally correct (`slugify("Hello, World!")==="hello-world"`).
  Inserted in the synth-miss branch (server.ts ~2926): when deterministic synth (L0/L1) misses, VGR
  proposes-verifies-certifies before the legacy unverified model loop.
- **Spec extraction shipped** — `specExtractor.ts`: harvests USER-stated `f(x)===y` examples as GOLD
  ground truth (trusted, no consensus) + model-proposed cases behind a cross-sample consensus filter.
  Gold user examples are the certification gate; model cases are advisory only (a wrong model-invented
  case must never make a solvable spec unsatisfiable — the vote-bias trap DOCTRINE.md warns about, hit
  live on `initials` and fixed).
- **Real bug fixed:** `codeVerifier` now transpiles TS→JS (esbuild) before executing — the FM emits
  TypeScript, which raw `node` can't run, so every candidate was failing at load regardless of correctness.
- Docs re-pointed: `CLAUDE.md`, `ROADMAP.md` lead with the north star → DOCTRINE.md.
- **VGR is now DEFAULT-ON (commit 96a5237)** — `CRUCIBLE_VGR !== '0'`; runs after synth L0/L1 miss, ships
  only certified code, falls through on abstain. Verified firing with no env flag. Interactive budget 8 calls.
- **Semantic-thrash detection (codeProposer, 96a5237):** the FM makes the SAME logical error with
  cosmetically-different code (live: `.join(/\s+/)` — regex-as-separator → "fox/\s+/brown…"), invisible to
  fingerprint-dedup. Now a recurring failure-SIGNAL triggers a pointed "you're stuck, fix THIS line" hint +
  higher temperature. reverseWords (which anchored on this) now solves.

**FM daemon contention — FIXED (cont.56, commit ee589fc).** Was the top blocker: live VGR exhausted on
`initials` (solves in 3 calls unloaded) because the single-session daemon, hit concurrently by
background work, returned empty responses that burned the search's patience budget. Two fixes:
(a) `fmQueue.ts` — a concurrency-1 priority queue in front of the daemon (interactive=HIGH, pipeline/
background=NORMAL); every daemon call site routed through it; `/api/diag.fmQueue` shows depth (observed
maxDepth 11 under load). (b) `search.ts` — null/empty proposals are retried on a separate bounded budget,
never charged to the reasoning/patience budget. Result: `initials` now certifies LIVE in 1 call. bench 12/12.

**Latency — PARTLY ADDRESSED (cont.56, commit a205213).** Foreground gate on fmQueue: /api/chat marks
itself foreground; FM-heavy background schedulers (improvement daemon tick, keepalive warmup) skip while
a request is live. Live `titleCase` certified in 41s; peak FM queue depth dropped 11→5 under load.
Residual: a background call ALREADY in-flight when the request arrives can still block it once (the queue
can't preempt in-flight); mitigate by giving background local FM calls a short timeout (they use
LOCAL_FM_TIMEOUT_MS, up to 600s in strict). 41s is still slow for interactive — the multi-call serial
search is inherently latency-heavy on one ANE session.

**Spec sourcing — DONE (cont.56, 4860796 + 940bdb7):** VGR ground-truth priority is now explicit —
(1) USER examples (gold; harvested via VGR regex UNIONED with synth/derive extractSpecExamples),
(2) GENERAL PROPERTY (new `propertyVerifier.ts` reuses `derive.ts derivePropertyTests`: sort/codec/
validator/transform families, executed in the codeVerifier harness), (3) model-consensus cases (last
resort). No-example tasks now certify: `sortAsc` → 5 sort properties → `arr.sort((a,b)=>a-b)`. bench 15/15.

**Property coverage widened (cont.56, 416a3d5 + e129726):** a model-free triage showed nearly every
common no-example task fell to the bias-prone model-consensus path. Added VGR-side `SUPP_FAMILIES` in
propertyVerifier.ts — factorial/fibonacci/gcd/isPrime/capitalize/sum/reverse/chunk — certified by
RECURRENCE / REFERENCE-DERIVATION / INVOLUTION general properties, NOT in the shared synth path (zero
prove:all risk), each tightly name-gated against the collision class. bench 21/21.

**Model-consensus fallback ROBUSTIFIED (cont.56, 9fdbf55):** `recoverFromPoisonedCase` in solve.ts — when
the model-consensus search exhausts, if ≥2 independent impls unanimously fail the SAME single case (pass
all others), that CASE is dropped (cross-derivation agreement > one model-invented value) and a candidate
is re-certified against the cleaned set. Strictly gated (≥3 cases, ≥2 agreeing, winner must pass the rest);
never ships code failing a trusted case; no model calls. bench 24/24.

**Multi-FUNCTION synthesis DONE (cont.56, c2ca1e1):** VGR now certifies several exports in ONE module.
Extractor tags each case by its target function (entries[] + tagged cases); verifier RUNNER routes each
case to its case.entry; proposer emits all required functions. Live: "add(a,b) and sub(a,b)…" → both
certified in 1 call, each against its own cases. bench 27/27. (Still ONE file — multi-FILE is next.)

**Emit planning DONE + wired (cont.56, 8d13b79 + a7316a9):** `emitPlan.ts` (pure, bench 34/34) decides
where certified code lands — explicit target path → that file (APPEND if it exists and the combined file
still compiles, else downgrade to a new file, never corrupting the existing one), else `src/<entry>.ts`.
Wired into the server VGR block. **LIVE ROUTING FINDING:** "add X to <existing file>" phrasing routes to
the LEGACY edit-file agent path BEFORE the VGR block, so emitPlan's append only fires for create-style
requests today. Fixing = moving/co-gating VGR ahead of the edit path (routing change near the agent
stack) — deferred to avoid colliding with the parallel cloud session.

**THE NEXT LEVER (highest priority — this is where capability now comes from):**
1. **Route edit-phrased requests through VGR** (the finding above): let "add/modify X in <file>" reach the
   VGR block (which already has emitPlan append). Then true **multi-FILE specs** — an entry per file +
   cross-file imports (semantic index + synth repo-context model this). THE mission gap.
2. **Widen property families further** (parsers, numeric min/max, stateful classes) — same recurrence/
   reference-derivation pattern in `SUPP_FAMILIES` (propertyVerifier.ts).
3. **Kill the memorized-answer critics.** Audit `answer/verify.ts` (clock-arith splicer, phrasing
   correctors) and `synthDriver` regex gates; replace any that patch a *specific* answer with a
   *general property* verifier, or delete them. They are doctrine violations.
4. **Sample-efficiency pass (continued):** semantic-thrash detection landed (96a5237); next add minimized
   counterexamples in `codeVerifier` signals, and for reasoning tasks an independent deterministic
   derivation that OVERRIDES the K-sample vote (replaces vote-counting, which amplifies model bias).
5. **Collapse the two agent stacks.** The orphaned capabilityRouter/decompositionDag/nodeExecutor
   stack should either become the VGR-shaped live path or be deleted. Maintaining dead "proven" code
   is why `prove:all` is green while the product underperforms.

**Prior answer-engine work (cont. 54-55)** — Stages 1-3 (classify → grounding → depth-scaled prompt →
deterministic critics → repair/abstain; K=5 self-consistency) remains live. Reframed under the doctrine:
its *general* critics (arithmetic re-derivation) are doctrine-aligned; its *answer-specific* correctors
(clock phrasing) are the debt called out in lever #3. The deterministic elapsed-time solver noted last
session is still worth building — but as a VERIFIER that overrides the vote, per the doctrine.

Everything below is PRIOR state, kept for history only.

---

## PRIOR STATE (cont. 37 — MULTI-TURN CONTEXT FIX. The user reported
that real chat is "dumb as fuck / misaligned instantly even on simple coherent prompts." Root-caused
LIVE (minted-JWT curl, not a boot screenshot): the offline conversational brain threw away
conversation history entirely — `solveNonCodeTurn(message)` got only the current message, so every
turn was answered in isolation and follow-ups hallucinated (e.g. a nonsensical refusal to recall the
user's favorite language). The client already SENT `history`; the server just dropped it. prove:all
is all single-shot so it stayed green while real multi-turn chat was broken — trust real chat over
the suites.

**cont. 37 — what shipped (tsc-clean server+app, all live-verified via /api/chat on :3001):**
1. `src/CrucibleEngine/agent/fmReact.ts`: new `ConvTurn` + `historyToMessages()`; `fmDirectAnswer`
   and `fmReact` now prepend prior turns as alternating chat messages.
2. `src/CrucibleEngine/agent/synthDriver.ts`: `solveNonCodeTurn(goal, projectPath?, history?)` threads
   history into the FM ReAct + direct tiers; a back-reference guard makes research-shaped follow-ups
   ("what is ITS population?") skip the history-blind research DAG and use the FM tiers instead.
3. `server.ts`: passes `history.slice(-6)` to `solveNonCodeTurn`; new `isContextDependent` (has
   history AND back-reference regex) forces triageTier='full' (so short follow-ups don't collapse to
   the history-blind simple-triage single call) AND bypasses both the exact + semantic response caches
   (message-keyed → would serve a stale answer from a different conversation).
   Verified: name recall, pronoun resolution (Rust vs Go), research follow-ups (Japan pop/capital),
   and standalone prompts all coherent. See [[crucible-multiturn-context-fix]].

**cont.37 second slice — runaway-repetition fix (committed 8d95e13):** Apple's FM has no
repetition-penalty knob, so open-ended prompts sometimes loop ("### Example 10, 11, 12…") to the
token ceiling. Added `stripRunawayRepetition()` in `fmReact.ts` (deterministic: cuts at the 3rd
occurrence of a digit-normalized block signature, drops dangling trailing headings, falls back to
original if the trim would gut the answer). Applied to `fmDirectAnswer`. Unit-verified 3286→603 ch
on the real signature; normal answers untouched. NOT yet applied to `fmReact`'s FINAL_ANSWER output
(lower risk there) — extend if runaway shows up in tool-loop answers.

**Still open after cont.37 (next priorities):**
- Research DAG occasionally self-contradicts on standalone factual Qs ("Paris is not the capital of
  France. The capital is Paris."). Could NOT reproduce in isolation this session — the DAG returned
  clean answers on repeated tries, so it's nondeterministic (source-snippet dependent). Left as a
  watch item; repro with several runs of `solveNonCodeTurn("what is the capital of France?")`.
- DAG answer FORMAT is verbose report chrome ("[CORROBORATED · 74% confidence…] *Sources: …*") even
  for conversational questions that reach the full tier — feels robotic vs a plain sentence. Consider
  a conversational post-format that drops the evidence scaffold unless the user asked for sources.
- Conversational latency is 12-17s for simple answers — worth profiling (research DAG + FM tiers).
- Everything below this block is the PRIOR (cont.36c) state, kept for history only.

---

## PRIOR — CURRENT STATE (last updated 2026-07-06, cont. 36c — FULL v3 CHAT REBUILD after the user
rejected cont.36's wrap-only slice as superficial ("didn't hit half the features"). This
continuation REBUILT the chat surface for real and fixed the actual ensemble-default leak,
which was SERVER-side. All verified live in the browser against a real running backend with
a minted JWT — screenshots of the logged-in UI, real queries answered, this is NOT the
boot-to-auth-screen verification ceiling of prior sessions.)

**cont.36c — what actually shipped (all tsc-clean, live-verified):**
1. **THE ensemble-default bug was server-side and is now structurally fixed.** server.ts's
   `/api/chat` had `mode = 'quorum'` as the DESTRUCTURING DEFAULT, and `mode:'code'`
   conversational turns were explicitly EXCLUDED from the offline-brain route (the old gate
   said `mode !== 'code'`), so ordinary chat fell through to the external multi-model
   pipeline regardless of the client's local default. Fix: (a) default is now `mode = 'code'`;
   (b) new per-request `requestOffline` lever right after body destructuring — ANY
   non-'quorum' request behaves as `CRUCIBLE_OFFLINE=strict` for its entire lifetime (all 5
   in-handler env reads now read `requestOffline`), making the external pipeline structurally
   unreachable without the explicit ensemble confirm + BYOK keys; (c) the offline-conv-brain
   gate now INCLUDES mode 'code'. Live-verified: 4 real queries in mode:code all answered
   on-device (one even with cited sources from the local research DAG), zero external
   fan-out. Also gated the CLIENT predictive pre-warm (App.tsx handleInput) on
   mode==='quorum' — typing was warming external Groq/OpenRouter models even in local mode.
2. **Old topbar DELETED, everything is left-rail now.** The 340-line topbar block (binder
   icon cluster + hamburger menu + Google-services menu) is gone. New slim in-chat header:
   Crucible wordmark + ON-DEVICE/ENSEMBLE badge + live elapsed/stage while working + New
   chat. The binders (History/Tasks/Integrations/Library/SelfRepair/SelfPatcher + governance
   trigger) moved into Settings → System section (SettingsTabView `advanced` prop). The old
   menu's dead items (API Keys/Pipeline Config/Model Roster "coming soon" alerts, About,
   Google-services status) were dropped entirely — Google status has no UI home now, flag if
   missed.
3. **MoltenPour is REAL now** — `src/MoltenPour.tsx`, verbatim canvas port of the reference
   (vessel + tilt-loop + molten stream + dual-edge border fill + top-down cool sweep),
   driven by round state via a new `PourWrap` (App.tsx) + `liveRoundId` state (only the
   round streamed live THIS session animates — restored history never replays the pour).
   The live round's card now mounts IMMEDIATELY on send (empty shell, `reserveTop` headroom)
   so the vessel visibly tilt-loops during 'thinking' — screenshot-verified live.
   `PourRing.tsx` is now DEAD CODE (unused, still on disk) — delete or keep as reference.
4. **Reply cards are clean per v3**: local replies = plain glass card + copy/feedback +
   `CRUCIBLE · ON-DEVICE` footer; ALL ensemble chrome (model chips, "consensus" label,
   attribution, the entire shows-its-work process trail with its "N models · X% confident"
   chips) now renders ONLY when `round.models.length > 0` (i.e. an actual ensemble run).
   Screenshot-verified: the old "0 models · 0% confident / SHOWS ITS WORK" junk is gone
   from local replies.
5. **Composer rebuilt to the reference**: crucible glyph + textarea + round send/stop
   (molten orange while working) in row 1; Ensemble pill + honest status line ("0 external
   calls" / "armed — will ask before any fan-out") in row 2. The ugly "+ KEY" pill is gone;
   with no keys the pill routes to the Settings tab. The per-query ensemble confirm and the
   no-keys prompt are now INLINE CARDS above the composer (reference style), not modals —
   `EnsembleKeyModal`/`EnsembleConfirm`/`EnsemblePill` in ensemble.tsx are now unused by
   App.tsx (dead exports, still on disk).
6. **Mode-machine purge**: `MODE_META` deleted; conversation-restore no longer adopts a
   stored 'quorum' mode (both restore sites); `classifyMode` was already gone. `mode` state
   survives internally ('code' default) but the ONLY write paths are the Ensemble pill and
   the confirm-card handlers.
7. **How this was live-verified (reusable recipe):** backend restarted onto current code
   (killed the pre-edit process on 3001 first — same stale-port class as the Electron fix
   earlier this session), vite preview + minted JWT (per [[crucible-local-auth-testing]])
   set as a browser cookie via preview_eval (cookies ignore ports, so a localhost cookie
   reaches :3001) — then drove the REAL logged-in UI: sent 4 queries, watched answers
   register, screenshotted the thinking-vessel animation and the clean cards. This bypasses
   the OAuth wall that capped every prior session's verification.

**Known rough edges left (small, listed so they aren't re-derived):**
- The pouring/cooling border phases weren't visually captured (local FM answered in one
  chunk after a long thinking phase; screenshots caught thinking-vessel only). The
  finishing-floor (1350ms) + cool floor (1000ms) guarantee visibility; if the user reports
  no border glow, debug MoltenPour's phase mapping in PourWrap first.
- `/api/prewarm` is still ungated server-side (client no longer calls it in local mode).
- Server-wide background external traffic still exists OUTSIDE /api/chat (free-model Hunter
  probing, ModelRefresh) — visible in the server log on boot. Product decision needed:
  those run on the bundled env key. Not chat-triggered.
- Dead files: PourRing.tsx, plus ensemble.tsx's EnsemblePill/EnsembleKeyModal/
  EnsembleConfirm exports.
- The Electron app: user must fully relaunch Crucible.app to get this server code (the
  electron.cjs stale-port fix from earlier today will clear any leftover 3001 process).

## PRIOR (cont. 36 first slice — superseded in part by 36c above): BUILD-BREAK FIX, Electron
stale-port fix, AND the v3 left-rail tab shell ported from a reference implementation. A new design
handoff (`Crucible UI redesign/v3/HANDOFF - Claude Code implementation brief.md` +
`Crucible v3.dc.html`, both untracked) superseded/clarified v2's ensemble UX. Discovered
mid-session: `git log` showed an UNDOCUMENTED commit `c9db65f` ("Update engine, UI, and
checkpoints...", 2026-07-06 07:02, after cont.35b's own commits) that left the working tree
with `npx tsc --noEmit -p tsconfig.app.json` FAILING — `App.tsx` imported `EnsemblePill` from
`./ensemble` but `ensemble.tsx` only exported the old `ModeBar`. Fixed first, before any new
feature work. `c9db65f` also added `SelfPatcherBinder.tsx` + `CrucibleEngine/selfPatcher.ts`,
unrelated to the UI redesign and not otherwise investigated — worth a look if unfamiliar.

**Also this session: root-caused the user's report that the Electron app "wasn't picking up
backend changes"** — a manually-started detached `tsx server.ts` from the PRIOR DAY was still
squatting on port 3001, so the app's own freshly-spawned server crashed silently with
EADDRINUSE and the window opened against the stale process instead. Killed it and hardened
`electron.cjs` (`spawnBackend()` now kills any prior 3001 occupant before binding, every
launch). Full detail in [[crucible-run-commands]].

**Then: the user pointed at a REFERENCE implementation repo** —
`https://github.com/mpd8zyb4yw-hash/Crucible-Code` (a from-scratch small reference app a design
handoff produced, NOT this project's real backend) — cloned to
`~/crucible-local/crucible-v3-reference` (sibling folder, untracked by this repo) and read in
full: `src/state/store.ts`+`types.ts` (zustand shape), `src/styles/tokens.css` (design tokens),
`src/components/NavRail.tsx`, `chat/{ChatView,Composer,MoltenPour}.tsx`,
`agents/AgentsView.tsx`, `history/HistoryView.tsx`, `settings/SettingsView.tsx`,
`shared/BackgroundBlobs.tsx`, and the mock `CrucibleEngine/{localModel,ensemble}.ts` (these
last two are explicitly-labeled zero-network stand-ins for a real backend — did NOT port them,
kept this app's real `/api/chat` streaming + tool/agent path).

**Ported into the REAL app this session (new `tab` state + 4 new files):**
- `src/NavRail.tsx` — the 56px left glass rail, near-verbatim from the reference (Chat/Agents/
  History/Settings icon buttons + wordmark).
- `src/AgentsTabView.tsx` — full-page Agents tab: the reference's 5 prebuilt-workflow cards
  (Vibe Code/Search Web/Deep Research/Smoke Test/Decide For Me), each wired to `onBuild` →
  real `send()` with a task-specific prompt (not the reference's mock `draftAgent`), plus the
  REAL skill/tool catalog (`GET /api/library/skills` + `/tools`, same data LibraryBinder's
  drawer already showed) rendered as a searchable grid below the cards.
- `src/HistoryTabView.tsx` — full-page History tab, same `GET /api/conversations` data source
  as the existing topbar `HistoryBinder` dropdown, day-bucketed list, click-to-restore (reuses
  the exact restore logic that lived inline for `HistoryBinder`'s `onRestore`).
- `src/SettingsTabView.tsx` — full-page Settings tab: the blank-slate BYOK key list promoted
  out of the composer-pill `EnsembleKeyModal` into its own tab, same underlying `ensemble`
  state/provider-auto-detection from `ensemble.tsx` (cont.36 build-fix work), just a full page
  instead of a modal.
- `src/App.tsx`: added `const [tab, setTab] = useState<'chat'|'agents'|'history'|'settings'>
  ('chat')`; wrapped the root render in a new flex row
  (`<NavRail/>` + a column div) and gated the ENTIRE pre-existing chat body (topbar, message
  feed, composer, all the topbar drawers — Library/SelfRepair/Integrations/Tasks/SelfPatcher)
  behind `{tab === 'chat' && <>...</>}` — a pure wrap at the two boundary points (right after
  `<style>`, right before the root's final closing div), no interior content touched, so the
  existing Chat-tab functionality is provably unchanged. `tsc --noEmit` clean; app boots with
  zero console errors in the preview (still auth-gated past that point — see the recurring
  verification-ceiling note below).

**Deliberately NOT done / left for next session (scope calls, not oversights):**
- The reference's `MoltenPour.tsx` canvas port was READ in full but NOT swapped in for the
  existing `PourRing.tsx` — cross-checked the two against each other and `PourRing.tsx` already
  implements the same phase model (idle→pouring→done, real-stream-driven, same
  `POUR_MIN_MS`/`COOL_MIN_MS` floors, top-center spout, dual-half-path border reveal, top-down
  cool sweep) via a different code path (dashed-stroke technique vs the reference's manual
  polyline stroke-by-arc-length). Functionally equivalent as far as a code read can tell; a
  literal byte-for-byte canvas port was judged not worth the regression risk this session. If a
  future session wants the exact reference visual (mottled-noise `moltenColor` formula vs
  `PourRing`'s hue-drift gradient), that's the remaining gap — not a missing feature.
- `tokens.css` was READ but deliberately NOT imported — its `:root` block defines `--bg`/
  `--text`/`--accent` etc. that COLLIDE by name with `src/index.css`'s pre-existing (differently
  valued, light/dark-mode) CSS vars, which other legacy components may depend on. The v3
  redesign already uses literal hex values inline (not CSS vars) throughout App.tsx/ensemble.tsx/
  the new tab views, and those literals already match the tokens.css values (`#101016`,
  `#e4e4ee`, `#7c7cf8`, `#4db89e`, etc.) — so the design system IS applied, just not via a
  shared stylesheet. Importing tokens.css for real would need renaming its vars first.
- Agents/History/Settings tabs are NEW, purpose-built full-page views — NOT the existing
  drawer components (`LibraryBinder`/`HistoryBinder`/`SelfRepairBinder`) repurposed. Those
  drawers are unconverted and still live, unchanged, inside the Chat tab's topbar button
  cluster (per the original brief's "keep existing structure/tools intact"). This means there's
  now SOME overlap (e.g. skill/tool browsing exists both in the Agents tab and the Library
  drawer) — worth deciding next session whether to fold the drawers into the new tabs or keep
  both.
- `SelfRepairBinder`/`SelfPatcherBinder`/`IntegrationsBinder`/`TasksBinder` have no tab-level
  home yet — they're still only reachable via the Chat tab's topbar icons.

**Cont. 36 (this session):**
1. **Fixed the build break** — added `EnsemblePill` to `src/ensemble.tsx` (a plain single
   toggle button; the old `ModeBar`'s Code/Search pills are gone for good, matching App.tsx's
   own comment "mode picker UI removed (v3)"). `tsc --noEmit` clean on `tsconfig.app.json`
   again; confirmed via `preview_start` (vite) — app boots to the (OAuth-gated) auth screen
   with zero console errors, same verification ceiling as cont.35b since the chat view itself
   still requires a real Google/GitHub login.
2. **Implemented the v3 handoff's BYOK key list** (`EnsembleKeyModal` in `src/ensemble.tsx`):
   replaced the old fixed 6-provider form (`BYOK_PROVIDERS`, always showing Mistral/Gemini/etc.
   input boxes) with a blank-slate, freely-named list — user types any name + pastes any key,
   `+ Add key`/`Remove` per row, stored as `NamedKey[]` in localStorage
   (`crucible_byok_named_keys`). Provider is auto-detected from the pasted token's own prefix
   (`detectKeyProvider()`: `sk-or-`→openrouter, `gsk_`→groq, `AIza`→gemini, `sk-`→openai,
   unrecognized → stored but flagged "not dispatchable yet" in the row). This was a judgment
   call reconciling the v3 spec ("no pre-baked provider fields... name freely") with the
   server's actual per-provider dispatch (`modelRegistry.resolveProviderKey`) — no code comment
   needed re-litigation per the handoff's own "make the closest reasonable call" instruction.
   **Caveat carried over from cont.35b, still true:** only `openrouter` is actually wired
   server-side (`server.ts` reads `resolveProviderKey('openrouter')` in exactly 2 places); a
   key that auto-detects as groq/gemini/openai is stored and shown correctly but the server
   won't use it yet — extending the SDK-client providers to accept BYOK keys per-request is
   still the next real step for those three, unchanged from before this session.

**NOT done this session (still the actual bulk of the v3 handoff, unstarted):**
- **Structural change #1** (delete the mode state machine entirely — `mode` state, remaining
  `research`/`seeker` MODE_META wiring) — NOT done; `mode` state and `MODE_META` still exist in
  App.tsx (`quorum`/`code`/`seeker`/`research`), just no longer auto-classified. The v3 brief's
  literal ask ("delete the mode state machine... zero external calls except via the pill") is
  ALREADY effectively true in behavior (no auto-escalation, confirmed cont.35), but the dead
  `seeker`/`research` states/menu remnants haven't been removed — check `modeMenuOpen`,
  `MODE_META`, and whatever still reads `mode==='seeker'`/`'research'` before assuming this is
  fully closed.
- **The MoltenPour canvas rewrite** — v3's handoff asks for a literal port of the prototype's
  `drawPour()` canvas methods into a new `MoltenPour.tsx`. The EXISTING `PourRing.tsx` (from
  cont.35b) already implements the same phase model (idle→pouring→done, live stream-driven,
  border-fill-tracks-card-height) by a different code path (dashed-stroke SVG-ish approach, not
  a raw `<canvas>` port) — functionally very close to spec per its own doc block above. Did NOT
  rewrite it as a literal canvas port this session; worth comparing directly against
  `Crucible v3.dc.html`'s `drawPour()` next time to decide if the existing implementation is
  good enough or needs the literal port.
- **The 56px left glass rail + Chat/Agents/History/Settings tab-nav** (task #4, still the single
  biggest unstarted structural piece, unchanged from cont.35b's description of it).
- **Settings → API keys as its own screen** (v3 puts key management under a Settings tab, not
  just a modal off the composer pill) — today's `EnsembleKeyModal` is still a modal, not a
  Settings-tab surface; low-risk to leave as-is until the tab-nav shell exists to house it.

**Also this session — root-caused why the Electron app "wasn't picking up backend changes":**
a manually-started detached `tsx server.ts` from the PRIOR DAY (`Sun Jul 5 22:05`) was still
squatting on port 3001. `electron.cjs`'s own `spawnBackend()` tried to bind 3001 too, crashed
silently with `EADDRINUSE` (only visible in `~/Library/Logs/Crucible-launch.log`), but
`waitForPort(3001)` doesn't check WHICH process answers — so the app window opened against the
stale day-old backend instead, with zero visible error. Killed the stale process and hardened
`electron.cjs`: `spawnBackend()` now calls a new `killStalePortOwner(3001)` (lsof+SIGKILL)
before every spawn, so this can't recur silently. Full detail in
[[crucible-run-commands]]. **The Desktop `Crucible.app` launcher itself was fine** (correctly
points at this repo) — the bug was purely the port race, not the launcher or the build step.
User should just quit and relaunch Crucible.app now to get a clean backend bound to current
code (the currently-open window, if any, is talking to the now-dead stale process).

**Next session should start by:** (a) reading the v3 handoff file directly (`Crucible UI
redesign/v3/HANDOFF - Claude Code implementation brief.md`) since it has exact current line
numbers for App.tsx's mode state/classifyMode remnants and the canvas port spec verbatim; (b)
deciding MoltenPour canvas-port vs keep-PourRing before touching animation code; (c) task #4
(left rail) is still the load-bearing remaining piece for the whole redesign to feel "done".

**Cont. 35b commits (all on `crucible-northstar-sessions`):**
- `9ef4aaf` — checkpoint of all verified cont.33/34 work (before touching App.tsx).
- `d112fed` — classifyMode no longer auto-escalates into ensemble; default mode `code` (local).
- `d34e123` — the v2 redesign slice (below).
- `c9db65f` — UNDOCUMENTED at the time; broke the build (see cont.36 above), fixed this session.

**What `d34e123` shipped:**
- **New component files:** `src/BackgroundBlobs.tsx` (ambient canvas backdrop, port of the v2
  `startBg`), `src/PourRing.tsx` (the FINAL 3-phase pour animation), `src/ensemble.tsx`
  (ModeBar pills + `useEnsemble()` toggle/BYOK store + `EnsembleKeyModal` + `EnsembleConfirm`).
- **App.tsx:** root bg `#101016` / text `#e4e4ee`; `<BackgroundBlobs>` mounted; ModeSwitcher
  (+ `MODES`/`Mode`) removed, replaced by `<ModeBar>`; reply card wrapped in `<PourRing>`
  driven by `round.synthDone/synthStreaming`; `send()` gains the ensemble opt-in+BYOK gate and
  sends `byokKeys` only for ensemble; key modal + per-query confirm modal mounted.
- **BYOK server plumbing:** `modelRegistry.ts` — AsyncLocalStorage scoping
  (`runWithByokKeys`/`enterByokKeys`/`resolveProviderKey`/`currentByokKeys`); `providerHasKey`
  activates a provider when the user supplies a key; `server.ts` `/api/chat` calls
  `enterByokKeys(byokKeys)`, `callModel` bypasses the shared key-proxy when a user key is
  present, and the OpenRouter branches read `resolveProviderKey('openrouter')`.
  **KNOWN LIMIT:** SDK-client providers (groq/mistral/gemini, instantiated once at module load
  with env keys) are still env-only — only OpenRouter (the recommended single BYOK key) is
  fully wired for user keys. Extending BYOK to the SDK providers = reinstantiate their clients
  per-request from `resolveProviderKey`, next-session work.

**PourRing animation — how it maps to the FINAL spec** (so the next session can tune, not
re-derive): phase = `idle` (pre-first-token) → `pouring` (streaming) → `done`. Pouring draws a
molten stream from the card's top-center spout, then fills BOTH border edges via two mirrored
half-paths dashed by an eased fill fraction that tracks live card height (ResizeObserver) with a
`POUR_MIN_MS=1350` floor; everything poured stays lit (3-pass bloom/glow/crisp). Done runs a
top→bottom cool sweep over `COOL_MIN_MS=1000` then clears to the card's default border. Motion is
routed through an eased current→target animator so choppy token streams still read fluid. Tune
the molten palette in `mottled()` and the floors as needed — spec is final, don't re-ask Justin.

**REMAINING redesign work (task #4, structural — the big piece left):** the v2 **56px left glass
rail** with Chat / Agents / History / Settings tab-nav + avatar, and the **Agents** and
**History** full-screen tabs (v2 has them as distinct screens; today the app is a single chat
view with drawer binders). This needs a `tab` state + screen router in App.tsx and restyling the
existing binders (Library/SelfRepair/History/Tasks/Integrations) into the new look. `Crucible
v2.dc.html` has the exact markup for all three tabs (Chat/Agents/History) — reimplement from it.
Also task #6 (gate the pipeline theater explicitly behind ensemble) is only implicitly handled
(local mode simply doesn't populate `round.models`, so the theater stays empty) — make it
explicit when building the tab shell.

**Design assets** (untracked, in `Crucible UI redesign/`): `Crucible v2.dc.html` (target),
`Crucible - Current UI.dc.html` (current), `support.js` (dc-runtime — these are divine.computer
design-tool exports, a VISUAL SPEC, not importable React). The canvas code in v2's
`<script>` (startBg/startMark/startRing) was the reference for BackgroundBlobs/PourRing.

## PRIOR (cont. 35 kickoff): NORTHSTAR UI/ROUTING REDESIGN STARTED
on branch `crucible-northstar-sessions`. Two clean commits landed: (1) `9ef4aaf` the entire
verified cont.33/34 body of work (NL-skill pipeline, /skill+/tool, RSI auto-approve) —
committed as a checkpoint before the redesign, at the user's explicit instruction; (2)
`d112fed` first redesign increment — Crucible-LOCAL is now the default path and the external
ensemble is never silently entered. The big visual redesign, BYOK ensemble gating, and the
3-phase pour animation are SCOPED + TASK-TRACKED but NOT yet built. Read the "cont.35 REDESIGN"
block immediately below before continuing.)

**Cont. 35 (this session) — NEW LARGE TASK RECEIVED mid-session: merge the `Crucible v2.dc.html`
UI redesign and make Crucible (local), not the external pipeline, the default experience.
Full brief lives in the user's handoff message + `Crucible UI redesign/` (untracked design
assets: `Crucible v2.dc.html` = target spec, `Crucible - Current UI.dc.html` = current, both
are design-tool exports with `{{ }}` template syntax — a VISUAL SPEC to reimplement, NOT
importable React).**

**Clarifying answers the user gave (authoritative for this redesign):**
1. **Commit current work first** → done (`9ef4aaf`).
2. **Crucible = local FM path** — BUT external API calls must be **opt-in AND bring-your-own-key
   (BYOK)**: end users supply their OWN keys, so Crucible doesn't infringe provider ToS if
   monetized. NEW durable constraint saved as memory [[crucible-byok-ensemble-constraint]].
3. **Ensemble opt-in = BOTH** a persistent per-session toggle AND a per-query "use ensemble?"
   confirm ask.
4. **Keep all coherent features**, restyle them into the new look (Library/SelfRepair/History/
   Integrations drawers, agent tool-calling all stay — verify post-merge, don't assume parity).

**DONE this session (commit `d112fed`, tsc clean, app boots — auth-gated so no deep UI check):**
- `classifyMode` (App.tsx ~2102) no longer escalates INTO `'quorum'` on complexity/research-verb
  heuristics — those two branches removed. It now only routes between local modes (code/seeker)
  and respects an explicit ensemble/research opt-in once chosen. This was the mechanism silently
  sending long/multipart prompts to the external pipeline with no consent.
- Default `mode` state + `preBrainModeRef` (App.tsx ~1874/1888): `'quorum'` → `'code'` (local).

**NOT DONE — the actual bulk of the redesign (task IDs #4-#7 in the tracker):**
- **#4 Visual redesign:** port `Crucible v2.dc.html`'s design system into App.tsx — 56px glass
  left rail (Chat/Agents/History/Settings nav + avatar), `#101016` dark-only bg, canvas bg
  layer, "Crucible" wordmark + ENSEMBLE badge topbar, its spacing/type/color tokens. App.tsx is
  a 5049-line monolith; `App()` = lines 1856-5049. Component map captured this session (ModeSwitcher
  ~50, PipelineTheater ~575, CritiqueGrid ~594, HistoryBinder ~1208, ClarificationCard ~1578,
  AuthScreen ~1753). Do it incrementally with tsc-clean/app-boots checkpoints, NOT one rewrite.
- **#5 Ensemble opt-in + BYOK (partially done — see above):** still need the persistent toggle +
  per-query confirm UI, and BYOK — `modelRegistry.ts` already has `providerHasKey()`/
  `PROVIDER_KEY_ENV` (env-var gating, line ~152-170); extend it to accept USER-supplied keys
  passed per-request, with NO bundled-key fallback and an "add your API key" affordance. Also:
  the server only has a SERVER-WIDE `CRUCIBLE_OFFLINE` env (server.ts ~2765), not a per-request
  local-vs-ensemble signal — that per-request plumbing is the missing server piece so the client
  default actually prevents external calls (right now `mode:'code'` non-agent chat can still fan
  out server-side; the client default is necessary but not yet sufficient).
- **#6** Move pipeline theater (PipelineTheater ~575, `crucible-pipeline-theater/status/log`
  classes ~579/4091/4713) behind the opt-in; restyle preserved features into the new look.
- **#7** Final 3-phase Crucible pour chat animation (idle tilt-loop → pour w/ molten border fill
  tracking live content height, ≥1.2-1.5s floor → upright fade + top-to-bottom cool, ≥0.8-1.2s).
  Spec is FINAL per the user — do not re-ask. Masked/clipped SVG or pseudo-element overlay driven
  by real stream lifecycle (send/first-token/stream-end). LAND LAST, once structure is stable.
- **Do NOT** regress the prior-session critic split-routing fix in synthDriver.ts/driver.ts
  (handoff says it's already verified — I did not touch it; note it wasn't in the working tree
  this session, so confirm it's already committed on this branch before assuming it's safe).

**Also still open from cont.34 (not lost, just deprioritized by the redesign):** Feature 4
(retrievalLayer recommendation cards, apply-gated) and the RSI trend-gate self-deadlock decision.

---

## PRIOR: 2026-07-06, cont. 34 — both cont.33 "next increment" items
BUILT AND LIVE-VERIFIED: (a) the verified NL-skill pipeline — a plain-language request in
the Library drawer now becomes a PROVEN catalog entry in `catalogs/user-skills.json`, first
real entry `user/slugify` landed via on-device FM + a NEW deterministic repair, prove:all
251/251; (b) the RSI auto-approve consumer — the 6h scheduler now routes every tick through
the stakes router (`rsi_cycle`, its FIRST non-filesystem consumer, priority-ladder item 3),
proposing-and-waiting by default and auto-approving only under the explicit AFK opt-in.)

**Cont. 34 (this session) — FABLE5_HANDOFF execution, second slice. All items below are
live-verified against a restarted `:3001` (current code IS running there now), not just
bench-verified.**

**1. Verified NL-skill pipeline (Feature 1 increment) — DONE.**
`src/CrucibleEngine/synth/userSkillPipeline.ts` (`buildUserSkill`): admission gate (the
request must declare an exact exported API and pin ≥2 worked examples `f(x) -> y`, else
honest rejection with guidance — no examples ⇒ nothing to prove ⇒ nothing enters the
library) → duplicate check (export-name collision against merged catalog + on-disk user
batch; an L0 primitive hit is also reported as "already covered") → `synthesizeUniversal`
(maxFmRounds 6, distill:false, oracle-gated on the request's own examples) → CatalogEntry
(patterns = exact export names at weight 0.9 per the skill-factory self-match convention;
tests[] = the SAME examples the oracle ran, via the new `extractSpecExamples` export from
derive.ts) → whole-user-batch `validate-batch` in scratch → append to
`catalogs/user-skills.json` → `generate:skills` + full `prove:all`, with rollback +
re-generate + re-prove on failure so the manifest never drifts from green. Server:
`POST /api/library/skills/build` (async job, 409 single-flight — FM + manifest contention)
+ `GET .../build/:id` polling; successful entries are pushed into the in-process
SKILL_CATALOG so the drawer/shortcuts see them without a restart. LibraryBinder's skill
BuildBox now calls this pipeline and renders a live status card (stage/message/detail,
amber on failure, dismissable) — browser-verified. **First proven user skill landed:
`user/slugify`** — FM round-1 candidate had the classic dash-run bug, the oracle rejected
it, the new repair fixed it deterministically, ALL PASS, batch oracle PASS, prove:all
251/251. Rejection paths (no examples / no API / hexToRgb duplicate) all verified too.

**2. 9th deterministic repair — `repairSeparatorRunNormalize` (repairProposers.ts).**
Added on a REAL recurrence: the FM failed slugify 9/9 rounds across 2 independent fires
with the same fingerprint (maps chars to '-' correctly but never collapses runs nor trims
edges; read from `.crucible/fm-rounds.jsonl` per the item-17 discipline before acting).
Closed-world: parses derive.ts's own `FAIL — name(...) === "want"  (got "got")` lines and
proposes ONLY when a single separator ('-'|'_') explains EVERY failing pair; transform
renames the export to a `__raw_` impl + re-exports a normalizing wrapper; oracle re-gates.
`__repairProposers_bench.ts` 11→14/14. This is what turned the pipeline's happy path GREEN.

**3. /skill + /tool slash shortcuts — DONE.** In server.ts `/api/chat`, ahead of ALL NL
intent classification: `/skill <id|filename|export>` writes the proven entry's impl to its
defaultPath in the project (reindexed, SSE tool_call/tool_result/final); `/tool <name>
[json|text]` executes the registry tool directly (JSON args or raw text mapped onto the
first required param), with fuzzy closest-match suggestions on unknown names. All paths
live-verified through authed `/api/chat` (emit → read back via `/tool read_file`).

**4. RSI auto-approve consumer (Feature 7 increment) — DONE, and it IS the stakes
router's first non-filesystem test case.** `assessStakes` gained an `rsi_cycle` branch:
the cycle is reversible by construction (snapshot→measure→keep-if-not-worse→restore), so
stakes reduce to pure AUTHORIZATION — the durable fully-automatic toggle is the standing
equivalent of EXPLICIT_VERBS. `runScheduledRsiTick()` (server.ts, next to the RSI
endpoints) replaces the old silent 6h `runRsiCycle` call: high stakes → `buildCycleProposal`
and WAIT (card appears in SelfRepairBinder); low stakes → approve pending-or-new proposal →
same gated cycle as the manual Apply → `recordProposalOutcome`. `POST /api/rsi/tick` fires
one tick on demand (ops/testing). `stakesRouter-bench.ts` 15→17/17. **Live-verified both
paths:** toggle OFF → `proposed` (plain-language reason) then `already-pending` on re-tick;
toggle ON → `auto-approved`, a real 222s cycle ran and honestly recorded
`failed/reverted — trend_down` onto the proposal. Auto-approve was restored to OFF
after testing (its pre-session state), so the scheduler is in propose-and-wait mode.

**5. OPEN OBSERVATION (flagged, deliberately not changed): possible RSI trend-gate
self-deadlock.** The last two cycles IMPROVED the benchmark (0.53→0.6, 0.47→0.6) yet both
reverted solely because `qualityPredictor.stats().trend === 'down'` (controller.ts step 5,
documented belt-and-suspenders). If the live trend stays down for a stretch, RSI
structurally cannot promote the very improvements that might fix the trend. Decide next
session: keep (conservative), or let a benchmark-IMPROVING (not merely holding) candidate
through despite a down trend.

**Verification summary:** `tsc --noEmit` clean on both configs; `prove:all` 251/251 (ran
as the pipeline's own gate post-landing); `__fuzz_bench` 31/31; `ambiguity:bench` 9/9;
`__repairProposers_bench` 14/14; `stakesRouter-bench` 17/17; drawer + status card verified
in the real browser preview (localStorage still had a stale `crucible_api_base=:3012`
override from cont.33's verification — cleared; watch for it when browser-testing).
Nothing committed (standing rule: no commit without an explicit ask).

**NEXT (in order): (a) Feature 4** — surface `retrievalLayer.ts` recommendations as cards
with apply-gated integration (drawer pattern exists; `retrieveForTask`/`rankByRelevance`
already compute everything; route accepts through applyLayer, never blind-paste);
**(b) decide the RSI trend-gate question above; (c) Feature 2** (conversation mode, scope
WITH Workstream 2 — read HITL_PLANNING_TRACK.md first); **(d) Feature 3** (Pocock research
pass); **(e) Feature 5** (parallel agentic calling — re-read crucible-agentic-architecture
memory first); **(f) Feature 6** (design note only). Also worth a quick pass: the NL-skill
pipeline requires literal worked examples by design — a fair v2 increment is having the
drawer SUGGEST example lines derived from the request before rejecting outright.

## PRIOR: 2026-07-06, cont. 33 — FABLE5_HANDOFF Features 1 and 7
BUILT AND LIVE-VERIFIED: skill/tool Library drawer + self-repair propose/explain/approve
drawer, both endpoint-tested with a minted JWT and browser-verified through the real UI.
Also: cont.32's pending 12-task regression sweep COMPLETED CLEAN — 10/12 HARD-green,
"No regressions vs the previous scorecard", caseCompareModule GREEN at full-suite level.)

**Cont. 33 (this session) — first execution slice of FABLE5_HANDOFF.md (read that file for
the full 7-feature plan; ROADMAP.md's sharpened 5-point MISSION block is the success bar).**

**1. Regression sweep from cont.32 — CLOSED.** Full 12-task `smoke:code` against the fixed
server: 4/4 catalog GREEN + 6/8 generation GREEN (filterModule, summaryModule, clampModule,
leaderboardModule, usernameModule, caseCompareModule). sortModule RED (unchanged accepted
boundary), tagSetModule RED (same genuine intersect-dedupe generation variance as cont.31,
rubric 40 — still below the repair-recurrence bar). Both cont.32 derive.ts fixes are
confirmed at full-suite level. No open verification debt from cont.32.

**2. Feature 1 (skill/tool Library drawer) — BUILT, VERIFIED.** New `GET /api/library/tools`
(built-ins from `registry.list()` + per-project dynamic tools) and `GET /api/library/skills`
(the merged 229-entry catalogIndex, `?q=` filtered) in server.ts (next to
`/api/debug/dynamic-tools`). New `src/LibraryBinder.tsx` — topbar trigger + frosted drawer
(same pattern as HistoryBinder/IntegrationsBinder) with two nested collapsible sections
(Skill Library · 229 / Tool Library · 49 built-ins + dynamic), live search, and a
plain-language "describe it, have it built" BuildBox per section that routes the request
into the agent loop (tools land on the existing `create_tool` persistence path;
`.crucible/dynamic-tools/`). Verified: endpoints curl-tested with minted JWT (229 skills,
`?q=semver`→3, 49 tools), drawer opened/searched/screenshotted in the real browser preview,
tsc clean. **REMAINING from Feature 1:** the NL skill request currently routes through the
agent as a normal build task — the dedicated generate→validate→`catalogs/user-skills.json`
pipeline (so NL-built skills become PROVEN catalog entries automatically) is not built;
that's the next Feature-1 increment. Slash shortcuts (`/tool <name>`, `/skill <name>`)
also not built.

**3. Feature 7 (self-repair propose/explain/approve) — BUILT, VERIFIED.** New
`src/CrucibleEngine/rsi/proposals.ts`: `RsiProposal` records persisted to
`.crucible/rsi-proposals.json`, `buildCycleProposal()` composes a plain-language
what/why/how/risk card from REAL live signals (quality-history size, qualityPredictor
trend, learned-weights balance, RSI cycle track record) with zero model inference;
`resolveProposal`/`recordProposalOutcome` carry the cycle's honest verdict back onto the
record; one-pending-at-a-time guard; `isAutoApproveEnabled`/`setAutoApprove` opt-in flag
(`.crucible/rsi-auto-approve.json`). Five new endpoints in server.ts next to the existing
RSI block: `GET /api/rsi/proposals`, `POST /api/rsi/propose` (409 on duplicate pending),
`POST /api/rsi/proposals/:id/approve` (runs the normal gated `runRsiCycle` with the same
`buildRsiDeps()` as `/api/rsi/cycle`; outcome recorded on completion),
`POST .../:id/reject`, `POST /api/rsi/auto-approve`. New `src/SelfRepairBinder.tsx` drawer:
track-record header (real data: 34 runs / 2 kept / 14 auto-undone), pending-proposal
decision card (Apply / Not now), running state with 5s polling, history with honest
outcome labels, fully-automatic toggle. Verified end-to-end: propose→409-duplicate→reject
via curl; propose→plain-language card→"Not now" through the real browser UI; approve
verified live END-TO-END: a real gated cycle ran on the :3012 instance, learned state
dipped on re-measure, the cycle honestly REVERTED, and `recordProposalOutcome` wrote
`status:failed / verdict:reverted / "Quality dipped on re-measure — changes were
automatically undone."` onto the proposal record — the complete propose→approve→run→
honest-outcome loop is proven, including the safety path. tsc
clean throughout. NOTE: the auto-approve flag is stored+toggleable but nothing CONSUMES it
yet (no scheduler auto-runs cycles when it's on) — wiring it into the idle scheduler is the
next Feature-7 increment, and per FABLE5_HANDOFF this approval gate should become the first
concrete test case of the HITL/AFK stakes router (priority-ladder item 3).

**Verification environment note:** all live checks ran against a SECOND server instance
(`PORT=3012 CRUCIBLE_OFFLINE=strict`) + the vite preview with `crucible_api_base` localStorage
override, so the primary `:3001` (mid-sweep) was never disturbed. `:3001` still runs
pre-cont.33 code — restart it onto the current commit before any sweep that touches the new
endpoints. The 12-task suite does NOT touch them, so the clean sweep above is valid.

**NEXT (in order): remaining FABLE5_HANDOFF features** — (a) Feature 1 increment: verified
NL-skill pipeline + slash shortcuts; (b) Feature 7 increment: auto-approve consumer in the
idle scheduler; (c) Feature 4 (retrieval recommendations surface — `retrievalLayer.ts`
already ranks, just needs the drawer card + apply-gated integration); (d) Feature 2
(conversation/plan mode — scope WITH Workstream 2, read HITL_PLANNING_TRACK.md first);
(e) Feature 3 (Pocock research pass); (f) Feature 5 (parallel agentic calling — biggest bet,
re-read crucible-agentic-architecture memory first); (g) Feature 6 (design note only).

**Cont. 32 (this session) — audit-only continuation of cont.31's explicit "not yet
live-confirmed" item: `derive.ts`'s `comparator` family "unconditionally tests both
numeric AND string calls on every comparator regardless of declared type."** Confirmed
by reading the code (`src/CrucibleEngine/synth/derive.ts:216-232` pre-fix): every
comparator match unconditionally emitted BOTH a numeric-pair assertion
(`${name}(1, 2)`) AND a string-pair assertion (`${name}('a','a')`), regardless of the
spec's declared parameter types. A comparator explicitly typed `(a: string, b: string)`
(a very ordinary shape — e.g. `compareVersions(a: string, b: string): number`) would hit
the identical unwinnable-oracle-gate bug as `tagSetModule`: the generated property-test
file itself fails `tsc` (`Argument of type 'number' is not assignable to parameter of
type 'string'`) before any candidate is even judged. This had NOT yet fired live (no
comparator-family generation-stress task exists yet), so this was caught by inspection,
same discipline as cont.30's proactive fuzz-family audit — not a live-repro this time.

**Fix (same pattern as cont.31's set-op fix):** reused the existing `getSpecParamsRaw()`
helper to sniff the spec's declared signature; when explicitly `string`-only, emit just
the string assertions; when explicitly `number`-only, emit just the numeric assertions;
untyped/generic signatures (the common case, no declared types) are unchanged — still
get both, exactly as before. Scratch-verified directly against `derivePropertyTests()`
with three synthetic specs (string-typed `compareVersions`, number-typed `compareNums`,
untyped `compare`) — confirmed each produces only the assertions that will actually
typecheck, and the untyped case is byte-identical to the old unconditional behavior.
`npx tsc --noEmit` clean, `npm run prove:all` 250/250 unchanged (no catalog skill uses
this family's code path with a string-typed comparator, so no regression risk there).

**Not done:** did not add a new generation-stress task to exercise this live (e.g. a
`versionCompareModule` task with a `string`-typed comparator) — this fix closes the
identified risk but, like cont.30's fuzz-family audit fixes, has zero live-fire
confirmation yet. That is the natural next verification step, same shape as how
cont.31 closed the loop on cont.30's two new tasks. Did not touch any other `derive.ts`
family — no other family was flagged as having this risk.

## PRIOR: 2026-07-06, cont. 31 — live-fired the 2 new tasks from
cont.30; tagSetModule's first fire was RED at 0% (module never produced) and root-caused
to a REAL oracle bug in `synth/derive.ts`'s `set-op` family — same audit discipline as the
sum/summarize fix, this time caught on first live contact rather than by proactive
inspection. Fixed, re-verified, and a full 11-task sweep confirms no regressions.

**Cont. 31 — continuation of cont.30's "not yet live-fired" open item.**
Restarted `:3001` clean (`CRUCIBLE_OFFLINE=strict` in the server's own env) and fired
`usernameModule`/`tagSetModule` live. `usernameModule` GREEN first try (11/11 hidden,
genuine generation signal). `tagSetModule` RED: `module exists FAIL` — the FM never
produced a passing candidate at all, oracle honestly escalated after 3 rounds with an
identical compile-error fingerprint.

**Read `.crucible/fm-rounds.jsonl` before guessing (the item-17 discipline) — found a real
oracle bug, not an FM capability gap.** The repeating error was
`__property__/spec.test.ts(10,64): error TS2322: Type 'number' is not assignable to type
'string'` — `synth/derive.ts`'s `set-op` family (union/intersect/difference) hardcodes
NUMERIC literal test data (`[1,2,3]`, etc.) unconditionally, regardless of the task's real
declared parameter types. `tagSetModule`'s spec correctly declares `string[]` params
(`unionTags(a: string[], b: string[])`), so the auto-generated property-test file itself
failed to compile — an unwinnable oracle gate no candidate could ever pass, same failure
class as the `localHardenFuzz.ts` type-collision risks found earlier this session, but in
the DIFFERENT derive.ts/oracle-side property-test system (built from the spec's own prompt
text before any candidate exists, not from candidate code).

**Fixed:** `getSpecParamsRaw()` + a type-aware `arr()` literal-builder in `derive.ts`'s
set-op block — sniffs the spec's own declared signature and switches to string literals
(`'a'`,`'b'`,...) preserving the exact same overlap/dedup relationships when the params
are explicitly typed `string[]`; numeric/untyped specs are unaffected. Scratch-verified
directly against `derivePropertyTests()` with the real `tagSetModule` prompt text before
touching the live server (confirmed string literals + no assertion-semantics change).
`npx tsc --noEmit` clean, `npm run prove:all` 250/250 unchanged (set-op catalog skills use
numeric specs, untouched by this branch).

**Re-verified live, 3 fires total post-fix:** `tagSetModule` now reliably reaches
`module exists PASS` + `compiles clean PASS` + hidden suite (previously 0/1 ever got that
far) — the oracle bug is confirmed fixed. Hidden-suite result is now genuine
generation-quality signal: fire 1 caught a severely broken `intersectTags` (inverted
membership check, `result.includes(tag) && b.includes(tag)` — can never be true from an
empty result, so intersect returns near-empty); fire 2 and fire 3 caught a narrower,
DIFFERENT bug (`intersectTags` correct but doesn't dedupe when `a` itself has repeated
tags). **Deliberately did NOT add a `repairProposers.ts` entry** — the two bugs are not an
identical recurring fingerprint (this project's established 2-3-identical-recurrence bar
for adding a repair, see items 30/31 in [[crucible-coding-harness]]), they're genuine
FM-generation variance on this task shape. `tagSetModule` is RED 3/3 so far but for a real,
hand-verifiable reason each time, not an oracle artifact — legitimate new generative-
capability signal, the exact goal of broadening the suite.

**Full 11-task sweep run after the fix + server restart, to check for regressions:**
4/4 catalog GREEN (kvstore/ratelimiter/scheduler/regex, unaffected as expected — derive.ts's
set-op branch isn't in their path). Generation tasks: filterModule, summaryModule,
leaderboardModule, usernameModule all GREEN; sortModule RED (unchanged accepted boundary,
untouched per instruction); clampModule RED this run (oracle rejected 3 candidates with an
identical clamp-bounds failure shape, honestly escalated) — this is FM-generation
variance unrelated to this session's derive.ts change (clampModule uses the
`number-transform-clamp` family, a different code branch never touched this session);
consistent with this suite's long-documented run-to-run flakiness, not a regression.
tagSetModule RED as above (genuine signal, not oracle). **Net: 8/11 HARD-green
(4 catalog + 4 generation), 4/7 generation tasks GREEN** — no regressions vs. the pre-
session scorecard on any task this session didn't touch.

**Not done:** did not chase clampModule's flake (single-run, no established recurrence,
matches known variance); did not add a repair for tagSetModule's intersect-dedupe gap
(correctly below the recurrence bar); did not extend the type-aware literal fix to
`derive.ts`'s `comparator` family, which has a DIFFERENT, not-yet-live-confirmed risk
(it unconditionally tests both numeric AND string calls on every comparator regardless of
declared type — `comparator: correct string comparator, non-numeric params` audit-worthy
next, same discipline, no live evidence yet).

## PRIOR: 2026-07-06, cont. 30 — generation-stress suite broadened
5→7 tasks (usernameModule, tagSetModule) hand-verified against reference+buggy impls; a
proactive audit of every fuzz-family name-regex (same discipline that found the
summarize/sum collision) found and fixed 3 real type-collision false-positive risks in
`localHardenFuzz.ts` before any live sweep surfaced them)

**Cont. 30 (this session) — explicit ask: broaden the generation-stress suite beyond 5
tasks, leave sortModule's accepted capability boundary alone, and apply the
"is-the-checker-even-testing-the-right-contract" audit discipline (item 31's
summarize/sum lesson) to other fuzz families PROACTIVELY, not just when a live sweep
happens to surface a collision.**

**1. Two new generation-stress tasks added to `coding-benchmarks.ts` (5→7):**
`usernameModule` (standalone, `validator` family — `isValidUsername(name): boolean`,
3-20 chars/leading-letter/alnum-or-underscore rules) and `tagSetModule` (repo-context,
exercises BOTH `set-op-union` and `set-op-intersect` in one task —
`unionTags`/`intersectTags(a: string[], b: string[]): string[]`, no-mutation +
no-duplicates rules). Both confirmed not already covered by the skill catalog (checked
`validatorsB.json` for username-shaped validators, all catalogs for union/intersect —
only an unrelated `segmentsIntersect` geometry primitive exists). New hidden suites
(`coding-bench/usernameModule.hidden.ts`, `tagSetModule.hidden.ts`) hand-verified in
scratch BEFORE committing, same discipline items 9/21 used: a correct reference impl for
each passes 11/11 and 10/10 clean, and a deliberately buggy variant for each (missing
leading-letter rule; in-place-mutating union + wrong-answer intersect) is caught with
precise got/expected output. **Not yet live-fired against the actual agent** — these are
hand-verified test-design correctness, not a live GREEN/RED read; that's the natural next
step before trusting them as a live signal.

**2. sortModule:** untouched this session, per explicit instruction — its structural
conditional-grouping miss (item 16 in [[crucible-coding-harness]]) stays the one
documented, accepted capability boundary. No code touched, no new investigation opened.

**3. Proactive fuzz-family contract audit (the actual point of this session) — read
every `detectChecks()` name-regex in `localHardenFuzz.ts` the way item 31 diagnosed
`/^sum/i` matching `summarizeByAccount` post-hoc, but BEFORE a live sweep forced the
issue.** Found 3 real risks, all sharing one root cause: a family's name+arity gate can
match a real, common function whose declared TS parameter TYPES don't match the family's
numeric fuzz-input assumption, and the resulting throw/type-mismatch inside `fc.assert`
would be misreported as a genuine counterexample on perfectly correct code:
   - `comparator` family (`/^(compare|...)/`, arity 2) would misfire on something like
     `compareVersions(a: string, b: string): number` — fuzzes with random integers,
     `a.split('.')` throws on a number.
   - `set-op-diff` family (`/^(difference|subtract|complement)/`, arity 2) would misfire
     on `differenceInDays(a: Date, b: Date): number` — a very ordinary date-math helper
     name, not a set operation at all.
   - `array-dedupe` family (`/^(dedupe|unique|distinct)/`, arity 1) would misfire on
     `uniqueId(prefix: string): string` — an ID generator, not an array dedupe.
   None of these three had actually fired live yet (unlike item 31's summarize case,
   which needed 3 live recurrences before the root cause was found) — this audit found
   them by inspection first. **Fix:** added `paramsLookNonNumeric()` in
   `localHardenFuzz.ts` — sniffs the raw declared parameter-type text for an explicit
   `string`/`Date`/`boolean` annotation and skips the numeric-input families (sort,
   comparator, set-op-*, clamp, array-dedupe, number-aggregate-sum) when found, leaving
   `validator`/`string-transform` (which correctly expect real strings) untouched. Added
   3 regression cases to `__fuzz_bench.ts` (28→31/31, all passing) — one per collision
   shape, each asserting the correct-but-non-numeric-typed candidate produces NO finding.
   `npx tsc --noEmit` clean, `npm run prove:all` 250/250 unchanged throughout.

**Not done this session:** no live `smoke:code` sweep (neither the 2 new tasks nor the
fuzz-audit fix were fired against a running server) — the two new tasks are hand-verified
design-correct but have zero live pass/fail history yet; that's the natural next step.
Did not extend the same param-type audit to `localHardenCheck.ts`'s AST scanner (a
different gate, item 25 already gave it its own mirror-image audit pass) or to
`derive.ts`'s oracle-side family conventions (a related but separate system from the
harden-fuzz layer audited here) — worth doing the same discipline there next if this
proactive-audit pattern keeps paying off.

## PRIOR: 2026-07-05, cont. 29 — cont.28's flagged summaryModule
empty-array shape recurred 2 more times (3 confirmed total) but turned out to be an ORACLE
false positive, not an FM bug — fixed the fuzz classifier, not repairProposers.ts

**Cont. 29 (this session) — picked up cont.28's explicit next step: re-run the authed
debug-stream-tail technique against summaryModule + the 4 non-sortModule generation tasks a
few more times to see if the byte-identical `Counterexample: [[]]` empty-array shape recurs;
2-3 confirmed recurrences was the stated bar for writing a 9th repairProposers.ts entry.**

Minted an authed JWT ([[crucible-local-auth-testing]]), tailed `GET /api/debug/stream` to a
scratch log, and fired `summaryModule` 3 times and `clampModule` once via `npm run smoke:code`
while the tail ran. **The shape recurred all 3 times** — byte-identical
`summarizeByAccount fails the number-aggregate-sum property ... Counterexample: [[]]` at iters
7/8/9 every single fire, clearing the 2-3-recurrence bar cont.28 set.

**But investigating WHY before writing a repair proposer changed the diagnosis entirely: this
is not an FM generation bug, it's an oracle false positive — the exact same name-collision
class as items 11/24/25.** `localHardenFuzz.ts`'s `detectChecks()` classified
`summarizeByAccount` into the `number-aggregate-sum` fuzz family because its old regex was
`/^sum/i && arity===1` — it matches any name starting with "sum" with one argument, including
"summarize", regardless of what the function actually returns. `summarizeByAccount` returns a
`Record<string, {...}>`, not a number, so the fuzz property's `typeof r !== 'number'` check
fails on EVERY call unconditionally — no possible generated code could ever satisfy this
check, which is why the finding was byte-identical every time and why it always harmlessly
self-corrected by iter 10 (the harden critic is soft, not a hard gate). Writing a 9th repair
proposer would have been the wrong lever entirely — there is no code fix for a check that's
testing the wrong contract.

**Fix (not repairProposers.ts): narrowed the classifier regex** to
`/^sum(?:[A-Z]|$)/` — requires a camelCase boundary right after "sum" (matches `sumValues`,
bare `sum`; rejects `summarize*`/`summary*`), same convention `^is[A-Z]` already uses one line
above it in the same function. Added a regression case to `__fuzz_bench.ts` (27→28/28, the
exact `summarizeByAccount` shape asserted clean). `npm run prove:all` → 250/250 unchanged.
**Re-verified live, not just via the bench:** re-fired `summaryModule` (still GREEN, 14/14
hidden, zero `number-aggregate-sum` finding in the fresh debug-stream capture — confirms the
fix, not just the unit test) and `clampModule` (GREEN, unaffected — confirms no regression on
an unrelated fuzz family).

**Net this session: 0 lines changed in repairProposers.ts or loop.ts** — the honest answer to
cont.28's open question was "the recurrence was real, but it wasn't an FM bug," not "add a 9th
proposer." Lesson for future sessions applying this same investigate-before-fixing discipline:
a harden/fuzz finding that survives 3 confirmed live recurrences is strong signal SOMETHING is
wrong, but check whether the checker itself is testing the right contract before assuming the
generated code is at fault — the fix belongs wherever the false signal actually originates.

## PRIOR: 2026-07-06, cont. 26 — clean generation-stress baseline
confirmed post-ambiguity-fix (4/5 gen tasks GREEN, sortModule the only accepted boundary);
first three commits of the session landed; a new deterministic repair added for
leaderboardModule's mutation bug, with an important caveat about which path it actually covers)

**Cont. 26 (this session) — committed the full accumulated session (3 commits: agent/HITL
layer, deterministic critic layer, docs — see `git log`), then re-ran the generation-stress
suite live now that the ambiguity gate fix (cont.25) is in place, to get the clean baseline
that fix was blocking.**

**Clean baseline, live-verified:** filterModule GREEN (15/15 hidden), summaryModule GREEN
(14/14 hidden), sortModule RED (the pre-existing, documented ACCEPTED capability boundary —
unchanged, not a new regression), clampModule GREEN (from cont.24's session), leaderboardModule
RED (reaches the hidden suite now, per cont.25 — fails on a mutation bug, a completely
different failure mode from "never attempted"). **4 of 5 generation tasks are GREEN** — the
healthiest read this suite has ever had, and for the first time one we can trust wasn't
undercounted by the ambiguity-gate bug.

**New deterministic repair added, with a real scope caveat found while adding it:**
`repairProposers.ts` gained `repairMutatingSort` — rewrites a bare `paramName.sort(...)` (which
mutates its argument) to `[...paramName].sort(...)`, gated on the fuzz layer's own
mutation-failure message text. The regex structurally cannot false-fire on already-correct
`[...x].sort(...)` or `x.slice().sort(...)` forms (a `]`/`)` sits between the identifier and
the dot in both). Verified directly against leaderboardModule's exact failing candidate — the
proposed repair is byte-identical to hand-writing the fix. **Caveat found while wiring this
in: `repairProposers.ts`/`proposeRepairs` is only called from `universal.ts` — the synth/oracle
round-based generation path — never from `agent/loop.ts`, the interactive tool-calling path
`smoke:code`'s live agent-mode benchmark actually uses.** So this repair does NOT fix
leaderboardModule's specific failure in the benchmark as currently run (mode:agent); it's
real, verified, and immediately useful for any task that goes through the synth/oracle path
(e.g. `synthesizePureCode`), but bringing deterministic repair to the agent-loop path is a
distinct, not-yet-done architectural step — flagged here rather than overclaimed as fixed.
Also: `repairProposers.ts` (7 pre-existing repair functions plus this new one) had ZERO test
coverage anywhere in the repo — added `__repairProposers_bench.ts` (11/11: one true-positive
per repair, two false-positive no-op guards for the new repair, one no-signal-no-repair
baseline), wired into `npm run prove:all` (`repair:bench`). `tsc` clean, `prove:all` 250/250.

**Not done this session:** bringing deterministic repair (or ANY repairProposers-style
mechanism) to `agent/loop.ts`'s interactive path — this is the concrete next step for actually
closing leaderboardModule's live benchmark failure, not just adding a repair that's reachable
from a different code path. Re-running clampModule/leaderboardModule together in one sweep to
double check nothing conflicts (each was tested separately this session).

## PRIOR: 2026-07-06, cont. 25 — CRITICAL FIX: ambiguity.ts's live-wired
gate (shipped cont.20) was silently killing real coding tasks at 0 iterations — a structural
false positive found by live-firing an actual benchmark task, not by code audit. Live-verified
fixed: leaderboardModule went from 0 iterations (never attempted) to 10 iterations reaching the
hidden suite.)

**Cont. 25 (this session) — while re-verifying cont.22's fuzz fix with a real live sweep
(routine confirmation, not expected to find anything new), `leaderboardModule` fired 0
iterations and produced nothing. This turned out to be the single highest-impact finding of
the session: ambiguity.ts's DEF_REF heuristic, live-wired into loop.ts since cont.20, has an
effectively unbounded false-positive rate on ordinary prose, and was actively preventing the
agent from attempting well-specified tasks.**

Root cause, confirmed via `/api/debug/history`: an `ambiguity_gate` event with 5
`unresolved-reference` signals (confidence 0.031) fired on leaderboardModule's spec BEFORE the
agent made a single tool call — `resolveAmbiguity` misread ordinary prose ("the COMPLETE...",
"the exact API...", "...that sorts a mixed list...", "confirms... that the input...") as 5
distinct unresolved code-symbol references and short-circuited straight to a clarification
stop, exactly the documented-but-never-fixed DEF_REF false-positive class (cont.17 already
fixed ONE instance of this, "that returns" → VERB_STOPLIST). Patched the 4 specific words
first (STOP_REFS: exact/complete/ordering/the/this/that/a/an; VERB_STOPLIST: sort/sorts/
sorted/sorting) — then, before declaring it closed, wrote a standalone script testing
`resolveAmbiguity` against the literal prompt text of **all 9 of this repo's own benchmark
tasks** (kvstore/ratelimiter/scheduler/regex/filterModule/sortModule/summaryModule/
clampModule/leaderboardModule). Result: **6 of 9 were STILL falsely flagged ambiguous** even
after the word-list patch (new false hits: "the least", "the WAL", "the injected", "the
rolling", "the preceding", "the primary", "the calls", "the account", "the credits" — a
different set of common words every time), proving conclusively that a hand-maintained
stoplist can never keep pace with ordinary English prose.

**Structural fix, not another word added to a list:** `resolveAmbiguity` now only generates
`unresolved-reference` signals when the goal does NOT already name a concrete target file
(`FILE_TOKEN` — the same check the `no-target` signal already used, just computed earlier and
reused). Rationale: DEF_REF's entire purpose is catching "fix THE parser" — a request that
refers to something via a definite article WITHOUT naming any concrete target. Once a file
path IS named (as every one of this repo's own benchmark specs does), the "what to change"
question is already answered, so hunting for other "the X" phrases in the surrounding
rules/behavior prose adds no real signal, only false positives. Auto-resolution (the single-
index-match rewrite) still runs unconditionally — it's purely additive goal enrichment, never
a source of a false "ambiguous" verdict, so no reason to gate it. Re-ran the all-9-prompts
check: **9/9 clean.** `ambiguity-bench.ts` still 9/9 (the "fix the parser" cases all have no
named file, so the gate correctly still applies there — verified this isn't a blanket
disable). `tsc` clean, `prove:all` 250/250.

**Live-verified end to end, not just via the standalone script:** restarted `:3001` clean
(`CRUCIBLE_OFFLINE=strict`, single LISTEN pid) and re-fired `leaderboardModule` through
`npm run smoke:code:offline`. Before the fix: `iters=0`, module never written. After the fix:
`iters=10`, module written, **compiles clean, reaches the hidden suite for the first time**
(still RED — the FM's candidate mutates the input array in place, the pre-existing
`sortScoresAscending` capability gap items 21-22 already characterized — but that's a
completely different, already-documented failure mode from "the task was never attempted at
all"). This is not a hypothetical fix — it demonstrably unblocks real task attempts.

**Why this matters more than every other fix this session combined:** items cont.22-24 all
hardened critics against bugs the FM might write. This fix removes a gate that was silently
preventing the FM from being given a chance to write anything at all, on the majority of
realistic, well-specified coding requests, the moment a semantic index is available (i.e. on
essentially every real repo-context task) — since cont.20 wired this gate into the actual live
`agent/loop.ts` path. **Any generation-accuracy measurement taken between cont.20 (2026-07-04)
and this fix should be treated as unreliable** — a nonzero fraction of "the FM failed" reads
during that window were likely actually "the request never reached the FM." No way to
retroactively quantify how much of item 2's measured gap this explains without re-running the
full generation-stress suite, which is the natural next step.

## PRIOR: 2026-07-06, cont. 24 — Gate A3 (contractGate.ts) audited next;
found and fixed a real FALSE POSITIVE that was actively hurting generation accuracy, not just
a missed-detection gap; both Gate A2 and Gate A3 gained their first-ever bench, wired into
`prove:all`)

**Cont. 24 (this session, continuing the systematic critic audit) — extended the mirror-image
audit from localHardenFuzz/localHardenCheck to the two Workstream-1 gates that hadn't been
touched yet (Gate A2 lintGate.ts, Gate A3 contractGate.ts).**

**Gate A3 (`contractGate.ts`) had a real, previously-unknown FALSE POSITIVE — worse than a
missed detection, since it actively rejects correct code.** `actualSignatures()` only
recognized `export function name(...)` (TS `FunctionDeclaration`). A candidate written as
`export const name = (a, b): R => ...` (arrow function) or
`export const name = function(a, b): R {...}` (function expression) — an equally common,
equally correct style — was completely invisible to it: `checkContract` reported "missing
export" and rejected a CORRECT candidate, burning an FM retry round on nothing. Confirmed live
before the fix (`checkContract` on a correct arrow-const candidate → rejected) and after
(→ accepted, while arity mismatches and non-exported bindings are still correctly caught).
Fixed: `actualSignatures` now also walks exported `const name = <arrow|function-expression>`
declarations. **This directly serves item 2 (generation accuracy) in a way none of the prior
fixes did** — every prior fix this session hardened a gate against bugs the FM might write;
this one removes a gate rejecting correct FM output for a superficial style reason, which
means Gate A3 was silently degrading the FM's effective pass rate on any spec whose actual
implementation preferred arrow-function style. Checked `.crucible/fm-rounds.jsonl` (599 lines)
for a historical `"verdict":"contract:..."` rejection — zero hits, so this specific bug hasn't
been observed to have actually fired on the current generation-stress suite's tasks (the FM
happened to always write `export function` style for these); it's a real, confirmed defect via
direct test, not a proven explanation for any of the measured item-2 gap. Still worth watching
for on future/different tasks now that it's fixed rather than latent.

**Gate A2 (`lintGate.ts`) had zero known defects** — it wraps trusted ESLint rules, so the
risk profile is wiring regressions (e.g. the already-once-hit flat-config `files` matcher
pitfall), not incomplete pattern coverage. No fix needed, but it had no bench either.

**Both gates had NO test coverage anywhere in the repo before this session** — same
test-debt-cleanup discipline as cont.20's `localHardenCheck` bench. Added
`__contractGate_bench.ts` (10/10: the arrow/function-expression false-positive case, arity
mismatches in both declaration styles, missing-export, non-exported-binding, return-type
widening-to-any allowed, return-type array-ness mismatch caught) and `__lintGate_bench.ts`
(12/12: one true-positive per configured ESLint rule + one clean-code true-negative). Both
wired into `npm run prove:all` (`contract:bench`, `lintgate:bench` scripts added). `tsc`
clean, `prove:all` 250/250 unchanged (bench suites run before the 250-skill catalog check,
same pattern as the other 3 bench suites already wired in).

## PRIOR: 2026-07-06, cont. 23 — localHardenCheck.ts's 5-shape AST scanner audited the same
way the fuzz layer was in cont.22; found 5 MORE real false-negative gaps, all fixed

**Cont. 23 (this session, continuing cont.22's methodology) — the item flagged as "not done
this session" in cont.22 ("localHardenCheck.ts wasn't audited for analogous gaps") is now
done.** Read all 5 AST checks looking for the same class of defect found in the fuzz layer:
an operand/statement-shape the check silently doesn't recognize even though it's the identical
bug. Found and fixed 5, each confirmed live before AND after the fix:
1. `checkOffByOneLoopBound` only matched `i <= arr.length` (loop var on the left) — the
   logically-identical reversed form `arr.length >= i` passed clean. Now handles both.
2. `checkOffByOneTerminalAccess`'s `X.length + k` addition only checked length-on-the-left —
   `arr[1 + arr.length]` (operands swapped) passed clean. Now checks both operand orders.
3. `checkAssignmentInCondition` only visited `if`/`while`/`do-while` — `for (...; i = 1; ...)`
   (same always-truthy-assignment typo, different statement) passed clean. Now also visits a
   for-loop's own condition slot; verified no false positive on the legitimate
   `while ((x = next()) != null)` resumed-value idiom.
4. `checkNaNComparison` only matched the bare `NaN` identifier — `x === Number.NaN` (same
   global value, spelled via the `Number` namespace) passed clean. Now matches both forms.
5. `checkDivideByZeroLiteral` only matched the binary `/`/`%` operators — the compound
   assignment forms `x /= 0`/`x %= 0` (same bug) passed clean. Now matches both.
`__localHardenCheck_bench.ts` grew 10→16/16 (one regression case per fix). `tsc` clean,
`prove:all` 250/250 unchanged. All 5 are genuine reversed-operand/unvisited-statement blind
spots in a pattern-matching AST scanner — exactly the kind of gap that's invisible until you
go looking for the mirror-image of each existing pattern, which is what this pass did
systematically rather than waiting for a live sweep to surface one by accident.

**Cont. 22 recap (prior entry, kept for continuity):** found and fixed 5 real defects across
the fuzz-property gate (set-op-diff/intersect completeness, comparator degenerate-zero, clamp
flakiness) and the stakes-router (multi-tool-call gating, create_tool body scanning).

**Cont. 21 recap (prior entry, kept for continuity):** items 1 (frontend clarification
consumer) and 3 (HITL stakes-router) turned out to already be built, uncommitted, just
undocumented. Item 2's `leaderboardModule` Set-dedup bug was fixed (sort-family fuzz range
narrowed). See git history of this file / [[crucible-priority-ladder-2026-07-04]] for detail.

**Cont. 22 (this session) — driven by an explicit "keep going, no API calls, frontier-rivaling,
don't stop for input" directive. Audited every fuzz family and the stakes-router's own
documented scope gaps rather than picking a new task; found 4 more real, previously-invisible
defects in the verification layer itself.**

1. **`set-op-diff`/`set-op-intersect` fuzz properties had NO completeness check — `() => []`
   passed both silently, always, regardless of input.** Only "nothing foreign appears in the
   result" was ever checked, never "every qualifying element is actually present." Confirmed
   live: a candidate that always returns `[]` for `differenceArrays`/`intersectArrays` passed
   the gate with zero findings. Fixed both properties to also assert every expected distinct
   value is present (mirrors `set-op-union`'s existing two-directional check), and narrowed all
   three set-op families' integer range to `{min:0,max:8}` so `a`/`b` actually overlap often
   enough to exercise the new check (`localHardenFuzzWorker.cjs`). Added 2 regression cases.

2. **`comparator` property couldn't detect a degenerate "always return 0" comparator** — a
   comparator that treats every pair as equal trivially satisfies the old antisymmetry-only
   check (`a===b` branch aside, `ab===0 && ba===0` both hold). Confirmed live: `() => 0` passed
   clean. Fixed: for a distinct pair, `ab===0` is now itself a failure (documented as a
   heuristic tied to this family's naming convention — see the code comment on the honest
   tradeoff). Added 1 regression case.

3. **`number-transform-clamp`'s property was genuinely flaky — observed ~15-30% false-negative
   rate across repeated bench runs**, unrelated to anything touched this session or last.
   Root cause: `fc.double()`'s default arbitrary heavily biases samples toward "interesting"
   edge values (0, -0, tiny fractions) rather than spreading uniformly, even after an earlier
   narrowing to `[-1000,1000]` — so a real "never enforces the upper bound" bug only triggered
   on ~3 of every 4 bench runs instead of reliably every run. Switched `v`/`lo`/`hi` from
   `fc.double` to bounded `fc.integer({min:-1000,max:1000})`, which samples far more uniformly.
   Verified 20/20 clean bench runs after the fix (was ~15/20 before). This was a real
   reliability gap in a gate the whole zero-API vision depends on — a flaky critic is worse
   than a slow one, since it ships a false sense of "clean" some fraction of the time.

4. **Stakes-router scope gap #1 closed: multi-tool-call turns are now gated, not just
   lone-call turns.** `agent/loop.ts` (~420-438) previously only ran `assessStakes` when
   `turn.toolCalls.length === 1` — a destructive call co-emitted alongside benign ones bypassed
   the gate entirely (documented, not silent, but a real hole). Now scores every call in the
   turn and gates on the first high-stakes one found, holding the WHOLE turn (not just the
   flagged call) pending the user's answer. `stakesRouter-bench.ts` unaffected (pure-function
   logic didn't change, only the caller), still 11/11 → now 15/15 with item 5's additions.

5. **Stakes-router scope gap #2 closed: `create_tool` dynamic-tool bodies are now scanned for
   destructive native APIs at creation time.** A model-authored `create_tool` body is arbitrary
   JS, not shell-command text, so `destructiveReason()`'s shell-syntax patterns (`rm -rf` etc.)
   never saw it — a persisted tool calling `fs.rmSync`/`execSync`/etc. would register and
   auto-run in every future session with zero stakes gating, a real hole matching the module's
   own documented scope limitation. Added `destructiveToolBodyReason()`
   (`tools/registry.ts`) — coarse, deliberately-scoped native-API pattern scan (fs delete/
   overwrite, child_process exec/spawn) — wired into `assessStakes` for `toolName==='create_tool'`,
   gating at CREATION (a one-way door: the tool persists to disk and reloads on every future
   server start) rather than trying to recognize the tool's own name at later invocation time
   (which the router has no way to do generically). 4 new bench cases (destructive body → high;
   explicitly authorized → low; benign body → low).

**All changes this session:** `npx tsc --noEmit -p .` clean, `npm run prove:all` 250/250
unchanged throughout, `__fuzz_bench.ts` 20→27/27, `stakesRouter-bench.ts` 11→15/15. Every fix
directly re-verified against the exact buggy shape it targets (not just "tests pass").

**Not done this session:** stakes-router still doesn't cover `control_mac`/external
integrations or non-filesystem blast-radius classes (shared config/schema/migration edits) —
narrowed scope gaps, not closed ones. `localHardenCheck.ts`'s 5-shape AST scanner wasn't
audited for analogous gaps (only the fuzz/property layer was this session) — worth the same
audit treatment next. No live `smoke:code:offline` re-sweep of any task this session (all
verification was direct `runLocalHardenFuzz`/bench-level, not a full live FM regeneration).
Nothing was committed — `git status` still shows the same ~19 modified/untracked files plus
this session's edits sitting in the working tree (per standing git-safety rules: never commit
without an explicit ask, which this session didn't get).

---

## SESSION LOG — 2026-07-04, cont. 19 (fuzz mutation-blindness for
sort/set-op/dedupe families CLOSED, and a real self-inflicted bug in that fix caught and fixed
before it shipped)

**Cont. 19 (this session): NEXT SESSION item 1 from cont.18 ("fuzz mutation-blindness") is now
CLOSED.** `src/CrucibleEngine/agent/localHardenFuzz.ts`'s `detectChecks` now emits a companion
`<kind>-no-mutate` check alongside `sort`, `set-op-union`, `set-op-diff`, `set-op-intersect`,
and `array-dedupe` (5 of the 8 families — the mutating-prone ones; `validator`/`string-
transform`/`comparator`/`number-transform-clamp`/`number-aggregate-sum` don't apply, they
return new values by construction). Each new `buildProperty` case in
`localHardenFuzzWorker.cjs` calls `fn` on the caller's own array(s) and asserts they're
unchanged afterward — independent of whether the return value is correct.

**Caught a real bug in the fix itself before committing it:** an earlier draft passed fast-
check's OWN generated array directly to `fn`. A candidate that mutates its input then corrupted
fast-check's internal shrink bookkeeping and hung — reproduced standalone with a debug counter
showing an infinite shrink loop stuck replaying the identical counterexample forever (not a
candidate infinite loop — the CANDIDATE terminated fine each call; fast-check's own shrink
driver never converged). Fixed by always `.slice()`-ing a private copy before handing anything
to `fn`, never passing fast-check's array by reference. This is worth remembering as a general
rule for any future "call fn on the real object and check for mutation" property: never let that
real object be the one the property-testing library owns.

`__fuzz_bench.ts` extended 20→23 cases (3 new mutate-but-otherwise-correct cases covering
sort/union/dedupe), all pass, no hang, no timeout. Manually reproduced the EXACT
`leaderboardModule` shape from cont.17 (`sortScoresAscending(scores) { return
scores.sort(...) }`) directly against `runLocalHardenFuzz` — now flags it via `sort-no-mutate`
(`Counterexample: [[1,0]]`), closing the loop cont.17 opened when the hidden suite caught it but
fuzz didn't. `npx tsc --noEmit` clean, `npm run prove:all` → 250/250 unchanged.

**Not done this session:** `__fuzz_bench.ts` and `localHardenCheck.ts`'s own bench are still
standalone scripts, not wired into `npm run prove:all` (item 4 below, unchanged from cont.18).
Priority-ladder items 2 (generation accuracy) and 3 (HITL router) untouched. No live
`smoke:code:offline` re-sweep this session (the fix was verified via the bench + a direct
`runLocalHardenFuzz` repro of the known-buggy shape, not a fresh end-to-end FM generation run —
worth a live re-confirm next session if a `sort`-family task gets regenerated).

---

**Cont. 18 (prior session) — ambiguity.ts got its first regression bench, 9/9, locking in
cont.17's VERB_STOPLIST fix; fuzz layer got its first LIVE positive catch; families broadened
6→8; generation-stress suite broadened 3→5; HITL Workstream 2 got one narrow, verified
data-shape slice)

**Cont. 18 addendum (same day, small follow-up):** `src/CrucibleEngine/ambiguity-bench.ts`
added (`npm run ambiguity:bench`, 9/9) — this module had zero test coverage before. Covers the
`VERB_STOPLIST` regression (`validateEmail`/"that returns" no longer flips to ambiguous), "fix
the parser" resolving against a fake `SemanticIndex` for single/zero/multi-match cases and with
no index at all, plus baseline `no-target`/`vague-scope`/`underspecified-behavior` signal
firing. Standalone `tsx` script, no framework (matches `__critic_bench.ts` convention — repo
has no test runner configured). Does not change any behavior in `ambiguity.ts` itself and does
not touch item 2 below (still unwired into the live path).

**Mandate this session: (1) get the fuzz layer a live positive catch, (2) broaden fast-check
families past 6 and/or commit a real bench, (3) broaden generation-stress suite past 3 tasks,
(4) build HITL/AFK Workstream 2. All four addressed; (4) deliberately scoped narrow, not the
full router.**

**1. Fuzz layer bench committed — `src/CrucibleEngine/agent/__fuzz_bench.ts`, 20/20.**
Replaces cont.15's 4-case ad hoc scratch verification with a real, committed test covering
every family, true-positive AND true-negative each (same discipline as `localHardenCheck`'s
bench convention). Run: `npx tsx src/CrucibleEngine/agent/__fuzz_bench.ts`. NOT yet wired into
`npm run prove:all` (kept standalone, consistent with cont.12-16's precedent of not yet
formalizing these gate benches into that harness — a real next step, not done this session).

**2. Families broadened 6 → 8** — added `array-dedupe` (`dedupe*`/`unique*`/`distinct*`,
arity 1: no duplicate values in output, every distinct input value present, no foreign values)
and `number-aggregate-sum` (`sum*`, arity 1: output equals the exact numeric sum) to both
`localHardenFuzz.ts`'s `detectChecks` and `localHardenFuzzWorker.cjs`'s `buildProperty`. One
tuning fix caught by the bench itself: `array-dedupe`'s property initially used
`fc.array(fc.integer())` (full int32 range), which almost never generates actual duplicates,
so the "leaves duplicates in" bug case went undetected — narrowed to
`fc.integer({min:0,max:5})` so generated arrays collide often enough to exercise the property.
`npx tsc --noEmit` clean; `npm run prove:all` → 250/250 unchanged.

**3. Generation-stress suite broadened 3 → 5, AND a root cause found for why the fuzz layer
had never fired live before this session:** `filterModule`/`sortModule`/`summaryModule`'s
real exported APIs never match ANY fuzz family by name+arity convention (e.g.
`sortProducts(products, opts)` is arity 2, not the arity-1 `sort` family) — so the fuzz layer
had zero surface area on the existing suite regardless of how many live sweeps ran. Added two
new repo-context tasks to `coding-benchmarks.ts`'s `TASKS` array, deliberately shaped to land
inside a family's detection window: `clampModule` (`clampVolume(value,min,max)`, arity 3,
`number-transform-clamp` family) and `leaderboardModule` (`sortScoresAscending(scores)`,
arity 1, `sort` family). Each has a hidden adversarial suite
(`src/CrucibleEngine/coding-bench/{clampModule,leaderboardModule}.hidden.ts`, same convention
as the existing three) — these were MISSING on first run and crashed `auditTask`'s
`copyFileSync` (ENOENT); fixed by adding both hidden files before the confirming re-run.

**4. LIVE fuzz catch — CLOSES the "only scratch-verified" gap.** Restarted `:3001` with
`CRUCIBLE_OFFLINE=strict` in the server's own env (one clean LISTEN pid verified), ran
`npm run smoke:code:offline -- clampModule leaderboardModule` end to end (real agent fires,
real FM generation, no mocking). `.crucible/gate-telemetry.jsonl` recorded, live, during the
`leaderboardModule` run:
```
{"gate":"harden","ran":true,"reason":"local-fallback (reviewer error: [offline-escalate] critic turn class has no offline equivalent — routing to local harden fallback): findings [+1 fuzz]"}
```
appearing twice — the fuzz layer contributed a real finding during the FM's 9-round
generation loop for `leaderboardModule` (a `sort`-family match), on a genuinely live sweep,
not a scratch script. Priority-ladder item 1's "has it ever caught anything live" flag,
open since cont.15, is now CLOSED. Scorecard: `clampModule` GREEN (hidden suite 9/9,
generated path); `leaderboardModule` RED — the FM's final candidate sorted correctly but
mutated its input array in place (`scores.sort(...)`, no copy), a real bug the HIDDEN suite
caught. Honest gap: fuzz's `sort` property always calls `fn(arr.slice())` (a defensive copy),
so it structurally cannot see mutation-of-input bugs — only the hidden suite's own explicit
mutation check caught this one. Not fixed this session (would need a second property variant
that passes the caller's own array and checks it's unchanged) — flagged as a concrete next
family-hardening step, not assumed away.

**5. HITL/AFK Workstream 2 — one narrow, verified slice, NOT the full router.** Read
`HITL_PLANNING_TRACK.md` §3 (MC-first clarification + visible recommended default) against
the ALREADY-LIVE `ambiguity.ts` (Tier 2.4, code-agent pre-synthesis check) rather than
building a new parallel mechanism per §7's own open question. Added
`clarificationOptions?: string[]` + `recommendedOption?: string` to `ResolutionResult`,
populated ONLY for the `unresolved-reference`-with-multiple-candidates signal — the one
existing signal type with a genuinely enumerable answer set (the candidate symbol list).
Deliberately did NOT force fake MC options onto `no-target`/`vague-scope`/
`underspecified-behavior` (open-ended by nature; a wrong-shaped list would violate this
module's own zero-guessing discipline). Verified: multi-candidate case produces correct
options (`["parseTokens (src/parseTokens.ts)", "parseExprTree (src/parseExpr.ts)", "Something
else / not sure"]`) + recommended default; vague-scope case correctly has none; `npx tsc
--noEmit` clean. **Not done:** wiring this into the actual live path — the only current
caller, `nodeExecutor.ts`, is the PARKED capabilityRouter/decompositionDag stack per
[[crucible-agentic-architecture]], not `agent/planner.ts`+`loop.ts`. Wiring the MC options
into `loop.ts`'s real `ask_user`/`'clarification'` stop reason (loop.ts:356) is the natural
next step and wasn't attempted this session. Everything else in the design doc (§2 stakes
router by reversibility/blast-radius, §4 self-directed tool suggestion, §5 skill library, §6
UX refinements) remains unbuilt — see HITL_PLANNING_TRACK.md §8 for the full status writeup.

**Found in passing, FIXED same session (spawned as background task `task_8da28286`, completed
before this doc was finalized):** `ambiguity.ts`'s `DEF_REF` regex spuriously matched ordinary
prose like "...that returns true..." as a definite-article code-symbol reference, flipping an
otherwise well-specified request to `ambiguous:true` whenever an `index` was supplied and no
symbol matched. Fixed with a `VERB_STOPLIST` (returns/is/has/does/matches/... and conjugations)
checked alongside the existing `STOP_REFS` set. Re-verified live after the fix: the
multi-candidate `clarificationOptions` case (this session's own addition) still works
unchanged, and the previously-false-positive case now correctly reports `ambiguous:false`.
`npx tsc --noEmit` clean.

**Verification summary, all real (not assumed):** `__fuzz_bench.ts` 20/20 (8 families × TP/TN);
`npx tsc --noEmit -p tsconfig.server.json` clean throughout (pre-existing `_author_parsers2.ts`
TS1109 aside, not mine); `npm run prove:all` → 250/250 unchanged; one live
`smoke:code:offline` sweep against a freshly-restarted `:3001`, confirmed via the real
`.crucible/gate-telemetry.jsonl` ledger, not console text or assumption.

**NEXT SESSION — HIGH TIER ITEMS (concise), superseding the 2026-07-04 list below:**

1. ~~Fuzz mutation-blindness~~ DONE cont.19 (`sort-no-mutate` + 4 set-op/dedupe companions,
   see CURRENT STATE above). Live re-confirm via a fresh `smoke:code:offline` sweep on a
   `sort`-family task is still worth doing (this session verified via bench + direct repro of
   the known-buggy shape, not a brand-new end-to-end FM generation run).
2. **Wire ambiguity.ts's new `clarificationOptions` into the live path** —
   `agent/planner.ts`+`loop.ts`'s real `'clarification'` stop reason (loop.ts:356), not the
   parked `nodeExecutor.ts`. Currently computed but unconsumed anywhere live.
3. ~~Fix the DEF_REF false-positive~~ DONE (`VERB_STOPLIST`, see cont.18 above).
4. **Commit `__fuzz_bench.ts` (now 23/23) into `npm run prove:all`** rather than leaving it
   standalone — same formalization gap cont.12-16 left open for `localHardenCheck`'s bench too.
5. **Generative coding accuracy remains the deeper open item** — `leaderboardModule`'s
   mutation bug is itself fresh evidence for priority-ladder item 2 (thin/under-measured
   accuracy on novel tasks): even a 9-round FM loop converged on subtly-wrong code that only a
   hand-written hidden suite (and now fuzz, post cont.19) caught.
6. Items 3 ("Second Workstream 1 critic") and 6-7 (pre-existing `_author_parsers2.ts` TS1109;
   e002/e005 explain-category retrieval gaps) from the 2026-07-04 list are UNCHANGED, not
   touched this session — see that list below for full detail, still accurate.

**Composite benchmark baseline (conversational suite) as of last confirmed sweep (2026-07-03,
N=3 post premise-gate fix):** pass 0.920 ± 0.000 — unrelated to and not re-run this session.

---


## SESSION LOG — 2026-07-04 night (fail-open gate telemetry — IMPLEMENTED, VERIFIED, CLOSED; found grounding+harden dark)

Shipped `debug/gateTelemetry.ts` + wiring into gateA2_lint/grounding/harden (`c79da7c`).
Full detail in ROADMAP CHANGE LOG (2026-07-04 cont. 8). Key facts a future session needs:
- `.crucible/gate-telemetry.jsonl` is the ledger; console.warn fires once per gate per
  process on first skip. recordGate() is best-effort and must stay that way.
- smoke:code verifies THROUGH the running `:3001` server process — telemetry (and any
  in-process change) is invisible until the server is restarted onto the new commit.
  prove:all and the catalog path bypass the oracle's verifyCandidate entirely and will
  never generate gate telemetry; only gen-path traffic exercises it.
- First instrumented sweep: grounding 0/2 usable verdicts, harden 0/3 — both fail open
  every time (FM glue turn returns no JSON / empty text). This is now CURRENT STATE item 0.

## SESSION LOG — 2026-07-03 (N=5 confirmation + premise-gate explain-category fix — IMPLEMENTED, VERIFIED, PARTIALLY CLOSED)

**Mandate: run the N=5 confirmation sweep parked from last session, then work down the
open-items list (explain category / Frontier-SWE-gap) as far as comfortable, flagging
decision points rather than guessing priorities.**

**N=5 confirmation sweep — DONE, cl001/cl003 fix CONFIRMED ROBUST:**
- clarify **1.00 / 1.00 across all 5 runs**, zero flips — not a single-run fluke.
- Composite baseline (pre-fix, N=5): pass **0.924 ± 0.008** [0.92, 0.94], cov **0.942 ± 0.004**.
- All other categories held their clean bands (general/definition/abstain/reasoning/
  false-premise all 1.000 ± 0.000). Only `explain` (0.526 ± 0.052) and one flipper
  (e007, GPS wording variance) kept the composite off a perfect 1.0.
- Infra note: the sandbox environment reset mid-run once (port 3001, FM daemon, and all
  `/tmp` scratch state wiped simultaneously, mid-background-process). Git tree was
  untouched. Recovered by restarting the FM daemon (`local-inference/crucible-fm-daemon`,
  not yet a launchd service — see [[crucible-track-s-local-inference]]) and the server,
  then relaunching the sweep from scratch. If this recurs, treat any long
  background/scheduled-wakeup run as possibly needing a full respawn, not just a log check.

**Root-caused explain-category always-fail (e002, e005) — NOT what prior sessions assumed:**
Prior handoffs called this "pre-existing DAG-mangles-explainers." Actual mechanism, traced
via `/api/debug/history` on live fires:
- `checkPremiseGrounding` (`researchDag.ts` — the "Bug A" false-premise fix from an earlier
  session) ran **unconditionally on every research-DAG answer**, not just questions with an
  embedded false premise. On ordinary "explain how X works" questions, the on-device FM
  still gets asked "does the verified fact contradict this question's presupposition?" and
  answers yes with high confidence — hallucinating a contradiction where none exists.
- **e005** ("Explain the water cycle"): a good, complete, grounded 677-char answer was
  discarded in favor of the FM's "correction," which cut off mid-word.
- **e002** ("How does a refrigerator keep food cold?"): the FM's "correction" directly
  negated its own cited source — "Solar-powered refrigerators do **not** keep food cold"
  while the quoted evidence says they can. Confidently wrong AND self-contradicting.
- e003 ("Why is the sky blue?") is unrelated — genuine leaf-level abstain (no source found),
  the already-accepted strict-mode corpus-coverage tradeoff from 2026-07-01. Not a bug.

**Fix — `isPremiseBearing` gate, committed `311ae9f`:**
New primitive in `leafPrimitives.ts` (Primitive 3a) classifies the question as
CLAIM (myth/trivia-shaped, checkable assertion about a named subject — reaches the
existing correction path) or MECHANISM (explaining a well-established phenomenon — skips
it, keeps the grounded synthesis untouched). Wired into `researchDag.ts` ahead of
`checkPremiseGrounding`.

**Verified over 3 fresh full CONVOEDGE_50 sweeps post-fix:** zero regressions.
false-premise held **1.00 ± 0.000** across all 3 (fp001-4 untouched — they're
CLAIM-classified and still reach the correction path). All other categories unchanged.
Composite passRate rock-stable at **0.920 ± 0.000** across the 3 runs. The truncation and
self-contradiction bugs are gone — confirmed by direct re-fire, not just aggregate score.

**Cache-poisoning side-investigation (e002) — dead end, real finding:**
`.crucible/research-claims.json` had a stale claim keyed to "how does a refrigerator keep
food cold" mapping to an off-topic *solar-powered*-refrigerator fact — looked like classic
cache poisoning. Purged it (backed up first to `/tmp/research-claims.json.bak-preclean`,
user-confirmed before the destructive write — the auto-mode safety classifier correctly
blocked two earlier attempts as under-authorized). **Did not fix e002**: fresh live
retrieval reproduces the identical mismatch. The real root cause is the web-search/ranking
layer itself consistently preferring the "Solar-powered refrigerator" Wikipedia article over
the general one for this query — a retrieval-ranking issue, not a cache/data issue. Bigger
and differently-scoped than what was authorized this session; explicitly NOT investigated
further — flagged for a future session to pick up deliberately.

**Current state (post-session, N=1 spot-check):** overall passRate 0.92–0.94 depending on
run (e007 remains a wording-variance flipper, not a regression). explain 0.5–0.63 (e001,
e004, e006, e008 clean; e002/e003/e005 fail for three now well-characterized, distinct
reasons — see above).

**STILL OPEN (unchanged from before, plus one new item):**
- e002 — retrieval/web-search ranking prefers an over-specific source. NEW finding this
  session, not previously diagnosed at this depth. Needs its own scoping conversation.
- e003 — accepted strict-mode corpus-coverage tradeoff (2026-07-01 decision), unchanged.
- e005's remaining gap (post-fix) — the grounded source is accurate but framed around
  water mass-balance rather than evaporation/condensation; a retrieval-content-relevance
  gap, distinct from the truncation bug just fixed.
- Frontier-SWE-gap phase — still untouched. Note: ROADMAP.md's gating condition
  ("timeout verification/regression, clarify wiring, and any still-open false-premise/trust
  diagnosis") no longer names an unresolved item verbatim — timeout and clarify are closed,
  and today's fix hardened the false-premise/trust path further. Whether that means the gate
  is now open is a judgment call left to the user, not decided here.

---

## SESSION LOG — 2026-07-02 (cl001/cl003 clarify-wiring — IMPLEMENTED, VERIFIED, CLOSED)

**Mandate: pick up the parked clarify-wiring thread (cl001/cl003, stuck at 0.500±0.000
across every prior sweep). Diagnose in isolation, fix, confirm against the full
CONVOEDGE_50 sweep before closing.**

**Also closed as a side effect of session-start housekeeping:** the working tree had
gone a long stretch with zero commits (757 files / ~48k lines of accumulated,
undocumented WIP across many sessions — a new chat-conversations store, synthDriver.ts,
researchDag.ts, retrievalLayer.ts wiring, the synth skill library, Electron launch
pipeline, Off-Fly cutover staging, and the corpus-acquisition strict-mode gate this
doc had flagged as still-open — that gate was in fact already fixed, just uncommitted).
All of it is now one checkpoint commit on `crucible-northstar-sessions`. Recommend
committing at the end of every session going forward instead of letting this
accumulate again.

**Root cause — TWO bugs, not one:**
1. The offline-conversational path (`solveNonCodeTurn`, server.ts ~3090) had no
   pre-check for under-specified requests at all — unlike the code-agent path, which
   has a dedicated Tier 2.4 (`ambiguity.ts`) that resolves-or-asks before synthesis.
   Conversational turns just got handed straight to the FM, which always tries to
   produce a confident answer.
2. Compounding it: Track M1's casual-mode short-circuit (`detectConversational` in
   `conversationalMode.ts`, server.ts ~2857) treats any message ≤4 words with no
   `DOMAIN_SIGNAL_WORDS` hit as small talk, and instructs the local model to "mirror
   exactly what was sent." "Book it for tomorrow." (4 words, no domain-signal word —
   `book` isn't in that list) fell into this bucket and got echoed back verbatim
   before ever reaching the conversational pipeline. `translate`/`fix` *are* in
   DOMAIN_SIGNAL_WORDS, so cl002/cl004 were already skipping M1 — this is why the
   bug looked partial rather than total across the 4 clarify cases.

**Fix — new file `src/CrucibleEngine/conversationalClarify.ts`:**
Pure, deterministic, zero-inference — same philosophy as the abstain/false-premise
checks, extended to the "under-specified" failure mode. Three narrow detectors:
- action verb (book/schedule/translate/send/order/buy/...) + a bare dangling pronoun
  object (it/this/that/them) in a short command → ask what it refers to.
- immediate-tense weather question with no location given → ask which location.
  Deliberately excludes far-future/impossible-horizon phrasing (digits, "in exactly
  N days") so it never intercepts a006-style abstain cases — those must still abstain,
  not ask for a location that wouldn't help anyway.
- "fix/solve/debug/resolve the bug/issue/error" with no file path, error text, or
  code identifier → ask which bug/file.

Wired in at TWO points originally (before M1's casual short-circuit, and again before
`solveNonCodeTurn`); the second was provably dead code once the first was in place
(strict subset of the same guard condition, same message, no way to reach it with
`needsClarification` still true) — removed it, kept only the M1-level check.

**Verification (empirical, not assumed):**
- Pure-function check against all 50 CONVOEDGE_50 prompts (no server): exactly the 4
  `cl0xx` prompts fire, zero false positives on the other 46 — including a006
  ("weather... in exactly 100 days"), which stays correctly unintercepted (still
  reaches the FM's own abstain behavior).
- Live N=1 full CONVOEDGE_50 sweep on `:3011` strict, post-fix:
  - **clarify: 1.00 / 1.00 (was 0.500 ± 0.000)** — all 4 pass, ~0ms each (short-circuits
    before any model call).
  - general 1.00, abstain 1.00, false-premise 1.00, reasoning 1.00 — all held their
    prior clean bands exactly.
  - definition 0.88 — the one miss is d005, the same pre-existing surface-form flip
    already documented in the prior session's log, not a new regression (only
    definition-path-independent code changed this session).
  - explain 0.50 — unchanged, still parked, not touched.
- Re-confirmed live after removing the dead second insertion — all 4 cl0xx still pass.

**Not done / open for next session:** N=5 confirmation sweep (this session ran N=1
live + the full-50 pure-function check, per the standing "isolate then confirm"
pattern, but hasn't yet repeated the live sweep 5x the way the daemon-timeout fix did
before updating the baseline of record). Composite baseline not yet formally updated —
do that after an N=5 run. explain category and Frontier-SWE-gap phase remain parked,
untouched this session.

---

## SESSION LOG — 2026-07-02 (daemon-timeout fix — IMPLEMENTED, VERIFIED, CLOSED)

**Mandate: implement fix (d) mislabeled error string + fix (a) FM_TIMEOUT_MS 30s→45s,
verify r001 in isolation, then full convoedge-50 regression N=5 before updating baseline.
DONE — both fixes landed, isolation confirmed clean, full regression confirmed clean.**

**Code changes (both live in the repo now, not yet committed to git — this project isn't
a git repo; changes are just on disk):**
- `src/CrucibleEngine/agent/fmReact.ts`: `FM_TIMEOUT_MS` raised `30_000` → `45_000`, with a
  comment explaining why (healthy generation measured 21-28s, already against the old
  ceiling).
- `server.ts` (~3121, the `offline_conversational_escalate` catch block): now distinguishes
  `e.name === 'TimeoutError'` (FM_TIMEOUT_MS abort — daemon healthy, just slow) from a
  genuinely unreachable daemon (`OfflineEscalateError` health-check failure, or
  `ECONNREFUSED`/`ECONNRESET`) from any other solve failure, and reports the correct one of
  three distinct abstain strings instead of always claiming "daemon is unreachable". Also
  added `errName` to the `debugBus.emit` diagnostic event for future debugging.
- Verified empirically (not assumed) that `AbortSignal.timeout()` rejects with
  `e.name === 'TimeoutError'` and a real `ECONNREFUSED` rejects with `e.name === 'TypeError'`
  + `e.cause.code === 'ECONNREFUSED'`, on this Node version (v26.4.0), before writing the
  distinguishing logic — see the node -e repro if this ever needs re-verifying.

**r001 isolation re-test (CONFIRMED, N=10 cold + N=10 warm, :3011 strict, new code):**
- First attempt (both :3001 and :3011 freshly restarted together, corpus background
  acquisition actively running): cold 8/10 (80%), warm 6/10 (60%) — better than the old
  47%/25% baseline but not at the ~90%+ target.
- Root-caused the shortfall to a confound, not the fix: `initCorpus()` at server.ts:6394
  kicks off a background "deliberate-curation acquisition" cycle (fetches from arxiv.org)
  on EVERY boot with no `CRUCIBLE_OFFLINE` gate — a genuine external-call-under-strict leak,
  same bug class as the already-fixed Hunter boot probes but NOT covered by that fix. It was
  actively running (visible in the :3011 log) during the first isolation attempt and is the
  likely source of the elevated latency/failures (CPU contention on this 8GB machine, not a
  timeout-margin problem).
- Re-ran with `CORPUS_AUTOACQUIRE=0` (existing env escape hatch, used only to get a clean
  benchmark signal — does NOT fix the underlying gate-missing bug): **cold 10/10 (100%),
  warm 10/10 (100%)**, latencies 21-37s, comfortable margin under the new 45s ceiling. This
  is the confirmed result — the timeout fix works.
- **New finding NOT fixed this session** (flagged as a background task chip for the user,
  task_7db1d756): gate `initCorpus()`'s `autoAcquire` behind `CRUCIBLE_OFFLINE === 'strict'`
  the same way the Hunter probes were gated. Until fixed, `:3011` (and any strict instance)
  leaks external arxiv calls at boot, violating the "no external calls under strict"
  standing constraint.

**Full convoedge-50 regression sweep (CONFIRMED N=5, :3011 strict, `CORPUS_AUTOACQUIRE=0`
to keep the corpus-acquisition confound out of the measurement):**
- Composite pass: **0.876 ± 0.015** [0.86, 0.90] (was 0.868 ± 0.020 [0.84, 0.90] stale).
- Composite cov: **0.896 ± 0.010** (was ~0.886 ± 0.014 stale).
- Per-category (5-run band):
  - general **1.000 ± 0.000** — unchanged, clean.
  - abstain **1.000 ± 0.000** — unchanged, clean.
  - definition **0.976 ± 0.048** — unchanged, clean (one d005 flip, pre-existing surface-form
    variance, not new).
  - false-premise **1.000 ± 0.000** — unchanged, clean.
  - reasoning **1.000 ± 0.000** — UP from 0.888 ± 0.056. This is the fix's headline result:
    the r001/r004 daemon-timeout flake is gone, confirmed at N=5, not a single-run fluke.
  - explain **0.502 ± 0.079** — roughly flat vs 0.552 stale (within the category's known
    instability — e004/e008 hit the *harness's own* 180s outer fetch timeout twice across
    5 runs, unrelated to FM_TIMEOUT_MS; e007 flipped again as previously documented). Still
    parked, not touched this session.
  - clarify **0.500 ± 0.000** — unchanged, still parked.
- **general/abstain/definition/false-premise held their prior clean bands exactly — no
  regression from the shared FM_TIMEOUT_MS constant change.** reasoning is the only category
  that moved, and it moved up.

**Infra note for future sessions:** during this session's long benchmark runs, the `tsx`
node server processes for both `:3001` and `:3011` died silently (no crash log, no
exception) mid-run on the machine's tight 8GB memory (observed 60-150MB free / 7.5-7.7GB
used while both servers + FM daemon were up). The compiled Swift FM daemon (`:11435`) never
died. Worked around by (1) temporarily stopping `:3001` during the :3011 sweep and (2)
wrapping the sweep loop in a self-healing restart-if-down check. `:3001` was restored to its
normal non-strict default config at the end of the session. If this recurs, consider not
running `:3001` and `:3011` simultaneously for long unattended benchmark runs on this
machine, or a launchd-based restart-on-exit supervisor (already flagged as a TODO in the
run-commands memory for the stale-process hazard, same root cause: this box can't
reliably keep long-lived nohup'd node processes alive unsupervised).

**Baseline updated. Daemon-flake thread CLOSED** (per the standing constraint, closes once
verified clean — it now is, at confirmed N=5). New baseline of record: composite
0.876 ± 0.015, per-category as above. cl001/explain/Frontier-SWE-gap remain parked,
not started this session, per the explicit "stop and report" instruction.

**Open for the user:** decide whether to pick up the newly-flagged corpus-acquisition
strict-mode leak (chip already spawned) before or alongside the next parked item.

---

## SESSION LOG — 2026-07-01 (roadmap addition — Frontier-SWE gap phase queued)

**User-provided roadmap addition incorporated into `ROADMAP.md`, not started.**

- Added a queued phase near the top-level build order: **Closing the Frontier-SWE Gap**.
- Preserved the honest framing: the target is not frontier-model parity, but reliable
  autonomous handling of conventional, well-specified, tool-verifiable engineering work
  plus explicit escalation for judgment-heavy remainder.
- Preserved sequencing: this phase starts only after current trust-bug work closes
  (timeout verification/regression, clarify wiring, and any remaining false-premise/trust
  diagnosis). Do not start Workstream 1 in parallel.
- Captured the three workstreams:
  1. deterministic critic tooling,
  2. upfront elicitation / ambiguity surfacing,
  3. out-of-depth tripwire.
- Open user decision remains: which Workstream 1 critic to build first once the phase
  actually starts (static-analysis gating, contract/interface checking, fuzzing/property
  tests, security scanning, or known-bad-pattern scanning).

---

## SESSION LOG — 2026-07-01 (timeout fix verification — PARTIAL, interrupted by architecture pivot)

**Mandate resumed from platform handoff:** verify the Tier-3 FM timeout/error-label fix on
:3011 strict, then run full convoedge-50 regression before closing. **Partially done only.**

**Verified code/runtime state:**
- Actual repo root confirmed as `/Users/justin/crucible-local/crucible-local`.
- `:3011` was listening as PID **11165**.
- `src/CrucibleEngine/agent/fmReact.ts`: `FM_TIMEOUT_MS = 45_000` confirmed present.
- `server.ts` strict catch block confirmed present: distinguishes `TimeoutError` from
  genuinely unreachable daemon errors and reports timeout as "local model is taking too
  long to respond (timed out)".
- Apple FM daemon health on `:11435` returned `status: ok`.

**r001 isolation post-fix (confirmed N=10 cold + N=10 warm, :3011 strict):**
- Cold back-to-back: **9/10 pass (90%)**.
- Warm/loaded back-to-back: **9/10 pass (90%)**.
- The two failures were exact **45.0s timeout** abstentions, now correctly labeled as
  timeout rather than "daemon unreachable".
- Several successful fires landed above the old 30s ceiling (e.g. 32-44s), so the 45s
  bump is a real improvement. However, the new ceiling still has limited slack; 45s is
  not a complete elimination of the timeout edge under sustained load.

**NOT YET DONE / still required before closing this fix:**
- Full convoedge-50 sweep **N=5 minimum** on :3011 strict.
- Confirm general/abstain/definition remain near prior clean bands.
- Update per-category confirmed numbers only after that N>=5 sweep.
- Surface the :3001 restart decision after the full sweep is clean; do not restart
  :3001 unilaterally.

---

## SESSION LOG — 2026-07-01 (daemon-flake DIAGNOSIS — r001 isolation)

**Mandate: diagnose the r001 "daemon unreachable" flake in isolation (10-20x outside the
full sweep) to determine load-dependent vs standalone. Diagnose only, do not fix without
go-ahead. DONE.**

**ROOT CAUSE FOUND — it is a too-tight timeout, NOT a daemon crash/reliability issue, and
the "daemon is unreachable" label is WRONG.** Concrete measured numbers, r001 fired in
isolation against :3011 (strict), via scratchpad `r001_iso.ts` (fire() copied from
__convoedge_bench.ts):

- RUN A (cold, back-to-back N=15): **7/15 pass (47%)**. First 7 passed 21–24s, then #8–15
  ALL failed identically at exactly 30.0s.
- RUN B (warm, back-to-back N=12): **3/12 pass (25%)**. Passing fires were SLOWER (26–28s).
- RUN C (20s idle gap between fires, N=8): **6/8 pass (75%)**. Latencies 18–29s; the fastest
  (18–19s) appear only after idle recovery.

**Mechanism (traced through code, not assumed):**
- r001 ("I have $1000 to invest safely. What are some options?") is NOT research-shaped
  ("what are" ∉ isResearchShaped regex) and NOT complex → routes straight to Tier-3
  `fmDirectAnswer` (synthDriver.ts:162) → `callFm` with `FM_TIMEOUT_MS = 30_000` and
  `max_tokens: 1536` (fmReact.ts:32,46).
- A healthy r001 generation takes 21–28s — already RIGHT against the 30s ceiling. Any
  slowdown (sustained load, ANE throttle, warm-session degradation on the 8GB A18) pushes
  it past 30s → `AbortSignal.timeout` fires → caught → solveNonCodeTurn throws → server.ts
  catch (3121-3124) abstains with the hardcoded "local model daemon is unreachable" string.
- The REAL escalate reason (from /api/debug/history `offline_conversational_escalate`) on
  EVERY failure is `"The operation was aborted due to timeout"` — a slow generation, NOT an
  unreachable socket. The daemon `/health` stayed `ok` throughout, and a small direct prompt
  to :11435 returned in <1s during the failure window. Daemon never crashed.

**Verdict on the handoff's two diagnostic questions:**
1. Load-dependent or standalone? → **Load-dependent** (margin-vs-fixed-timeout). Back-to-back
   it degrades to 25–47%; 20s idle gaps recover it to 75%. NOT a standalone random crash.
2. Root-cause category? → **Timeout/throughput margin, NOT concurrency** (fires are strictly
   sequential — no concurrency backlog) and **NOT daemon reliability/crash**.
- This fully explains the ~80% in-sweep failure: during a 50-prompt sweep the daemon is
  continuously loaded, so r001-class generations sit in the 28–32s band and time out most
  of the time.

**Fix NOT applied (per trace-first / ask-before-fix constraint).** It is a tuning/structural
decision with tradeoffs, not a trivial bug. Candidate fixes to discuss:
  (a) raise `FM_TIMEOUT_MS` for Tier-3 direct answers (e.g. 45–60s) — simplest, but slow turns;
  (b) lower `max_tokens` for direct answers (1536 → ~768) — faster, shorter answers;
  (c) cap/cooldown the daemon under sustained load; (d) fix the mislabeled error string so it
  reports "timeout" not "unreachable" (low-risk, orthogonal, worth doing regardless).
**Open question for user: which fix direction, or stop here?**

NOTE: the 0.868 baseline's reasoning category (0.888 ± 0.056) is depressed by exactly this
timeout flake — once mitigated, reasoning should rise and stabilize.

---

## SESSION LOG — 2026-07-01 (re-confirmation sweep; 0.90 did NOT hold)

**Mandate this session: re-run convoedge-50 on :3011 to test whether the prior 0.90
composite was a stable baseline or a lucky single run. Result: it was the top of the
range, not the center.**

**Re-confirmation sweep — convoedge-50, N=5, :3011 (strict, no code changes):**
- Per-run passRate: **[0.90, 0.86, 0.88, 0.86, 0.84]**
- **Composite pass 0.868 ± 0.020 [min 0.84, max 0.90]**, cov 0.886 ± 0.014.
- The prior session's 0.90 = the single best run, not a representative baseline.
  **New ground-truth baseline going forward: ~0.87 (0.868 ± 0.020).**
- Stability: 42 always-pass, 5 always-fail (cl001, cl003, e002, e003, e005), 3 flippers.

**Per-category bands (N=5):**
- general 1.000 ± 0.000 · abstain 1.000 ± 0.000 · **false-premise 1.000 ± 0.000** (fp fix robust)
- definition 0.976 ± 0.048 · reasoning **0.888 ± 0.056** (was claimed 1.00) · explain 0.552 ± 0.064 · clarify 0.500 ± 0.000

**DIVERGENCE = SIGNAL, not noise (per standing constraint, called out plainly):**
- **false-premise held perfectly across all 5 runs** — the fp004 grounding fix is
  confirmed stable, not a one-run artifact. fp004 independently re-fired: genuine
  evidence-grounded negation ("did not purchase Alaska from Canada … sold by Russia",
  SOURCE-QUOTED), not a false-premise parrot. SOLID.
- **reasoning dropped from claimed 1.00 → 0.888 ± 0.056.** Cause identified: the
  daemon-unreachable flake the prior handoff flagged as "could be luck rather than a
  fixed issue" is REAL AND RECURRING. r001 flipped Ynnnn (1/5) — 4 of 5 runs returned
  "I can't answer this offline right now — the local model daemon is unreachable, and
  strict mode blocks external escalation." The prior 1.00 was the flake being absent
  that run, NOT a fix. This is the single biggest contributor to the composite drop.
- **e007 is NOT stable-pass** (prior log claimed "e007 now passes"): flipped YnYnn (2/5).
- e003 regression still present (always-fail, cov 0.50) — unchanged, still needs decision.

**Unchanged / re-confirmed:** :3001 PID 94614 still serving (non-strict, not flipped).
:3011 env CRUCIBLE_OFFLINE=strict confirmed. No code changes made this session — pure
measurement. fp004 rubric NOT reverted.

**USER DECISIONS (made this session, 2026-07-01):**
1. **Baseline → accept ~0.87 (0.868 ± 0.020) as the new ground truth.** 0.90 is retired as
   a one-run high, not a representative baseline. Compare future sweeps to ~0.87.
2. **e003 → ACCEPT tradeoff (a), logged as accepted.** "Why is the sky blue?" abstaining
   under PREMISE_RX→DAG is a KNOWN, ACCEPTED tradeoff. fp001-004 passing is the higher-value
   outcome; the FM-direct-fallback fix that would solve e003 would re-break fp001. Do NOT
   "fix" e003 by loosening PREMISE_RX or adding a no-evidence FM fallback — that path is
   closed by decision. (Option (b), a narrower evidence-absence signal, was NOT chosen.)
3. **Hunter boot probes → GATE under strict (DONE + VERIFIED this session, see below).**
4. **reasoning daemon flake → PROMOTED to a real tracked fix item** (no longer "parked
   infra"). It, not explain/clarify, is what gates reasoning (~4 composite pts). See
   "DAEMON FLAKE" below.

**DECISION 3 IMPLEMENTED — Hunter/waitlist external calls gated under strict:**
- `server.ts`: added `if ((process.env.CRUCIBLE_OFFLINE ?? '1') === 'strict') return` to all
  three external background tasks — boot Hunter (setTimeout, ~line 488), 24h Hunter
  (setInterval), and 6h waitlist scorer (updateWaitlistScores). Guard sits AFTER the
  existing `if (!apiKey) return`, matching the canonical strict convention at server.ts:2985.
- **Verified empirically:** restarted :3011 (strict) on gated code, waited past the 30s
  boot-Hunter delay. Pre-gate log (/tmp/crucible-3011.log) had **9** external probe lines
  (1 catalog fetch + 8 OpenRouter model probes). Gated log (/tmp/crucible-3011-gated.log)
  has **0**. The only remaining `[Hunter]` line is "Loaded 3 previously-discovered model(s)"
  — a LOCAL file read, not a network call. Chat path unaffected: fp004 re-fired post-restart
  returns the same grounded Russia negation (200, SOURCE-QUOTED). **The "no external calls
  under strict" constraint now holds literally — the 3-session re-flag thread is CLOSED.**
- **New :3011 PID 90630** (was 92024). Still strict, still serving fixed grounded corrections.
- NOTE: :3001 was NOT restarted (non-strict by design; the gate is a no-op there since the
  guard only triggers under strict — strict default NOT flipped). :3001 will pick up the gate
  on its next natural restart; no action needed.

**DAEMON FLAKE — now a tracked fix item (was parked):**
- Symptom: r001 (reasoning) returned "I can't answer this offline right now — the local
  model daemon is unreachable, and strict mode blocks external escalation" in 4 of 5 runs.
  This is the Apple FM daemon (port 11435) intermittently unreachable mid-sweep, NOT a
  routing/grounding bug. It depresses reasoning from a true ~1.0 to ~0.89 and is the single
  largest contributor to the 0.90→0.87 composite move.
- Next: investigate daemon liveness/reconnect (Track S Swift bridge, port 11435). Until
  fixed, reasoning numbers carry this flake — read sweep dips in reasoning as likely-daemon
  before assuming a real regression.

**STILL OPEN (unchanged, parked per standing plan):**
- cl001/cl003 clarify-wiring (0.50) — separate session, needs explicit go-ahead.
- explain e002/e005 (pre-existing DAG-mangles-explainers) — separate from e003.
- Frontier-SWE-gap roadmap phase — starts after cl001 + (now-closed Hunter) threads.

---

## SESSION LOG — 2026-06-30/07-01 (verification + :3001 restart)

**Verification of prior session's claims (both independently re-checked):**
- **Item 1 (fp004 "rubric artifact"): CONFIRMED.** Fresh fires against fixed :3011 return
  the grounded, *negated* correction ("The United States did not purchase Alaska from
  Canada … purchased from Russia in 1867", SOURCE-QUOTED, evidence-backed). The rubric
  failed only because the forbidden substring `from canada` matched inside the negation.
  The earlier 0.5 `/tmp/fp-strict.log` (22:57) was a STALE pre-restart :3011 run (it
  predated the 23:09–23:13 fixes), which is why it showed flat false-premise acceptance.
- **Item 2 (zero external chat calls under strict): CONFIRMED.** `/tmp/crucible-3011.log`:
  all 8 external (openrouter) hits are `[Hunter]` boot probes at lines 13–27, ALL before
  the first `/api/chat` at line 29. Chat region (lines 29–294) has zero
  groq/openai/anthropic/openrouter strings. Confirmed `:3011` env `CRUCIBLE_OFFLINE=strict`.

**DECISION 1 — :3001 RESTARTED on fixed code (user-approved Option A).**
- Old PID 89496 (started 2026-06-30 22:41:41) was objectively pre-fix (fixes landed
  23:09–23:13) and had `CRUCIBLE_OFFLINE` unset (NOT strict).
- Restarted with identical config (default PORT 3001, no env overrides — strict default
  NOT flipped, per standing constraint). **New PID 94614, started 2026-06-30 23:56:47.**
  Verified serving fixed grounded correction on fp004. `/tmp/crucible-3001.log`.

**DECISION 2 — fp004 rubric fixed (pre-authorized, applied after Item 1 confirmed).**
- `__convoedge50.ts` fp004: dropped bare `from canada` forbidden check; kept `russia`
  required and `canada in` (matches acceptance phrasing only, not the negation).
- Post-fix fp set N=5 on :3011: composite **1.0** (fp001–004 all 5/5).

**Final authoritative sweep — convoedge-50 N=5 on :3011 (strict, fixed):**
overall pass **0.90**, cov 0.91. Per-category: general 1.0 (12), definition 1.0 (8),
reasoning 1.0 (7), abstain 1.0 (7), **false-premise 1.0 (4)** [was 0.5], explain 0.63 (8),
clarify 0.5 (4). Remaining fails: e002/e005 (pre-existing explain), e003 partial
(NEW regression, cov 0.50), cl001/cl003 (parked clarify-wiring). e007 now passes.

**Still open / surfaced (NOT decided this session):** e003 regression tradeoff;
boot-time `[Hunter]` external probes under strict (3rd flag); cl001; explain category.

---

## PRIORITY 1 — Close the Learning Loop (The Compounding Gap)

**The problem:**
Crucible has all the pieces of a self-improving system — genealogy attribution, specialization
memory, quality predictor, triumvirate governance, ANIMA truth store, uncertainty surface — but
they feed into each other weakly. The system learns within a session and across sessions via EMA
weights, but it does not yet systematically identify what is working, extract the pattern, and
harden it into the pipeline configuration itself.

**What's missing:**
The self-patcher (`selfPatcher.ts`) exists and is documented as [x] but needs verification that
it is actually wired and firing. The specific missing behavior:

- After every N pipeline rounds (suggest 20), read the last 100 debug events
- Identify which pipeline stage most frequently precedes a low synthesis score
- Cross-reference with `quality-history.json` and `specialization.json`
- Propose a concrete config change (stage prompt tweak, model weight adjustment, early-exit
  threshold change) — not code, just config that the existing infrastructure can apply
- Route proposal through triumvirate (already built)
- Apply on approval, log to `.crucible/self-patches.json`
- Roll back automatically if quality predictor trend goes negative within 10 rounds

**Key distinction from fine-tuning:**
Crucible does NOT train model weights. It refines ITSELF — its routing logic, its stage prompts,
its scoring thresholds, its model selection weights. The models stay external and free. The
intelligence that compounds is in the pipeline configuration and the accumulated signal in
`.crucible/`. This is the correct framing of "self-improvement" for Crucible's architecture.

**Files to verify/fix:**
- `src/CrucibleEngine/selfPatcher.ts` — confirm it is actually called from server.ts on a schedule
- `src/CrucibleEngine/autoImprove.ts` — confirm `triggerImprovementPass()` is firing after rounds
- `GET /api/self-patcher/patches` — check this endpoint returns real data, not empty

---

## PRIORITY 2 — Regression Safety Net (Benchmark Suite)

**The problem:**
Architectural decisions — which models to favor, which pipeline stages to keep, which weights to
tune — are currently made based on feel and spot-checking. A bad patch could degrade answer
quality and would only be caught through user observation, not measurement.

**What's missing:**
Track E3 (benchmark suite) is marked [x] in the roadmap but needs verification it is actually
running continuously. Specifically:

- `.crucible/benchmarks.json` should exist with 50+ canonical questions and known correct answers
  across all prompt types (coding, reasoning, factual, math, creative, general)
- After every significant pipeline change, the suite should run in the background and record
  pass rates per category
- `GET /api/debug/benchmarks` should return rolling pass rates and flag any category that dropped
  more than 5% from its baseline
- The neuromorphic stress test (documented in ROADMAP.md) should be one of the benchmark entries
  with its 7-section pass criteria

**Implementation note:**
The benchmark runner should use the SIMPLE_PIPELINE_CONFIG (not full ensemble) to avoid burning
quota on self-testing. Results go to `.crucible/benchmark-results.json`. The signal is trend,
not absolute score — is the system getting better or worse over time on a fixed question set.

---

## PRIORITY 3 — "Shows Its Work" Mode (The Demo Mode)

**The problem:**
Crucible performs extraordinary reasoning — triadic dialectics, abductive synthesis, epistemic
calibration, ANIMA shaping, confidence annotation — and the user sees almost none of it. The
process trail exists but is collapsed by default and doesn't tell a coherent story.

**What's missing:**
A toggle in the UI (off by default, labeled something like "thinking visible") that expands the
synthesis to show:

- Which models agreed vs disagreed at Stage 1 (score variance visualization)
- What the Critic flagged (already stored in `criticProblems`)
- Which claims are HIGH vs LOW confidence (already stored in `round.confidence`)
- The fragile assumption (already stored in `fragilityAssumption`)
- What ANIMA detected and how it shaped the response (transparency layer already built)
- Cross-domain connections MASTERPIECE found (already stored in `masterpiece` field)
- Which model actually contributed most to the final synthesis (genealogy attribution)

**Why this matters:**
This is simultaneously the strongest marketing asset (visible reasoning beats any benchmark
number) and the best debugging tool (when something goes wrong, you can see exactly which stage
failed and why). It is not a new system — it is a UI layer over data that already exists in
every `Round` object. Estimated build: 2-4 hours in `App.tsx`.

**Design constraint:**
No emojis. No clutter. A single toggle that reveals/hides a structured breakdown panel below
the synthesis. Mobile-first — must work at phone width. Should feel like turning on subtitles,
not opening a dashboard.

**Status (June 14 2026):**
Genealogy contribution rates are now sent over SSE (`genealogy` event type) and displayed in
the process trail — showing which model contributed what fraction of the final synthesis.
`recordPipelineRun()` and `recordProbationOutcome()` wired. Probation status shown in topology.
The "toggle all open by default" version of Shows Its Work is still not built — the process
trail is still collapsed by default. A `showWork` boolean in state that auto-opens the
`<details>` elements and adds a toolbar toggle is the remaining work.

---

## PRIORITY 4 — Voice Pipeline (Mobile Transformation)

**The problem:**
Crucible on mobile requires typing. The Remote Brain track is documented but not built. Even
without the full screen-stream vision, a voice input → pipeline → spoken response loop would
transform how the system feels and dramatically expand its use cases.

**What to build (minimal viable version):**
1. Microphone button in the mobile input bar
2. On press: record audio, send to Whisper on HuggingFace Inference API (free, no key needed
   for public models, ~300ms transcription)
3. Transcribed text enters the normal pipeline
4. After synthesis, pass response text through Edge-TTS (Microsoft, free, no API key) for
   spoken playback
5. The response plays through the phone speaker while text is visible

**What NOT to build yet:**
The full Remote Brain (screen stream, Mac control, Bluetooth fallback) is a larger project.
Build the voice I/O loop first — it is self-contained and validates the audio pipeline
before adding the complexity of screen streaming.

**Key files to create:**
- `src/CrucibleEngine/voice/stt.ts` — Whisper HuggingFace wrapper
- `src/CrucibleEngine/voice/tts.ts` — Edge-TTS wrapper
- `App.tsx` — microphone button + audio playback (mobile only, hidden on desktop)

**Free-tier note:**
HuggingFace `openai/whisper-large-v3` is available on the Inference API free tier.
Edge-TTS is accessed via the `edge-tts` npm package, no API key, Microsoft's free
neural voices. Both fit the free-tier-only philosophy exactly.

---

## PRIORITY 5 — Persistent Agent Goals (Long-Horizon Continuity)

**The problem:**
Every agent session starts from zero context about multi-session goals. The checkpoint system
saves iteration state within a session, and episodic memory summarizes what happened. But if
you tell Crucible "refactor this codebase over the next week," it has no structure for tracking
progress across sessions, knowing what's done vs pending, or picking up intelligently where it
left off.

**What's missing:**
A task graph that persists across sessions:

```json
// .crucible/task-graph/<goal-id>.json
{
  "goal": "Refactor authentication system",
  "created": "2026-06-14T…",
  "status": "in_progress",
  "nodes": [
    { "id": "n1", "task": "Audit current auth flow", "status": "done", "completedAt": "…" },
    { "id": "n2", "task": "Replace JWT library", "status": "in_progress", "startedAt": "…" },
    { "id": "n3", "task": "Update tests", "status": "pending", "dependsOn": ["n2"] }
  ]
}
```

At session start, agent checks for open task graphs matching the current project, reports
progress naturally ("Last session I finished the auth audit — continuing with the JWT
replacement"), and resumes from the correct node.

**Integration points:**
- `goalDecomposer.ts` already exists — extend to write decomposition output to task graph file
- `episodicMemory.ts` already summarizes sessions — link summaries to task graph nodes
- Agent loop preamble already reads `memoryDigest` — add task graph injection here
- New `GET /api/task-graph` endpoint for inspection
- New `POST /api/task-graph/create` to initialize a multi-session goal

---

## PRIORITY 6 — Actionable Uncertainty (Closing the Epistemic Loop)

**The problem:**
H1 confidence calibration flags LOW and UNVERIFIED claims. H4 surfaces the fragile assumption.
H2 routes uncertain topics to the full pipeline. But none of this tells the user what to DO
about the uncertainty. A flagged claim with no suggested action is decorative, not useful.

**What's missing:**
When the confidence calibrator produces LOW or UNVERIFIED claims, generate a specific
suggested action alongside each flag:

- For UNVERIFIED factual claims: auto-generate a web search query the user can run to verify
  (use the existing DDG grounding infrastructure — `webGrounding.ts` — to attempt verification
  first, surface the query if grounding fails or conflicts)
- For LOW confidence reasoning claims: surface the specific assumption that if wrong would
  break the claim (this is already computed by H4 `getFragilityAssumption` — just link it
  to the specific flagged sentence rather than the synthesis as a whole)
- For PROVISIONAL world model facts: surface when the fact was last verified and what would
  update it

**Implementation:**
Extend `confidenceCalibrator.ts` `calibrate()` return type to include `suggestedAction?` per
flagged claim. Extend the `confidence` SSE event to carry these. Extend the UI confidence
strip to show the action inline with each flagged claim — a small "verify →" link or suggested
search query. No new model calls needed — this is recombination of existing signals.

---

## ARCHITECTURAL REMINDER — What Self-Improvement Means in Crucible

Crucible does NOT fine-tune or retrain models. The models are external, free-tier, and fixed.

What Crucible refines is ITSELF:
- **Routing logic** — which model gets which query (specialization memory, viability scores)
- **Stage configuration** — which pipeline stages fire, in what order, with what prompts
- **Scoring thresholds** — when to early-exit, when to force full pipeline, when to escalate
- **Model selection weights** — EMA-based bias toward models that actually survive into synthesis
- **World model** — accumulated facts, decisions, episodic memory that inform future responses
- **Pipeline prompts** — the system prompts driving each stage, tunable via self-patcher

The compounding advantage is not in model weights. It is in the accumulated signal in
`.crucible/` and the pipeline configuration that has been tuned on real usage. Six months of
real queries produces routing intelligence, uncertainty surface calibration, and specialization
memory that cannot be replicated by spinning up the same stack on a fresh install.

This is the correct framing. Build everything with this in mind.

---

## QUICK WINS (< 2 hours each)

These are not priorities but are high-value and low-effort:

**A. Wire `recordPipelineRun()` verification** — DONE (June 14 2026)
`recordPipelineRun()` is now called after every Stage 5 completion so the specialization
forcing recency counter advances correctly. `pipelineRunCount` was stuck at 0 — forcing decay
never fired. Fixed in server.ts.

**B. `/api/waitlist` auto-promotion on boot** — DONE (was already wired)
`promoteNextFromWaitlist()` is already called at server boot (line 336 in server.ts).

**C. Probation outcome recording** — DONE (June 14 2026)
`recordProbationOutcome()` now called alongside `recordModelOutcome()` at Stage 1 outcome
sites. Probation models now accumulate outcome data and can graduate or be rejected.

**D. Debug topology shows probation status** — DONE (June 14 2026)
`GET /api/debug/topology` now includes `probation` array with id, label, callsRemaining for
each model in a probation slot.

**E. Genealogy contribution rates in UI** — DONE (June 14 2026)
`genealogy` SSE event now emitted after attribution pass. Process trail in App.tsx now shows
per-model contribution rates as percentage bars under the ensemble section.
