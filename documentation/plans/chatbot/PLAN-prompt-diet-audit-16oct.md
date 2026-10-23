# PLAN: PROMPT-DIET audit of the production parser prompt (16 Oct 2026)

Status: PARKED (crew, 16 Oct ~18:40) until the EVAL-BENCH follow-up slice exists (CP0); crew then measures v112 vs v94
there over 3 runs and the lane resumes only if v112 is not worse. PR #1739 stays open at c06e082bd (dev v112 1de617ac).
Why: on the step 7 pick v112 fell back to outstanding where v94 stayed so_outstanding (history-dependent).
Stages 2-5 HELD for crew's chatbot architecture. Track: deliverable 1 docs only; stage 1 M (see below).

Result: 91 sections, 35,585 tokens today, about 20,435 after the proposed five stages (-43%). Two text bugs
(v94:891-893 vs :900; missing comma v94:765), one dead section (REFERENCE TARGET), two stored-only keys
(`contains_flyer`, `correction`), policy block drifted from the DB (`has_massage`, `purchase_order`).

Lane: PROMPT-DIET (16 Oct), branch `crew/prompt-diet-16oct` off origin/main, its own draft PR. Brief:
`crew/state/briefs/PROMPT-DIET.md`. The older branch `crew/prompt-diet` (draft PR #1568, the 10-11 Oct
"prompt diet measurement record, STOPPED at DP1" spike) is INPUT only: what was measured and why it stopped.

## Why

Owner, 16 Oct, reading the production parser prompt (`chatbot_semantic_parser`, prod v63 = prod v52 + live
`{{find_filters}}`): "very very overloaded ... bloated". Section-by-section doubts: domain_in_message,
teaching rules ("if previous offered X then Y"), message_type / user_goal unused?, attachment types and
access levels hard-coded although the DB has the lists, flyer flag, never-an-entity and pronoun teaching,
broaden axis repeats, positional reference when the user answers with a code, specification block length.

## Source text

Dev `sorento_cagent_stack` v94 (`CHAT-FIND: v91 with the live {{find_filters}} block`); v91 is
`PROD v52 plain (md5 f447ad50)`. v94 differs from v91 by exactly one line (`{{find_filters}}`, v94:1847), so
v94 is the prod v63 text. Crew lanes never read prod or the prod clone, so the prod row itself is not read.
1,849 lines, 140,897 chars, 35,585 tokens (o200k_base) before `{{current_date}}` / `{{find_filters}}` render.

## Deliverable 1 (this plan)

One self-contained HTML page, `documentation/plans/chatbot/PROMPT-DIET-16oct.html`, for Lavish:

1. Every section (91, split at `== X ==` headings and banner titles): lines, tokens, what it tells the model,
   output fields it drives.
2. Code readers of each field, `file:line`, or "unused".
3. Static lists that exist in the DB (attachment types, access levels, spec registry, brands, product
   types, domains) and whether a `chatbot_prompt_vars.py` variable already renders them.
4. Teaching logic the engine already knows deterministically (could be structured context instead).
5. Duplicates / repeats, and each owner doubt answered with evidence.
6. Parser-gold TRAIN items that exercise each section (`items_TRAIN_lane.jsonl` only; never held-out).
7. Verdict per section: KEEP / SHRINK / MAKE DYNAMIC / MOVE TO CONTEXT / DELETE, with risk.
8. Tokens today vs after diet; staged plan (3-5 stages, each its own prompt version, gated by parser-gold
   TRAIN no-drop + crew held-out, cost per stage).

Method: scout subagents read the prompt, the parser schema/consumers, `chatbot_prompt_vars.py` and the TRAIN
file, each writing findings to the session scratchpad; the lead assembles and spot-checks every
`file:line`. Filed as ONE `crew report --ask` with the repo path.

## Later (only after owner annotations)

Each stage is its own PR + unlabelled prompt version; never published or labelled without owner PASS.
No overlap with CHAT-ADVISOR-SPIKE (#1720/#1730/#1731/#1737, F5 `typed_as`).

## Known constraint from 11 Oct (DP1, PR #1568)

The static parser prompt is ~96% served from the provider prompt cache, so token count is not the main
cost driver (`project_prompt_diet_dp1_11oct`). The diet's value is attention / instruction load and
latency, judged by parser-gold pass rate, cost per turn and p95, not tokens alone.

## Owner rulings on the page (16 Oct 16:31, relayed by crew)

- Q1 order: stage 1 first, and "we already had a cut before" (#1574). Q2 attachment types: dynamic, a new variable
  from `attachment_types` (option b). Q3 access levels: dynamic (a). Q4 stage 5 code: allowed (a). Q5 examples:
  trim only 65 (a).

## #1574 (PROMPT-ABLATION) and why prod is still 35.6k

#1574 (merged 11 Oct, 75f142874) cut v50's language teaching with 118 exact cuts
(`scripts/build_parser_ablation.py` CUTS; 37.9k to 34.9k tokens; DEV 82.2% vs 84.1%, hidden 83.2% vs 80.8%).
Its migration `pab_0001_parser_ablation` published the text UNLABELLED (dev v84); the label never moved. Prod
moved along the v50 line instead (v52, then v63 = v52 + `{{find_filters}}`), so 204 of the 235 lines #1574 cut
are still in v91 (dev copy of prod v52). The ablation text is now stale, so it is ported, not labelled.

## Stage 1 (gate PASS 16 Oct; PR #1739, hand test next)

Status: gate PASS on dev v111 (4f48d7a5); hand test, then owner PASS before any label move. Stages 2-5 HELD (crew is
writing the chatbot architecture: fast/slow path, catalogue-constrained parser output, per-domain prompts).
Scope after two crew re-scopes: the #1574 cut port (100 of 118 cuts), the section 43 contradiction fix and the two
missing OUTPUT commas (requested_attributes, asks). REFERENCE TARGET kept: the model emits reference_target with no
marker (107 "dym" verdicts in tests/chatbot/replay_turns) and lanes/business/answer.py:1996 reads it. v109 and v110
were voided builds.

Gate (crew, v111 vs v94): TRAIN 91/90 vs 92/90 (noise); held-out 83/80 vs 79/80; cost per parse $0.00544 vs $0.00620
(-12%); cached-token share 0.971 vs 0.951; same-hour latency not slower. Watch items: G178, G174 (picked_option),
G165 (reference_target lost).

Track: M (prompt text + build script + publish migration), lead pattern.
UAC: `prompt-diet-s1-acceptance-criteria.md`.

- Base: dev v94 stored verbatim as `alembic/data/chatbot_semantic_parser.v94.txt`.
- `scripts/build_parser_diet.py`: v94 -> #1574 CUTS re-applied (100 of 118 match; 18 skipped by id) -> stage-1
  edits (fixes, dead text, banners folded into OUTPUT) -> `alembic/data/chatbot_semantic_parser.diet-s1-20261016.txt`.
- Migration `pdiet_s1_0001`: publishes it unlabelled (pattern of `pab_0001_parser_ablation.py`).
- Gate: lead publishes the text as an unlabelled dev version on `sorento_cagent_stack` (crew ruling (a), 16 Oct);
  crew runs parser-gold TRAIN x2 against today's fresh v94 baseline, then held-out. No label move without owner PASS.
