# Voice-Audit Phase 4 — prompt-iteration changelog

Append-only. One row per hypothesis: **hypothesis → edit → result → keep/revert**. The basis of
record is **n=3, t0.3, 9 golds, `--pointwise`** (odd counts only; n=1 is smoke-only — never a
keep/revert basis). Optimization target = pairwise **win+tie** rate vs gold across the 9 songs.
Gates: tier1 0 HIGH, grounding judge passes. See `claudedocs/04-voice-audit-orchestrator.md`.

Baselines carried in (captured 2026-06-07, doc 03): **v17** and **v18** each **0/9 win-or-tie**
(0W/0T/27L), grounding **100%**, dominant failure **essayistic/book-report register**
(`essayistic-register` 0/27 v17, 2/27 v18). Iterate from **v17**; v18 is a dead end.

Artifacts: `scripts/voice-audit/eval-artifacts/{v17-base,v18-regrouped-base}.json`.

---

## H1 — v19: name the book-report register; turn the digest's recurring tells into Wrong→Right

- **Date:** 2026-06-07
- **Parent:** v17 (`lyrical-v17.ts`)
- **Hypothesis:** v17's essayistic-register failure is a *register* miss, not a content miss
  (grounding is already 100%). The existing soft "be the friend, not the critic" line tells but
  never shows. Naming the book-report register explicitly and converting the actual recurring
  failure tells from the "what keeps losing" digest into Wrong→Right pairs — the same
  corrected-pair pattern Gemini follows elsewhere in the prompt — should move
  `essayistic-register` off 0% and start converting losses to ties.
- **Edit (ONE):** new `SOUND LIKE A PERSON, NOT A BOOK REPORT:` section in `lyrical-v19.ts`,
  inserted between `INTERPRET, DON'T DESCRIBE` and `FIND THE READ BEFORE YOU WRITE IT`. Bans three
  named tells with the digest's verbatim failures as the Wrong side: the grand abstract opener
  ("The song lives in…", "finds its rhythm in…"), the theme-summary apposition ("a defiant
  celebration of her survival…"), the floating poetic flourish ("the ghost of what he lost is
  always dancing beside him"). Right rewrites are invented (NO-GOLD-BAKED-IN held). Template diff =
  exactly this one block; everything else byte-identical to v17. Registered "19"; ACTIVE still 13.
- **Smoke (n=1, 2026-06-07):** **DEAD ON ARRIVAL.** Generated 8/9 (motion-sickness's single
  candidate did not store — a generation gap, not the edit's fault). `eval-artifacts/v19-screen.json`.
  Designated smoke signal — `essayistic-register` — **0% → 0% (+0pt)**: did NOT move off zero.
  Pairwise 0W/0T/8L. Per the methodology, n=1 is smoke-only; the secondary-judge deltas
  (redundancy −24pt, voice-softness −12pt, abstract-noun-trap −12pt) are n=1-vs-n=3 noise, not read.
- **Why it failed (Opus pairwise rationales, convergent):** the phrase blocklist was routed around.
  I banned "The song lives in…" / "finds its rhythm in…"; Gemini produced "The song transforms…",
  "It charts a course…" instead — same book-report register, different tokens. It also kept
  restating the lens as decoration in the take. A blocklist of example phrases cannot suppress a
  *behavior*; it only teaches which exact strings to avoid.
- **New signal (separate target):** the candidate repeatedly leaks raw audio-feature vocabulary
  ("low energy and sad valence", "high danceability", "low valence wrap the vocals") out of
  `texture` into the `take`. Candidate for a later hypothesis (possibly tier1-able).
- **Keep/revert:** **REVERT.** Do not spend the n=3 run. `lyrical-v19.ts` stays in-tree + registered
  as the experiment record (dead end, like v18); ACTIVE untouched (13). H2 iterates from **v17**,
  not v19 — replace the phrase blocklist with a *behavioral* register edit (mandate the opening
  move + ban the apposition *form*), not more example phrases.

---

## H2 — v20 (proposed): replace the blocklist with a behavioral register mandate

- **Date:** 2026-06-07
- **Parent:** v17 (NOT v19 — v19 is the failed branch)
- **Hypothesis:** the dominant essayistic tell — cited in nearly every Opus pairwise rationale on
  BOTH Flash and pro — is the **antithesis thesis-pivot** ("This is not X. It is Y", "not a rival
  but a predator"). v17 has one weak line against it that shows only the in-clause form and gets
  buried, so the cross-sentence form sails through. A behavioral, example-driven ban covering all
  forms (in-clause, cross-sentence, mirrored) should drop the tell out of the candidates and start
  converting losses toward ties.
- **Edit (ONE):** REPLACE v17's "Say what something is. Don't say what it 'isn't'…" line with a
  behavioral ban: names the move as the book-report tell, kills it in every form, gives Wrong→Right
  pairs from the actual cited failures (invented Rights), and keeps the legit subordinate-contrast
  carve-out. Template diff = exactly that one paragraph; everything else byte-identical to v17.
  Registered "20"; ACTIVE still 13.
- **Read criteria (refined):** the pointwise `essayistic-register` judge looks saturated at 0%
  (stuck even on pro candidates the Opus pairwise rated close/tie), so judge mainly on the Opus
  pairwise rationales — did "not X, it is Y" drop out? — plus any pairwise tie/close-call movement.
- **Smoke (n=1) — FREE mechanism check, Opus NOT spent:** generated 9/9 (tier1 mean-high 2.89,
  intact). A free grep of the raw v20 take/contradiction/scene text for the antithesis pivot found
  it STILL present in **4/9** candidates, in forms the edit's examples didn't literally name:
  beautiful-things "aren't just gifts; they are a ticking clock"; no-sex-for-ben "is not just bad,
  but pathetic"; dtmf "are not separate from the past; they are built on it"; not-like-us "is not
  just about one man; it is about his whole crew." The edit banned "This is not X. It is Y."; the
  model routed to "X is not just Y; it is Z" / "not just X, but Y." Same routing-around failure as v19.
- **Keep/revert:** **REVERT.** Opus smoke not spent — the free raw-text check already shows the
  mechanism failed (tell not suppressed). `lyrical-v20.ts` stays in-tree + registered as the record;
  ACTIVE untouched (13).
- **META-FINDING (across v19 + v20):** example-driven NEGATIVE instruction does not suppress the
  essayistic register on gemini-2.5-flash. Showing "here are bad forms, avoid them" teaches the
  model to avoid those exact strings and generate structurally-identical variants around them. Two
  prohibition edits failed this way; the pro probe (P1) showed the tells survive a model swap too.
  Next lever must change: from PROHIBITION to DEMONSTRATION (make the worked-example/{example} slot
  dominant, trim the wall of negative rules) or to a PIPELINE gate (a tier1 rule that catches the
  "not just X" / cross-sentence antithesis and forces regeneration). Strategic call — see below.

## P1 — Probe: v17 prompt UNCHANGED, model swap Flash → gemini-2.5-pro (model-ceiling test)

- **Date:** 2026-06-07 · **n=1 smoke**, 8/9 songs (dtmf generation dropped; excluded via `--songs`
  so no Flash fallback). Prompt held at v17; only `regen --model gemini-2.5-pro` changed.
  Artifacts: `eval-artifacts/v17-pro-screen.json` (model verified `google-vertex:gemini-2.5-pro`)
  vs `v17-base.json` (Flash n=3).
- **Question:** is the essayistic-register failure a gemini-2.5-flash ceiling? If a stronger model
  clears it with the same prompt, the fix is the model, not the prompt.
- **Result (divergent signals):**
  - Strict pointwise `essayistic-register`: **0% → 0%** — unchanged. Pro does NOT clear the register judge.
  - Opus pairwise vs gold: **0% → 13%** (1 tie / 8) — first non-loss in the whole program, several
    "close call" rationales. tier1 mean-high **3.67 → 2.13** (pro adheres to the mechanics better).
  - The lone tie (drivers-license) is **shaky**: its rationale flags invented details ("In-N-Out
    parking lot", "white Honda") not in the song — a possible fake tie / grounding-judge slip
    (the "when a win is fake" reflex), not a clean win.
  - Secondary judge deltas (voice-softness −25pt, redundancy +13pt, abstract-noun −12pt) are
    n=1-vs-n=3 noise; not read.
- **Conclusion: pro is NOT a register ceiling-break.** The dominant tells survive the model swap —
  the **antithesis pivot ("This is not X. It is Y", "not just a feeling. It is…", "not a rival but
  a predator")** and the **book-report opener ("This is…", "The song is…")** appear in nearly every
  pro pairwise rationale, the same as on Flash. Pro mainly cleans tier1 (a guardrail we already
  pass) and buys one shaky tie. **The register is a prompt/behavior problem, model-independent.**
- **Keep/revert:** no keep. Stay on Flash (cheaper; pro's only real gain is on tier1, which isn't
  the target). The probe SHARPENS H2: the single most-cited essayistic tell across both models is
  the **antithesis thesis-pivot** (MEC-6 / SFT-7 mirrored parallelism) plus the book-report opener
  — target those two moves behaviorally, not a phrase blocklist.

## H3 — v21: demonstration over prohibition (elevate the worked examples above the rule-wall)

- **Date:** 2026-06-07 · **Parent:** v17 (branches from v17, not v19/v20).
- **Rationale (research-backed):** web research confirms few-shot exemplars steer style more
  reliably than verbal rules ("you can remove instructions if your examples are clear enough"), and
  negative "don't" rules are weak for register — which is why v19/v20 (both prohibition) were routed
  around. The demonstration lever is ALREADY present: `regen.ts` injects 2 full leave-one-out gold
  reads into `{example}` (rendered by `renderExemplarBlock`, "study their voice… write in the same
  voice"). But it competes against a ~20-rule prohibition wall and the prompt never says the examples
  OUTRANK the rules for voice — so the model obeys rules that *describe* essayistic constructions
  while banning them.
- **Edit (ONE):** insert one all-positive directive after `{example}` — "THE BAR IS THOSE EXAMPLES,
  NOT THIS LIST OF RULES… follow the examples… The rules… do not set the voice; the examples do."
  No new prohibition, no bad-register text to copy, no gate touched. Template diff = exactly that
  block. Registered "21"; ACTIVE still 13. typecheck clean.
- **Smoke (n=1) — FREE register scan (8/9; motion-sickness gen dropped):** MIXED. Several takes now
  open concretely on the person (beautiful-things, dtmf, blinding-lights — the example voice
  landing), but the book-report frame persists on no-sex-for-ben ("The song is a relentless… public
  denunciation"), not-like-us ("This is a declaration of war…"), as-it-was ("The song opens with…");
  antithesis pivot on ~3–4. Partial improvement, not a clean miss → free check can't decide it, so
  the Opus pairwise was spent.
- **INDEPENDENT FINDING (fixable, future hypothesis):** not-like-us's take opens **"This is a
  declaration of war"** — *verbatim v17's own `Wrong:` example* (template line 84). The model is
  lifting the prompt's in-prose negative examples as templates. v17 carries several `Wrong:` snippets;
  neutralizing/relocating them (or not spelling bad text at all) is a clean candidate edit, separate
  from H3.
- **Smoke (n=1) Opus result — `eval-artifacts/v21-screen.json`:** **0W/0T/8L (0%)** — back to the
  floor (worse than pro's 1 tie). Pointwise essayistic-register still 0%. Opus rationales cite the
  same tells: as-it-was "opens like a book report ('The song opens with…')"; dtmf "leans on
  antithesis ('This isn't a paralysis; it is a push')"; not-like-us "'This is a declaration of war,
  not just… but'" + **data-speak leak** ("Its low valence suggests a negative emotional tone").
  redundancy +13pt but register flat (n=1-vs-n=3 noise on the rest).
- **Keep/revert:** **REVERT.** One re-weighting sentence cannot overcome the ~20-rule wall. v21
  stays in-tree as the record; ACTIVE untouched (13).
- **DECISION POINT:** three Flash register hypotheses (v19 prohibition, v20 prohibition, v21
  demonstration-lite) have all failed to move the pairwise off 0. Per the brief's escalation ("2–3
  register hypotheses don't move it → suspect a Flash ceiling, try pro BEFORE grinding more prompt
  edits"), stop grinding Flash. The pro n=1 probe (P1) was the strongest signal in the program
  (cleaner tier1, 1 tie, close-calls). Next: **confirm pro at n=3 on v17** (basis-of-record) — does
  the prescribed escalation actually convert? See P2 below.

## P2 — Confirm: v17 prompt UNCHANGED on gemini-2.5-pro at n=3 (basis-of-record escalation)

- **Date:** 2026-06-07 · prompt held at v17, `regen --model gemini-2.5-pro --runs 3`. Confirms the
  P1 n=1 hint at the basis-of-record. Opus n=3 eval (81 calls) GATED behind verifying clean per-song
  pro coverage (≥3 fresh pro runs/song) to avoid Flash/pro-n1 contamination in selectCandidates.
- **Coverage:** pro generation is flaky — dtmf got 1 run, blinding-lights/as-it-was 2 each, the
  other 6 got 3. A reproduction of `selectCandidates` (newest-3 by version+temp) confirmed 8/9 songs
  resolve to all-pro at `--limit 3`; only dtmf is mixed (PRO,flash,flash) and was EXCLUDED via
  `--songs`. Evaluated 8 clean songs, 24 pro candidates. Artifact model verified all
  `google-vertex:gemini-2.5-pro`.
- **Result — `eval-artifacts/v17-pro-n3.json`:** **0 win / 4 tie / 20 loss → 17% win+tie**;
  per-song majority **1/8** (drivers-license TIE,TIE,LOSS). pink-pony (LOSS,TIE,LOSS) and as-it-was
  (LOSS,LOSS,TIE) each scraped one tie; the other 5 lost all 3. Gates held: grounding 100% (23/23),
  specificity 100%, tier1 1.75 high (cleanest of any run). essayistic-register 13% (3/24) — off
  Flash's 0% but still failing 21/24.
- **Two Opus retries (as-it-was, motion-sickness) fired** — the brief's 5-hour-cap signal. Stop
  launching big Opus runs.
- **Call:** pro is the strongest setup measured, and STILL **1/8 songs** — far below the bar
  (majority of 9). The 4 ties correlate with length (success Δ+131 vs fail Δ+45, r=0.43), and the
  free scan shows the **"X is not Y. It is Z" antithesis pivot in nearly every one of the 24 pro
  candidates** — pro produces the essayistic register as much as Flash. The model swap cleans tier1
  and scrapes a few length-driven ties; it does NOT fix the register. No keep (cost ~3–5× Flash for
  a register that isn't fixed).

---

# CONVERGENCE / READINESS CALL (2026-06-07)

**The loop has converged. The answer is a NO-GO for the Session-6 prod cutover, and the reason is
a single, well-localized, model-level wall.**

**What's solved (do not re-litigate):** grounding 100% (Opus, priority-1) on every version/model;
tier1 mechanics clean (1.7–3.7 high, all non-blocking); register-specificity ~100%; the v17 rebuild
closed the v14/v15 specificity/grounding gap entirely.

**The one residual risk — and it is the whole ballgame:** the **essayistic / book-report register**,
concretely the **"X is not Y. It is Z" antithesis thesis-pivot** plus book-report framing
("The song is a…", "This is a…"). It is the dominant reason candidates lose to the golds in the
Opus pairwise, on every version and both models.

**It resists every lever tried (5 experiments):**
| # | lever | result |
|---|---|---|
| v18 | regroup arc | dead (McNemar 1.000; worse on redundancy/voice-softness) |
| v19 | prohibition: blocklist essayistic openers | routed around (new openers substituted) |
| v20 | prohibition: behavioral ban on antithesis pivot + examples | routed around (new forms substituted) |
| v21 | demonstration: re-weight examples above the rule-wall | insufficient; pairwise back to 0 |
| P1/P2 | model swap Flash → gemini-2.5-pro (n=1, n=3) | best measured (17% / 1-of-8) but register pervasive; ties length-driven |

**Diagnosis:** the "X is not Y. It is Z" construction is how the Gemini 2.5 family writes by default.
Negative prompting teaches it to dodge the exact banned strings and emit structural twins (confirmed
twice). A stronger model writes the same register more fluently. Three orthogonal prompt-edit classes
+ a model upgrade all failed to remove it. **Prompt-only iteration has hit diminishing returns.**

**Converged best prompt:** **v17** (no edit beat it; v18–v21 all reverted). If shipping anything from
this program, ship v17 — but know it produces the AI register.

**Recommended paths (human's call — taste + cost + architecture):**
1. **Post-generation rewrite pass (most promising, cheap):** a second Flash call that takes the
   draft read and rewrites only the antithesis-pivot / book-report sentences into the friend
   register, preserving all grounded content. Attacks the failure where it is catchable — the
   finished text — instead of trying to suppress a default tendency at generation. No Opus needed to
   generate; Flash-rewrites-Flash.
2. **Deterministic de-essayist tier1 rule + regenerate-on-hit:** broaden the tier1 `antithesis` rule
   (currently in-clause/token-scoped) to catch cross-sentence "X is not Y. It is Z" and "not just X;
   it is Y". Won't fix generation, but makes the failure VISIBLE/gateable and enables reject-and-retry.
   This is why tier1 reads ~clean (1.75 high) while the pairwise loses — the dominant tell isn't gated.
   (Phase-1 territory; untouched per scope.)
3. **Accept the register gap and ship v17/v13** as "grounded, specific, mechanically clean, but
   AI-voiced." Honest if the rewrite pass isn't worth the latency/cost.
4. **Heavier lifts:** fine-tune on the golds, or a gold-dense few-shot regime.

**Calibration caveat to verify before trusting marginal "wins":** pro's ties correlate with length
(r=0.43) and drivers-license's n=1 tie used possibly-imported detail ("In-N-Out parking lot",
"white Honda") while grounding passed 100%. The 17% may be mildly inflated by the judge rewarding
longer/detail-dense candidates. Doesn't change the headline (register is the wall), but spot-check
the grounding judge (`grounding-calibration.ts`) before treating any pro tie as a real win.

**Uncovered:** dtmf (chronic pro-generation flakiness — 0/1/1 valid runs across attempts); motion-
sickness also flaky on n=1. Both generated fine on Flash. If pursuing pro, investigate the
generation drops (likely content-filter or length).

# POST-CONVERGENCE: target the antithesis pivot directly (2026-06-07, user-directed)

User priority: the **"X is not Y. It is Z" antithesis pivot** is the most evident AI tell and must
go. Two levers: (1) extend tier1 to catch it; (2) experiment to stop generating it. (Opus was NOT
actually capped — the earlier retries were transient CLI hiccups; ~72% of the window remained.)

## T1 — tier1 cross-sentence antithesis rule (DONE, shipped uncommitted)

- **Gap found:** the existing tier1 `antithesis` rule (`ANTITHESIS_FRAME`) uses `[^.]*?`, which stops
  at the period — so it catches the same-sentence form ("not just X; it is Y") but MISSES the
  cross-sentence pivot ("This is not a diss track. **It is** testifying."). That's why tier1 read
  ~clean (1.75 high on pro) while the pairwise drowned in the pivot — the dominant tell was ungated.
- **Rule added** (`scripts/voice-audit/tier1/rules.ts`, `ANTITHESIS_CROSS_SENTENCE`, folded into the
  HIGH `antithesis` rule): a negated copular clause ending a sentence, then a next sentence that
  RE-ASSERTS with a copula (pronoun + is/are/'s/a/an/the…). The copula re-assertion is the signature;
  narrative continuations ("She is not ready. She drives anyway.") use action verbs and are skipped,
  and the golds' legit contrasts ("could never be bought, only inherited"; "the door stays shut, not
  slammed") have no "is not … It is" shape.
- **Calibrated:** **0 hits on all 9 golds** (golds-are-truth gate intact — `exemplars.test.ts` green);
  catches the pivot on the real losing candidates. 4 unit tests added (positive + contracted +
  narrative-skip + gold-contrast-skip). **`bun run test scripts/voice-audit/__tests__` → 153/153.**
- **Baseline rate the rule now reveals (free, via runAllRules):**
  | version/model | n | % with antithesis | hits/cand |
  |---|---|---|---|
  | v17/flash | 40 | 23% | 0.28 |
  | **v17/pro** | 31 | **52%** | **1.13** |
  | v20/flash (ban) | 9 | 22% | 0.56 |
  | v21/flash (demo) | 8 | 50% | 0.63 |
  Pro is the WORST (more fluent → more pivots), and the prohibition/demo edits *raised* the rate.
- **Correlation with outcome (pro n=3, free join of artifact verdicts × recomputed antithesis):**
  TIES 75% antithesis-free (3/4) vs LOSSES 50% (10/20). Directional (pivot ↔ losing) but n=4 ties is
  small; and half the LOSSES are pivot-free too → **killing the pivot is necessary cleanup of the
  most-evident tell, not sufficient to tie the golds** (book-report openers, data-speak remain).

## H4 — v22: the PRIMING test (remove v17's anti-pivot line)

- **Hypothesis:** v20 (ban) and v21 raised the antithesis rate → naming the pivot PRIMES it
  ("don't think of an elephant"). Removing v17's "Say what something is. Don't say what it 'isn't'…"
  line should LOWER the rate. v22 = v17 minus that one line (diff verified = the single deletion).
- **Measurement:** FREE — regen v22 flash n=3, count antithesis via the new rule, compare to v17's
  0.28/cand & 23%. Opus only if the rate drops.
- **Result (free, n=26):** v22 = **0.38 hits/cand, 27% with-pivot** vs v17's 0.28 / 23% — flat-to-
  slightly-HIGHER, not lower. **Priming REFUTED.** No Opus spent (drop criterion not met).
- **Keep/revert:** REVERT. v22 in-tree as the record; ACTIVE untouched (13).

## CONCLUSIVE FINDING — the pivot cannot be prompted away; it must be GATED away

Four prompt formulations now measured against the antithesis rate (free, deterministic):
| prompt | how it treats the pivot | hits/cand |
|---|---|---|
| v17 | one mild "don't pivot" line | **0.28** (lowest) |
| v22 | no mention at all | 0.38 |
| v20 | strong ban WITH "Wrong:" pivot examples | 0.56 |
| v21 | "match the examples" demonstration | 0.63 |

The pivot is a **base-model default** (~0.28–0.38/cand on flash, **1.13 on pro**) essentially
independent of how the prompt addresses it — and **showing the literal pivot string as a "Wrong:"
example makes it WORSE** (v20; corroborated by not-like-us copying v17's "This is a declaration of
war" verbatim). Prohibition, demonstration, and removal all failed to reduce it. **You cannot prompt
it away.**

**Therefore the only reliable lever to "not get those" is non-generation:**
1. **Regenerate-on-hit (cheapest, uses the new gate):** at generation, reject any read with
   `antithesis > 0` and resample. Flash is ~73–77% pivot-free, so the gate accepts a clean draft in
   ~1.3–1.4 draws on average. Deterministic, no extra model, leverages exactly the rule shipped in T1.
2. **Post-generation rewrite pass:** a second Flash call that rewrites only the pivot/book-report
   sentences into the friend register, preserving grounded content. Fixes otherwise-good reads
   instead of discarding them. Verify removal for free with the same rule.

Caveat (unchanged): removing the pivot is necessary cleanup of the most-evident tell, but flash
candidates lost the pairwise even when pivot-free — other register issues (book-report openers,
data-speak leak) remain. The gate makes the #1 tell *gone and measurable*; it does not by itself
tie the golds.

**Status:** tier1 gate shipped + calibrated (153/153). Production mechanism (regenerate-on-hit or
rewrite pass) is a generation-path change — recommended, not yet built (it touches the prod pipeline,
a separate decision). Prompt-side research is exhausted: v17 remains the converged best prompt.

---

# ROUND 2 — research-backed register variants (H5–H10, 2026-06-07, user-directed)

User re-opened prompt research: "v17 is our best… research the web on best practices… completely
eliminate 'it is… isn't' and similar… try 5 or 6 adjustments, smoke, pick the best." Goal: kill the
pivot via the prompt. Flash only (Pro dropped — too expensive). The prior round's 4 formulations
(v17 mild line / v20 concrete-ban / v21 demo / v22 removal) all shared one flaw — they either *named
the pivot with a concrete bad-string example* (primes) or *removed the guidance into a vacuum*. This
round tests the corners those missed, each variant a single guarded edit to v17 (string-replace that
throws on a no-op so a mismatched anchor can't ship a v17 clone).

**Web research (sources at end) — the distinction the prior round missed:**
- Positive instructions beat negative for register; "larger LLMs perform *worse* on negative
  instructions"; negative prompts "shift focus toward what you're avoiding" (= the v20/v21 priming).
- **Concrete phrase-banning fails/primes, but *category-level* naming works** — "prohibiting
  'thesis-antithesis patterns,' 'dialectical hedging,' 'rhetorical equivocation' is significantly more
  effective," paired with "define affirmatively; treat contrast as a high-impact tool used sparingly."
- Few-shot *voice samples* (2–5) beat instructions for register (Gemini: "always include examples").
- Full elimination needs **sequence-level enforcement (Antislop) or fine-tuning (FTPO)** — i.e. the
  gate/rewrite, not the prompt. (Confirms the prior call from the literature.)

**Method:** free smoke = regen Flash n=3 × 9 golds, t0.3, score with the tier1 cross-sentence
antithesis rule (`runAllRules`). Same basis as the prior free measurements; v17 re-run this session as
the control. Scripts: `scripts/voice-audit/verify-variants.ts` (diff/guard check),
`analyze-smoke.ts` (rate table + per-song coverage + gate sim).

| version | lever | antith/c | % w/pivot | book/c | high/c |
|---|---|---|---|---|---|
| **v24** | copula-displacement (verbs of action; reserve is/are for plain fact) | **0.23** | 20% | 0.00 | **3.30** |
| v28 | synthesis: v24 + v25 | 0.29 | 25% | 0.04 | 3.75 |
| v25 | sentence-level friend-voice micro-exemplars | 0.30 | 23% | 0.00 | 3.30 |
| **v17** | control | 0.31 | 24% | 0.03 | 3.97 |
| v27 | category-level prohibition + affirmative, no concrete strings | 0.31 | 24% | 0.03 | 3.48 |
| v26 | purge v17's spelled `Wrong:` book-report strings | 0.36 | 25% | 0.04 | 3.54 |
| v23 | pure-affirmative line (zero negation words, no examples) | **0.44** | 33% | 0.07 | 4.30 |

**The differences among v17/v24/v25/v27/v28 are within smoke noise** (20% vs 25% w/pivot ≈ 6/30 vs
7/28; not distinguishable at n~30). What is robust + the hand-read of the actual prose:

- **H5 / v23 — pure-affirmative is the WORST (0.44).** Stripping all negation and the guardrail let
  the base default reassert (corroborates v22's removal → 0.38). **REVERT.** Lesson: v17's explicit
  caution does real work; you cannot just go positive-and-silent.
- **H6 / v24 — copula-displacement: best free score + cleanest, but partly rule-dodging.** Hand-read:
  genuinely direct, person-acting, present-tense on PROTAGONIST songs (drivers-license, DtMF, Motion
  Sickness, Blinding Lights). BUT on collective/argument songs (Not Like Us) the copula ban just
  reroutes the essayism into "It defines/weaponizes/draws…" (uncaught by the antithesis regex →
  flatters the count; one NLU candidate hit high=10). Real but partial. **DO NOT KEEP as a win** — the
  free gain is within noise and the register fix doesn't reach the songs that actually fail.
- **H7 / v25 — micro-exemplars: genuine second-person voice transfer.** Hand-read: As It Was rendered
  in "you" ("The world has shifted, and you find yourself in a new, solitary space… You ring the bell
  for help, but no one comes") — directly traceable to the voice-block, where v17 stayed in "he."
  COST: occasionally adds a pivot at confident take-closings (Pink Pony Club "not just a place; it is
  …"). Net: marginal, song-dependent. **REVERT** (as a measured win); the voice block is a candidate
  to fold into v17 only if a pairwise later shows it converts.
- **H8 / v26 — purging the spelled `Wrong:` strings did not help (0.36, flat-to-worse).** The H3
  finding (not-like-us copied "This is a declaration of war" verbatim) was real, but removing the
  source does not lower the *aggregate* pivot rate. **REVERT.**
- **H9 / v27 — category-level naming is SAFE (0.31 ≈ v17), unlike concrete banning (v20 0.56).** The
  genuinely NEW, research-validated finding: abstract category-level prohibition does NOT spike the
  rate the way v20's concrete `Wrong:` strings did. It doesn't *beat* v17, but it is the better-phrased
  way to state the same caution (no priming, all-affirmative framing). **Optional keep** as a wording
  refinement to v17's anti-pivot line; not a measurable win on its own.
- **H10 / v28 — synthesis (v24 + v25) did NOT stack (0.29 ≈ v17).** Inherits v25's second-person As It
  Was win AND its PPC pivot; collective-song essayism persists (one NLU candidate high=13). No
  additive gain. **REVERT.**

**Gate simulation (read-only, on the 200 candidates generated this round):** the pivot is ELIMINABLE
by prompt+gate, not prompt alone. Regenerate-on-hit (reject antithesis>0, resample) lands an
antithesis-clean draft in **~1.3 draws** (v17 76% clean / 1.32; **v24 80% clean / 1.25** — the lowest
base rate is the cheapest to gate), and on **0/9** songs did every draw pivot.

**IMPORTANT CORRECTION — v17 is NOT "tier1-clean," only gateable on the pivot subset.** The antithesis
gate removes ~8% of v17's HIGH hits. Per-candidate HIGH composition (this round):

| version | antithesis | participial-closure | self-reference | book-report | Σ high/c | % candidates 0-HIGH |
|---|---|---|---|---|---|---|
| v17 | 0.31 | **3.38** | 0.17 | 0.03 | 3.97 | **0%** |
| v24 | 0.23 | 2.93 | 0.10 | 0.00 | 3.30 | 0% |

The dominant tier1 tell is **participial-closure** (the "comma + -ing" construction the prompt
explicitly bans, ~3.4/read anyway), not the antithesis pivot — the pivot just READS as the most
evident tell to a human. And **0% of candidates are fully HIGH-clean**, so you **cannot resample to
tier1-clean** — a regenerate-on-hit gate can only ever fix what it gates on (the pivot). The only path
to an actually-clean read is a **rewrite pass** that surgically fixes participial-closure + antithesis
+ self-reference together. This makes the rewrite pass *higher-leverage than the antithesis gate*, not a
co-equal alternative — and it is consistent with the prior session already ranking the rewrite pass as
"most promising."

## CONVERGENCE — round 2 re-confirms the NO-GO; v17 stands

Six fresh, research-backed levers (v23–v28) **do not beat v17** on the pivot and **none eliminates it**.
The essayistic register + residual pivot are concentrated on **collective/non-protagonist songs** (Not
Like Us, No Sex for Ben — "The song is a public trial… It lists…") and are robust across all seven
versions including v17 — confirming the model-level Gemini-2.5 default diagnosed in round 1.

- **Best prompt: still v17.** No keep. v23–v28 registered in-tree as the experiment record (dead ends);
  ACTIVE still 13.
- **One optional prompt nicety:** swap v17's negatively-phrased anti-pivot line for v27's category-level
  + affirmative phrasing (safe, research-aligned, no priming, ~equal rate). Wording polish, not a win.
- **The lever that actually eliminates the pivot is the gate** (tier1 regenerate-on-hit, already built
  + calibrated) — optionally on the lower-base-rate v24 prompt to cut resample cost. Prod-pipeline
  change, still out of scope here (human's call). A rewrite pass is the alternative.
- **Untested by design:** a paid Opus pairwise on v28/v24/v25 vs gold (does the protagonist-song
  register polish convert any losses to ties?). The free + qualitative evidence shows v28 ≈ v17 on the
  failing songs, so no movement is expected; deferred to a user-authorized run rather than spent
  autonomously (cost). This is the one open question the smoke cannot answer.

**Sources (round-2 web research):**
- "Why Does AI Keep Saying 'It's Not X, It's Y'?" — DEV Community (category-level vs phrase-banning; affirmative reframe)
- "Some alternatives to 'It's not X; it's Y'" — Hardly Working / Substack (positive rewrite patterns)
- "Positive Prompts Outperform Negative Ones with LLMs" — Gadlet; KAIST finding via prompt-engineering best-practice roundups
- "Antislop: Identifying and Eliminating Repetitive Patterns in LMs" (arXiv 2510.15061) — sequence-level enforcement + FTPO
- Google "Prompt design strategies" (ai.google.dev) — always include few-shot examples; persona/instruction placement
- Humanizing-LLM editing guides (louisbouchard.ai; sabrina.dev) — 2–5 voice samples; negative-parallelism as the AI tell

# ROUND 3 — the rewrite pass, built and shipped (2026-06-07, user-directed)

Round 2 ended on the call that the register CANNOT be prompted away and that the **rewrite pass** is
higher-leverage than the antithesis gate (it can fix participial-closure + antithesis + self-reference
together; the gate only fixes the pivot, and 0% of candidates are gateable-to-clean). This round
**builds that rewrite pass**, proves it removes the tells for free, and runs the ship check (v13 vs
v17+rewrite) the program was waiting on.

## What was built

- **`scripts/voice-audit/rewrite/rewrite-pass.ts`** — `rewriteRead(read, llm, {maxPasses})`. A
  second Flash call that takes a finished `ConceptRead`, computes its tier1 HIGH hits, hands the model
  the **exact flagged spans by field** with a per-rule fix recipe (only the recipes for rules that
  actually fired, so it doesn't re-prime the full catalogue — the H4 priming lesson), and asks it to
  recast only those sentences. Loops up to `maxPasses` (default 2) until the targeted HIGH rules clear.
  - **Why a rewrite works where the prompt didn't:** generation is free composition, so the model
    falls into its essayistic default; a rewrite is a *constrained transformation* — the model is
    handed the sentence and told which construction to remove, so it doesn't re-invent the tell.
  - **Surgical guarantee (in code, not trusted to the model):** `applySurgical` pins lens/tension/
    `lines`/arc-labels/arc-moods from the ORIGINAL and takes the model's text ONLY for fields that
    were actually flagged this pass; a null contradiction/texture can never be filled. So a flagged
    sentence is the only thing that can change — unit-tested in `__tests__/rewrite-pass.test.ts` (6
    tests, incl. an adversarial model output that tries to corrupt every field and is rejected).
- **`scripts/voice-audit/rewrite-demo.ts`** — runs the pass on the dirtiest real v17 read per song
  from `experiments/` and prints BEFORE/AFTER HIGH composition (free, via `runAllRules`) + prose.
- **`scripts/voice-audit/ship-check.ts`** — generates v13 (prod, legacy shape) + v17 fresh per song,
  rewrites v17, scores all three on the SAME tier1 surface (v13 adapted: interpretation→take,
  journey→arc scene, sonic_texture→texture), dumps prose side-by-side.

**One bug found + fixed during the build:** the first prompt rendered each arc beat as
`beat N (label — mood): <scene>`, and the model echoed `"beat N"` back AS the scene value — destroying
content. Fixed by presenting the scene as an unambiguous `scene N:` value AND making `applySurgical`
field-aware (an unflagged or corrupted scene is discarded in favour of the original). `bun run test
scripts/voice-audit/__tests__` → **159/159** (153 + 6 new).

## Result 1 — the pass removes the tells, for free (rewrite-demo, 9 golds, dirtiest read each)

| total across 9 dirtiest v17 reads | targeted HIGH tells | Σ HIGH |
|---|---|---|
| BEFORE (v17 flash) | **56** | 56 |
| AFTER (+rewrite, ≤2 passes) | **1** | 1 |

55 of 56 genuine tells gone, mostly in **one pass**, ~3.2k tokens/read (Flash, cheap). The lone
residual (No Sex for Ben) is a **tier1 rule false-positive**, not a pass failure: `participialClosure`
flags `"a specific, shocking detail"` because "shocking" ends in `-ing` and the following noun
("detail") isn't a known determiner — but it's an adjective in a list, already good prose, so the
model correctly leaves it. (A narrow `participial-closure` blind spot: `comma + -ing-adjective + bare
noun`. Out of scope to fix this round; noted for tier1.) Content fidelity verified by direct diff:
flagged sentences recast with meaning intact ("find him alone, sitting on the floor." → "find him
alone. He sits on the floor."), **unflagged sentences byte-identical**, every named detail preserved.
One minor drift class: killing an antithesis pivot can drop a framing word ("not just a diss track;
it is a declaration of war" → "A declaration of war") — defensible (genre framing, not a lyric claim).

## Result 2 — the ship check: v13 (prod) vs v17 vs v17+rewrite

n=3 golds (not-like-us, drivers-license, as-it-was), fresh Flash generations, t0.3. Σ HIGH / read:

| song | v13 (prod) | v17 raw | v17 + rewrite |
|---|---|---|---|
| not-like-us | 1 | 10 | **0** |
| drivers-license | 4 | 0 | **0** |
| as-it-was | 0 | 5 | **0** |
| **total** | **5** | **15** | **0** |

The number is only half the story — **tier1 sees register, not grounding/specificity, which is v17's
whole gain.** The prose read is decisive and one-directional:

- **v13 is not reliably clean** (4 HIGH on drivers-license) AND it is **generic/thin**: Not Like Us
  reads "a definitive statement of loyalty… draws a clear line in the sand… Cultural Reclamation" with
  **zero names or quotes**; As It Was is tier1-clean but nearly empty — "The past is a powerful force.
  It shapes your present… universally felt," with an **empty `sonic_texture`**. This is exactly the
  "clean but says nothing" failure the v17 rebuild was meant to fix.
- **v17+rewrite is clean AND grounded** on every song: Not Like Us names Drake-as-colonizer, "hide
  your lil' sister," "certified pedophiles," the owl label, "drake's mansion on a sex offender
  registry map"; drivers-license has the blonde girl, white cars, "still fuckin' loves him"; As It Was
  has the goddaughter voicemail, "rings a bell for help, but no one comes," the locked door, the
  father living alone. The lenses are real claims ("a milestone as a funeral," "vulnerability as a
  locked door"), not moods.

So v17+rewrite **dominates v13 on both axes** (cleanliness AND depth) for these three. v17 raw confirms
the tells are pervasive at generation (15 HIGH/3 songs) — the rewrite is what makes it shippable.

# READINESS CALL (Round 3) — conditional GO for the cutover, with the rewrite pass in the pipeline

**The NO-GO from rounds 1–2 was "v17 produces the AI register and the prompt can't stop it." Round 3
removes that blocker with a mechanism, not a prompt.** Recommendation:

- **GO to take v17 + the rewrite pass into the Session-6 cutover plan**, on the evidence that
  v17+rewrite is tier1-clean (0 HIGH) and materially more grounded/specific than today's v13 — i.e. it
  ships v13's cleanliness without v13's generic thinness. The mechanism is cheap (Flash-on-Flash, ~1
  extra call/song, 1–2 passes) and its content fidelity is guaranteed in code + unit-tested.
- **Conditions / what is NOT yet proven (do before flipping `ACTIVE_LYRICAL_VERSION`):**
  1. **The official arbiter is still the paid Opus pairwise vs gold; it was NOT run** (cost; deferred
     to user authorization per the contract). The free tier1 + qualitative read is strong and
     one-directional, but the program's keep/revert bar is the pairwise. Recommend a small
     authorized run: **v17+rewrite vs gold, n=3, the 9 golds** — the open question is whether the
     now-clean grounded read converts the pairwise losses to ties/wins. Expectation from the prose
     read: yes for protagonist + collective songs; the residual risk is the judge rewarding gold's
     specific *turns* the rewrite preserves but doesn't add.
  2. **Productionize the pass** — it currently lives in `scripts/`. The cutover needs it in the prod
     generation path (`song-analysis.ts`), wired after the v17 generation, with the same tier1 rules
     as the in-pipeline gate. That is a prod-pipeline change (the Session-6 panel swap already
     touches this file), still the human's call.
  3. **Grounding was not independently re-judged** post-rewrite. The pass only recasts existing
     sentences (verified: no new facts in the diffs), so grounding should be inherited from v17's
     100% — but the productionization run should include the grounding judge as a gate, cheaply.
- **Residual risks named:** the `participial-closure` adjective-in-a-list false-positive (cosmetic,
  ~1/9 reads, leaves a HIGH that isn't a real tell — fix the rule or accept); the minor framing-word
  drop when an antithesis pivot is killed; and Flash's intermittent "could not parse" generation drops
  (the ship-check retries 3×; prod needs the same).

**Bottom line:** prompt iteration stays converged at v17 (do not reopen it). The lever the last two
rounds pointed at is now **built, measured, and content-safe**. The remaining gate to a true GO is one
user-authorized paid pairwise + the prod wiring — not more research.

# ROUND 3b — the paid arbiter VERDICT on the rewrite pass (2026-06-07, user-authorized)

Ran the deferred Opus pairwise. **Matched within-run design** (`scripts/voice-audit/pairwise-rewrite.ts`):
for each gold, the newest-3 real v17 flash reads were judged RAW vs gold AND after the rewrite pass vs
gold — same candidates both sides, so the only variable is the rewrite. n=3 × 9 golds = **54 pairs**,
Opus judge both orders, ~$5 spend. Two artifacts: `eval-artifacts/{v17-raw-matched,v17-rewrite-matched}.json`.

## Result — the rewrite buys ZERO pairwise conversions

| variant (matched, vs gold) | W/T/L | win+tie | songs success |
|---|---|---|---|
| v17 raw | **0 / 0 / 27** | **0%** | 0/9 |
| v17 + rewrite | **0 / 0 / 27** | **0%** | 0/9 |

The rewrite drove tier1 HIGH → 0 on nearly every read (a few residuals: one motion-sickness read
5→5, the no-sex-for-ben / beautiful-things `participial` false-positive →1) and **converted not one
loss to a tie**. This REPRODUCES the established v17-raw flash floor (0/27, `v17-base.json`) and proves
the rewrite's effect on the pairwise-vs-gold metric is **nil**. The register tells were never why v17
loses to gold.

## Why gold wins (judge rationales) — three gap classes, only one is register

- **(a) Residual register the rewrite did not catch** — because it is MEDIUM or UNGATED, outside the
  HIGH set the rewrite targets: **puffery** ("profound anxiety," "profound terror" — `profound` is a
  *medium* rule, untouched), **data-speak** ("low energy and valence" — no tier1 rule at all), and
  **book-report openers tier1 misses** ("The song grapples with," "The song is a public trial" — the
  `book-report-opener` list only has "This song is," not "The song…"). Fixable by broadening the
  rewrite's target set + the tier1 lists — but not the main event.
- **(b) Depth / specific noticing the rewrite STRUCTURALLY cannot add** — gold notices: "in a band
  the year she was born," "church camp," the "one, two, three, freeze" drop, "The regret does not
  leave. It becomes a vow," "silence as the grief he allows." A surgical register rewrite rephrases;
  it cannot invent insight or surface a detail the draft never had.
- **(c) Correctness / grounding errors the rewrite faithfully PRESERVES** — v17 misreads
  pink-pony-club as "a Midwest hometown" (it is Tennessee/the South), invents "a bell for help that no
  one answers" on as-it-was, asserts a wrong "reggaeton beat" on dtmf. These are generation defects;
  the rewrite carries them through unchanged.

# READINESS CALL — CORRECTED to NO-GO vs the gold bar (supersedes Round-3's "conditional GO")

My Round-3 "conditional GO" was premised on the pairwise being likely to convert. **It does not — 0/54,
confirmed by the program's official arbiter.** Correcting the call honestly:

- **Against the optimization contract (tie/win the majority vs gold): NO-GO.** Neither v17 nor
  v17+rewrite ties a single gold across 54 pairs. The rewrite is a real, content-safe engineering
  artifact (cleans tier1, preserves grounding — proven), but it does **not** close the gap to gold,
  because the gap is depth + correctness (b, c), not register. This re-confirms, now against the paid
  judge, the rounds 1–2 diagnosis. **v17 prompt stays converged; do not reopen it.**
- **What the rewrite IS good for is a different question this run did NOT test:** is v17+rewrite better
  than **v13 (current prod)**? The free ship check (Round 3) said yes on cleanliness + grounding — but
  the judge was never asked v17+rewrite-vs-v13 head-to-head, and the (c) rationales surface real v17
  misread/data-speak risks that temper it. **If the goal is "upgrade v13," the decision-relevant test
  is v17+rewrite vs v13 directly** (≈$3–4, n=3×9) — NOT vs gold. Recommended before any cutover, but
  not run here (separate authorization).
- **If anyone still wants to chase the gold bar** (out of scope per "don't grind"): the only levers
  left are non-register — add insight/correctness at generation (gold-dense few-shot, fine-tune, or a
  stronger model: pro hit the ceiling at 17%/1-of-8, length-driven), plus broaden the rewrite to (a)
  medium+ungated tells. None is a prompt edit; all were already flagged as the heavy lifts.

**Bottom line:** the rewrite pass works exactly as designed and is the right tool for "ship clean,
grounded reads" — but the paid arbiter is unambiguous that it does not make v17 rival the golds. The
honest program verdict is **NO-GO on matching gold**; the live product decision (upgrade v13?) is a
separate, cheaper head-to-head that remains open.

# ROUND 4 — the user's "anti-pivot formulation" (H11–H13, 2026-06-08, user-directed)

> **TL;DR (Round 4):** The user's specific anti-pivot formulation was tested in full — both halves —
> against the gold bar. **Generation half (v29):** does not reduce the pivot (≈v17, free). **Rewrite
> half (direct-assertion: delete A + strengthen B + `<master_prompt_override_style_guide>` XML):**
> removes the pivot cleanly with no drift, but the paid Opus arbiter scores it **0/27 vs gold — zero
> conversions**, reproducing the v17-raw 0/27 and Round-3b minimal-rewrite 0/54 floors. The XML wrapper
> changed nothing measurable. **NO-GO on matching gold, consistent with Rounds 1–3b: the gap is depth +
> correctness + ungated/MEDIUM residual register, never the HIGH antithesis pivot the idea targets.**
> v17 stays the converged prompt. v30 (XML-on-generation) is built + shelved for a later probe. The
> recommendation block is at the END of this round's rows.


User handed over a specific anti-pivot formulation to try (a positive-menu generation instruction +
a "Direct Assertion: Eliminate Dismissive Comparisons" rewrite block the author "runs all generated
text through," with a commenter note that the block "works even better enclosed in
`<master_prompt_override_style_guide>…</…>` XML tags"). Opus pairwise authorized. The idea has two
halves; mapped onto this pipeline they are NOT equally novel, and one is substantially what Round 3
already tested:

- **Generation half** ≈ prior v23/v24/v27, but no prior variant handed the model the author's
  POSITIVE MENU of constructions to reach for ("more importantly it needs better examples to
  follow"). Built as **v29**.
- **Rewrite half** ("Delete Statement A entirely") is substantially what the Round-3 rewrite pass
  ALREADY does — its `antithesis` recipe literally says "drop the negated setup entirely." The one
  untested divergence is the author's **"strengthen Statement B to stand alone powerfully"** vs the
  existing pass's deliberate "change as little as possible," plus the **XML wrapper**. Built as the
  rewrite-pass **`direct-assertion` mode** (delete-and-strengthen + `<master_prompt_override_style_guide>`
  tags), constrained to grounded detail already in the read so it cannot hallucinate.

**What was built (all green: typecheck clean, `bun run test scripts/voice-audit/__tests__` 163/163):**
- `lyrical-v29.ts` — v17 + ONE edit: the anti-pivot caution replaced by the positive menu (direct
  definition / image-embodiment / cause→effect / situational / small scene) + v27-style category-level
  naming (no concrete pivot string → no priming) + the author's rationale. The author's hard
  `not/but/just` token-ban was NOT copied (v20 proved it primes + would flag the golds' legit
  contrasts); the ad-copy "benefit-oriented" framing dropped as wrong register. Registered "29".
- `rewrite/rewrite-pass.ts` — added `mode: "minimal" | "direct-assertion"` (default `minimal` is
  byte-identical → Round-3b validity + the 6 existing tests preserved). `direct-assertion` deletes
  Statement A, lets B stand alone strengthened from EXISTING grounded detail, and wraps the corrective
  guidance in the commenter's XML tags. Only diverges when an antithesis pivot is actually flagged
  (true no-op otherwise). 4 new unit tests lock the mode→recipe wiring.
- `lyrical-v30.ts` — **H13, the user-requested "mix":** v29's positive-menu generation × the XML
  `<master_prompt_override_style_guide>` wrapper applied to the GENERATION side. Registered "30". Built
  FOR A LATER ROUND — not generated/judged in this pass.
- Harness: `pairwise-direct-assertion.ts` (matched Opus pairwise, version-parameterized),
  `rewrite-mode-compare.ts` (free minimal-vs-direct-assertion prose/drift read). v29/v30 wired into
  `verify-variants.ts` + `analyze-smoke.ts`.

## H11 — v29: positive-menu generation. FREE smoke (flash n=3 × 9 golds, t0.3, this-session v17 control)

| version | antith/c | % w/pivot | book-report/c | self-ref/c | Σhigh/c |
|---|---|---|---|---|---|
| v17 (control) | **0.23** | 19% | 0.00 | 0.00 | 3.00 |
| v29 | 0.30 | 26% | 0.11 | 0.11 | 3.00 |

- **Result:** v29 does NOT reduce the pivot — flat-to-slightly-WORSE (0.30 vs 0.23, within n~27 noise)
  and adds a little book-report-opener + self-reference v17 didn't have. This reproduces the Round-2
  META-FINDING exactly: the positive-menu generation lever lands ≈v17 on the pivot rate. The author's
  "better examples to follow" does not lower the rate on Flash.
- **Keep/revert:** **REVERT.** v29 in-tree as the record; ACTIVE untouched (17).

## H12 — direct-assertion rewrite (delete-and-strengthen + XML). FREE mode-compare, then PAID arbiter

**FREE mode-compare** (`rewrite-mode-compare.ts`, 4 dirtiest v17 reads, minimal vs direct-assertion on
the SAME reads):

| across 4 reads | antithesis | Σ HIGH | puffery | words |
|---|---|---|---|---|
| BEFORE (raw v17) | 7 | 24 | 2 | 1051 |
| minimal rewrite | 0 | 0 | 1 | 1020 |
| direct-assertion | 0 | 0 | 1 | 1022 |

- **The decisive free finding:** direct-assertion removes the pivot with NO drift (puffery flat, length
  flat, no hallucination — grounded quotes preserved), but its output is **nearly identical to the
  minimal recast**. "Strengthen B to stand alone" never manifests as materially stronger prose: there
  is no grounded material to strengthen *with*, so both modes just delete the `not just X` setup and
  keep B. This is Round-3b finding (b) — a surgical rewrite cannot invent depth — made visible. The XML
  wrapper did not change the behavior.
- **PAID arbiter (matched, v17 base, Opus, n=3 × 9 golds):** `pairwise-direct-assertion.ts --version 17
  --limit 3`. Same candidates judged RAW vs gold AND +direct-assertion vs gold. Reference floors:
  v17-raw 0/27 (`v17-base.json`), v17+minimal-rewrite 0/54 (Round 3b).

  **PAID RESULT (Opus, $5.30, 2026-06-08) — the author's rewrite buys ZERO conversions:**

  | matched, vs gold | W/T/L | win+tie | songs success |
  |---|---|---|---|
  | v17 raw | **0 / 0 / 27** | **0%** | 0/9 |
  | v17 + direct-assertion (delete+strengthen+XML) | **0 / 0 / 27** | **0%** | 0/9 |

  The direct-assertion pass drove tier1 HIGH → 0 on nearly every read (lone residual: not-like-us
  5→1, the known `participial` adjective-in-a-list false-positive) and **converted not one loss to a
  tie**. This reproduces the v17-raw flash floor (0/27) AND Round-3b's v17+minimal-rewrite result
  (0/54) — the author's "delete Statement A + strengthen Statement B to stand alone + XML wrapper"
  buys nothing the minimal recast didn't, exactly as the free mode-compare predicted (its output ≈
  minimal). Artifacts: `eval-artifacts/{v17-raw-matched,v17-direct-assertion-matched}.json`.

  **Why gold still wins (Opus rationales) — the same three gap-classes as Round 3b, none is the pivot:**
  - **(a) Residual UNGATED / MEDIUM register the pass cannot reach:** book-report framing tier1 misses
    ("This is a public execution"), **data-speak** ("low-valence aggression"), a soft-pivot form the
    antithesis rule doesn't catch ("should be pure joy, but instead a gnawing terror"), and **puffery**
    ("deepest fear" — a MEDIUM). The delete-and-strengthen pass only removes what tier1 flags HIGH.
  - **(b) Depth / specific noticing the rewrite STRUCTURALLY cannot add** — the decisive case:
    **as-it-was scored tier1 HIGH=0 and still LOST**, because the candidate is "abstract and academic,
    fitting any song" while gold names "his goddaughter calls every night," "father, alone since the
    divorce." "Strengthen B" had no grounded depth to strengthen *with*.
  - **(c) Correctness** — preserved misreads carry through unchanged (the pass recasts, never re-grounds).
- **Keep/revert:** **REVERT** as a gold-rivaling lever. The `direct-assertion` mode stays in-tree as a
  validated, content-safe rewrite option (cleans tier1 as well as minimal, zero drift — an equal
  alternative to minimal, not a better one); v29 stays registered as the record. ACTIVE untouched (17).

## H13 — v30: the "mix" (positive-menu generation × XML wrapper). BUILT, not run

- v30 = v29 × the `<master_prompt_override_style_guide>` wrapper on the generation guidance. Registered
  + diff-verified (+568 chars vs v17, distinct from all 7 other variants). Deferred to a later round
  per the user; the open question it probes is purely whether the XML delimiter improves Gemini's
  adherence at generation (v29's menu already free-smoked ≈v17, so the wrapper is the only new lever).

# ROUND 4 — RECOMMENDATION

**The user's anti-pivot idea is well-constructed and now fully measured; it does not move the gold bar.**

1. **Prompt iteration stays converged at v17 — do not reopen it.** v29 (positive-menu generation) did
   not reduce the pivot; v17 remains the best prompt, as it has since Round 1. v29/v30 stay in-tree as
   the record.
2. **The author's diagnosis is half-right, and the missing half is the whole ballgame.** The pivot IS
   the most visible AI tell, and deleting it (the author's instinct) is correct cleanup. But the
   antithesis pivot was never *why* v17 loses to gold — proven four times now (Round 3b minimal-rewrite
   0/54; Round 4 direct-assertion 0/27, including a tier1-perfectly-clean read that still lost). Gold
   wins on **specific noticing + depth + correctness**, plus residual MEDIUM/ungated register
   (data-speak, puffery, "should-be-X-but-Y" soft-pivots) that neither rewrite targets. A surgical
   register rewrite — minimal OR delete-and-strengthen — cannot invent the detail a draft never had.
3. **The XML wrapper is a no-op here.** On both the free mode-compare and the paid pairwise it changed
   nothing; it neither helped nor hurt. (It may still matter on the *generation* side — that is exactly
   what v30 is shelved to probe — but the rewrite-side claim does not reproduce.)
4. **What the direct-assertion mode IS good for:** it is a validated, content-safe register cleaner,
   equal to the existing minimal pass (tier1 → 0, zero puffery/length/grounding drift). If anything,
   prefer it as the default rewrite recipe only if a future read shows minimal leaving a framing-word
   stub; otherwise the two are interchangeable. It is NOT a reason to revisit the gold verdict.
5. **CORRECTION — prod already ships v17 (raw).** Rounds 1–3b repeatedly say "prod ships v13"; that is
   STALE. `ACTIVE_LYRICAL_VERSION = "17"` and `song-analysis.ts` has no rewrite-pass call, so production
   runs **v17 raw generation, no rewrite pass** (the Session-6 cutover landed: commits 7e7b6ae /
   8c77cfa). The old "upgrade v13 → v17" product decision is DONE.
6. **The genuinely open, decision-relevant questions (all OUT of this idea's scope):**
   - **Add the rewrite pass on top of the already-live v17 (v17-raw vs v17+rewrite), head-to-head** —
     the real remaining product decision, NOT "beat v13." The rewrite buys tier1-cleanliness + register
     polish with no grounding loss (free ship-check, Round 3); it does NOT rival gold (0/54, 0/27). So
     this is a "ship cleaner reads at +1 Flash call/song" call, decided on latency/cost/taste — never
     paid-judged head-to-head vs raw v17 directly. `direct-assertion` and `minimal` are interchangeable
     for it.
   - **Depth/correctness at generation** — gold-dense few-shot, fine-tune, or a stronger model — the
     only levers that can close gap-classes (b) and (c). None is a prompt edit.
   - **v30 (XML-on-generation)** — a cheap free smoke if the user wants to close the "does the XML tag
     help at generation" loop; v29's ≈v17 result predicts little, but it is the one untried corner.

**Bottom line for the user:** your formulation was tested exactly as written (both halves, with the XML
tags), against the program's official arbiter. It cleanly removes the pivot — but the pivot is not the
wall. v17+direct-assertion ties zero golds, same as v17-raw and the existing rewrite. The wall is depth
and correctness, and no prompt-or-rewrite phrasing reaches it. Honest verdict: **NO-GO on matching gold.**
Prod already ships v17 (the converged-best prompt); the one live, separately-decided question left is
whether to add the rewrite pass on top of it for cleaner reads — not a gold-rivaling change.

# ROUND 5 — the eval/prod few-shot DISSONANCE, measured (H14, 2026-06-08)

> **TL;DR (Round 5):** The prior handoff's headline claim — "prod ships v17 with EMPTY `{example}`/`{annotations}`
> while the eval fills them, and injecting the fixed prod pair will pull prod's 5.28 HIGH/read toward the
> eval's ~3.0" — was tested for free (Flash, t0.3) by isolating the `{example}` lever WITH vs WITHOUT on
> the SAME songs. **Half of it is true; the consequential half is FALSE.** TRUE: prod really does run v17
> with both slots empty (verified in source; an incomplete Session-6 cutover, not a token decision). FALSE:
> the example block is NOT why prod looks dirty. On the real prod song population the lever is **−0.07
> HIGH/read (2%, pure noise)** — half the songs improve, half get worse. The handoff's "2.3 gap" was a
> **song-set artifact** (it compared arbitrary user songs against 9 clean golds). **NO-GO on wiring examples
> into prod:** ~940 extra input tokens/call for ~0 tell reduction + occasional severe over-writing (one WITH
> draw hit 15 HIGH). The dissonance is real but the fix is to align the EVAL to prod, not prod to the eval.

## The dissonance — verified in source (not the doc)

- Prod (`content-analysis/pipeline.ts:361-369`) builds `AnalyzeSongInput` with only
  `songId/artist/title/lyrics/audioFeatures/genres/instrumentalness`; it never sets `exampleText`/
  `annotationsBlock`. `grep -rn "exampleText:\|annotationsBlock:" src` → 0 hits. `song-analysis.ts:232-233`
  resolves both v17 slots to `""`. Same template, same temp (0.3). **Prod runs v17 with NO worked example
  and NO annotations.** The harness (`regen.ts:285`) DOES fill them. Confirmed.
- **Intentional or oversight? OVERSIGHT (incomplete Session-6 cutover).** Four convergent proofs:
  (1) `06-block1-implementation-plan.md:168` WP1 "Locked decisions" names a *"Fixed prod pair: Not Like Us
  + Pink Pony Club"* and line 162 says "so eval **and prod** both see … annotations"; (2) the v17 prompt
  body (`lyrical-v17.ts:65`) tells the model "Any worked examples below are other songs … take none of their
  facts" — authored ASSUMING an example is present, so prod's empty slot leaves that instruction dangling;
  (3) the service was purpose-built with optional slots + `?? ""` for a caller to fill (WP1 line 187: "accept
  prebuilt … without changing existing callers"); (4) no doc records a "run raw to save tokens" decision. WP1
  deliberately built the capability while keeping `ACTIVE=13`; the cutover that flipped `ACTIVE=17` (commits
  7e7b6ae/8c77cfa) swapped the panel + version but never added the planned prod-side assembly.

## H14 — the `{example}` lever, isolated WITH vs WITHOUT (Flash, t0.3, n=3, same songs)

New tools (in-tree): `regen.ts --no-injection` (forces empty `{example}`+`{annotations}` to reproduce
TODAY'S prod), and `db-lever-compare.ts` (samples real DB songs, re-gens each WITHOUT vs WITH the fixed
prod pair, holds lyrics/audio/genres identical between arms; prints stored-prod tier1 as reference). Both at
prod settings (8k out for the DB tool; regen's historical 4k for the harness). The eval/regen default is
WITH examples; prod is WITHOUT — so "WITHOUT" is the prod-faithful arm.

**Arm 1 — 5 clean non-gold harness songs** (`regen --songs ribs,forever,gods-plan,houdini,thinkin-bout-you`):

| arm | overall HIGH/read |
|---|---|
| WITH (fixed pair NLU+PPC) | **2.33** |
| WITHOUT (today's prod) | **3.67** |

→ lever **−1.34 HIGH/read (−37%)**, 4 of 5 songs improve. On clean mainstream tracks examples DO help.

**Arm 2 — 10 songs sampled from the REAL prod population** (`db-lever-compare --n 10 --runs 3`):

| arm | HIGH/read |
|---|---|
| stored prod reads (n=1/song, literal live output) | 4.80 |
| re-gen WITHOUT examples (reproduces today's prod) | **3.97** |
| re-gen WITH fixed-pair examples (planned prod) | **3.90** |

→ lever **−0.07 HIGH/read (2%, noise)**. Per-song split: Feid −3.3, Beautiful Things −2.0, How Do I Breathe
−1.0, Blinding Lights −0.3, Under The Influence 0.0, Let Me Love You +0.3, Thinkin Bout You +0.6, Manchild
+1.0, Gracie Abrams +1.3, Too Sweet +2.7 (one WITH draw = **15 HIGH** — examples can trigger severe
over-writing, mimicking the rich gold prose). Per-rule WITHOUT→WITH: participial-closure 3.33→2.93 (small
help), but self-reference 0.50→0.67 and antithesis 0.10→0.27 (worse) — a wash. Cross-check: Thinkin Bout
You appears in both tools and both agree (WITH ~3.3), validating the implementation.

## Why the handoff was wrong about the consequence

The "~2.3 gap" was **DB-population (5.28) vs 9-clean-golds-WITH-examples (3.0)** — two DIFFERENT song sets.
That gap is the song set (real user songs include remixes, features, Spanish-language, thin pop), not the
example block. When you isolate the lever on the SAME songs it nearly vanishes on the population. Secondary
note: the prod-faithful WITHOUT re-gen (3.97, n=3) sits below the single-draw baseline (5.28, n=1/song),
i.e. prod's expected per-song tell rate is ~4, with the 5.28 inflated by unlucky single draws.

## Keep/revert

- **REVERT (do not ship): wiring `{example}` into the prod pipeline.** −0.07 HIGH/read on the population is
  not worth ~940 input tokens/call + added variance/outlier risk; and Round 4 already showed examples don't
  rival gold either. ACTIVE untouched (17); prod path UNEDITED (no approval sought — the data says don't).
- **KEEP (in-tree tools):** `db-lever-compare.ts`, `regen.ts --no-injection`. The `--no-injection` arm is
  now the **prod-faithful** way to read tier1 numbers.

## Recommendation

1. **Examples → prod: NO-GO.** No measurable tell benefit on the real population; recurring token/latency
   cost; occasional 15-HIGH blow-ups. Do not wire it.
2. **Resolve the dissonance by aligning the EVAL to prod, not prod to the eval.** The eval's default
   `regen`/tier1 numbers are WITH examples and run ~1 HIGH/read optimistic vs prod on clean songs (≈equal on
   the population). For prod-representative tier1, use `regen --no-injection`. The Round-4 NO-GO-vs-gold
   verdict stands regardless — it was measured WITH examples and still lost 0/27; WITHOUT is not better.
   (Any future PAID pairwise that wants to describe prod must run the WITHOUT arm.)
3. **`{annotations}` is a SEPARATE, unmeasured lever** (grounding, the program's GRD #1 gate — the frontier
   Round 4 says gold wins on). Not tested here (empty in both arms). Feasible in prod (`grounding-annotations.ts`
   + `ensureAnnotationDistillations` exist) but a larger change, and gated by sparse >15-vote Genius
   annotation coverage on real songs. Measure it on its own before considering wiring.
4. **If the goal is "ship cleaner prod reads," the lever is the REWRITE PASS, not examples** (see Round 5b).

# ROUND 5b — the REWRITE PASS on the real prod population (H15, 2026-06-08)

> **TL;DR (Round 5b):** With examples ruled out (Round 5), the rewrite pass is the sole proven tier1
> cleaner — so it was measured on the REAL population for the first time (prior rounds only ran it on
> golds/dirtiest reads). New tool `db-rewrite-compare.ts` runs `rewriteRead()` (Flash, minimal mode)
> over all 58 stored v17 reads. Result: **5.28 → 0.19 HIGH tells/read (96% removed), 0/58 → 52/58 reads
> fully clean (90%), prose length drift −0.4% (faithful), avg 1.12 passes, ~3.4k tokens/read.** The 6
> non-clean are 3 transient LLM errors (retryable) + the known participial false-positive. This is the
> free half of the story (tells removed + mechanical fidelity); the paid half (does NOT rival gold —
> 0/54, 0/27) is unchanged from Rounds 3b/4. **The rewrite makes prod reads sound human; it does not make
> them gold.** Whether to ship it (+1 Flash call/song) is a product cost/taste decision — PROD change,
> needs approval; ACTIVE/prod path untouched here.

## H15 — `db-rewrite-compare.ts --n 58` (minimal mode, Flash, all stored v17 reads)

| metric | before | after |
|---|---|---|
| HIGH tells/read | 5.28 | **0.19** (−5.09, 96% removed) |
| reads fully HIGH-clean | 0/58 | **52/58 (90%)** |
| prose length drift | — | **−0.4%** (≈0 = faithful recast, content invariants pinned in code) |
| passes used (avg) | — | 1.12 / 2 max |
| rewrite cost | — | ~3,434 tokens/read (the +1-call cost) |

Per-HIGH-rule before→after: participial-closure 3.91→0.16, self-reference 1.07→0.03, antithesis 0.22→0.00,
book-report-opener 0.03→0.00, structural-section 0.03→0.00. Residual 0.19 is the known participial
adjective-in-a-list false-positive (e.g. "a single, exhilarating night") + the 3 errored reads.

## The two levers, both measured on the real population (the honest comparison)

| lever | effect on prod tells | cost | verdict |
|---|---|---|---|
| `{example}` few-shot (Round 5) | −0.07 HIGH/read (noise) | ~940 tok/call, +variance | **NO-GO** |
| rewrite pass (Round 5b) | −5.09 HIGH/read (96%) | ~3.4k tok/call (+1 Flash call) | **the real lever** |

## Keep/revert

- **KEEP (in-tree tool):** `db-rewrite-compare.ts`. The free, prod-population way to measure the rewrite.
- **OPEN PRODUCT DECISION (needs approval): add the rewrite pass to the prod pipeline.** It cleans 96% of
  surface tells with no content loss for one cheap call/song. It does NOT close the depth/correctness gap
  to gold (Rounds 3b/4, paid) — it changes how the writing SOUNDS, not how deep/correct it is. So this is
  a "ship more human-sounding reads" call decided on cost/latency/taste, not a gold-rivaling change.
  ACTIVE untouched (17); prod path UNEDITED.

# ROUND 5c — the rewrite pass WIRED INTO PROD (H16, 2026-06-08, user-approved)

> **TL;DR (Round 5c):** The Round-5b open product decision was approved. The post-generation cleanup
> pass (minimal mode) is now wired into the production pipeline. The tier1 rules engine + rewrite pass
> were promoted out of the harness into a prod module (`content-analysis/voice/`) — prod must not import
> `scripts/` — and `song-analysis.ts` now runs the rewrite on every lyrical read before storing it.
> `ACTIVE_LYRICAL_VERSION` stays "17" (this is a PIPELINE change, not a prompt-version change). Existing
> stored rows are untouched until re-enriched; only newly-generated reads get cleaned. Typecheck clean;
> 226/226 tests green (prod content-analysis + harness).

## What changed

- **Promoted to prod** (`src/lib/domains/enrichment/content-analysis/voice/`): `tier1-rules.ts` (was
  `scripts/voice-audit/tier1/rules.ts`), `burstiness.ts`, `rules-types.ts` (new — `RuleHit`/`Severity`,
  the shared rules-engine types), `rewrite-pass.ts` (was `scripts/voice-audit/rewrite/`). The voice-audit
  harness now imports all four from prod (correct dependency direction: harness → prod; scripts already
  import `@/...` everywhere). `scripts/voice-audit/types.ts` re-exports `RuleHit`/`Severity` from prod
  (type-only — erased at compile time, no bundle cost), so the harness's many `from "../types"` importers
  are unchanged.
- **Wired into the pipeline** (`song-analysis.ts`, `analyzeSong`): after lyrical generation and before
  store, `rewriteRead(read, this.llm)` recasts the flagged AI-tell sentences. Instrumental analyses skip
  it (they aren't `SongRead`s). On any rewrite/LLM error `rewriteRead` returns the original read, so the
  cleanup can never block, fail, or corrupt an analysis — it only ever improves or no-ops.
- **Rewrite `maxOutputTokens` 4000 → 8000** (`voice/rewrite-pass.ts`), parity with generation: a rewrite
  returns a full read and had the same ~10%-of-long-reads-truncate risk that caused the 3 transient
  errors in the Round-5b run. So prod's expected cleanup ≥ the measured 96% removed / 90% fully-clean.
- **Regression tests** (`song-analysis.test.ts`): a lyrical read carrying one tell is stored clean (the
  rewrite ran and its output was used); an instrumental analysis calls generation once and skips the
  rewrite. Locks the wiring against silent removal.

## Cost / scope / caveat

- **Cost:** +1 Flash call (~3.4k tokens) per lyrical song at enrichment time. No schema change.
- **Scope:** newly-generated reads only; existing rows unaffected until re-enriched. No `ACTIVE` flip.
- **Caveat (unchanged from 3b/4):** this cleans how the writing SOUNDS (tier1 surface tells −96%); it
  does NOT close the depth/correctness gap to the hand-written golds. That remains a separate, harder
  generation-side problem (gold-dense few-shot / fine-tune / stronger model), not a rewrite or prompt edit.

## Keep/revert

- **KEEP (shipped):** rewrite pass live in prod (minimal mode). Round 5b's "OPEN PRODUCT DECISION" is now
  resolved GO. `direct-assertion` mode stays available as an interchangeable alternative recipe.
- Examples-into-prod remains **REVERTED** (Round 5): not wired, no benefit on the population.

<!-- next rows below -->
