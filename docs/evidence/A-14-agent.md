---
id: EV-A-14-agent
type: evidence
story: A-14
feature: FEAT-A14
test_cases: [A-14-TC-001, A-14-TC-002, A-14-TC-004, A-14-TC-005, A-14-TC-006, A-14-TC-007, A-14-TC-NF-01]
runtime_url: https://014-agent-and-mcp.d2lx0utip89u18.amplifyapp.com
data_snapshot: bafkreiasycmsr2qdlxqcfg3yc2conpn3jxmohz7gs55hkseipplhpqsk5i
branch: 014-agent-and-mcp
created: 2026-10-25
---

# A-14 agent: golden queries G1 to G6 on the deployed agent (final run)

This file was rewritten from the **final** golden run (`docs/evidence/A-14-golden-results.json`, committed in `95b6370` on 2026-10-25, build `313d628`). The earlier version described the first run (1 pass, 5 fail) and is replaced; the history of the runs is in "How the six queries came to pass" below.

## Read this first: what the six passes prove, and what they do not

All six queries pass the grader on the final build. That is true and it is a weaker statement than it sounds:

- **The run is the small published run, not the full county.** Every request carries `manifest_cid` `bafkreiasycmsr2qdlxqcfg3yc2conpn3jxmohz7gs55hkseipplhpqsk5i` (run `travis-202609-permits-20261021t103516z`: 14 properties, 35 reroof permits). On the full-county runs the agent times out (`docs/decisions/DEC-A-14-agent-mcp-full-county.md`). **These are not full-county results.**
- **G1, G2, G3 and G4 are vacuous.** The oracle (the real query-core function over the same run) returns **0 rows** for each. Precision, recall and groundedness are therefore 100 % of nothing: they show that the agent calls the right tool with the right arguments and invents no property, not that it ranks or cites real rows correctly.
- **G4 and G6 are inconclusive in part.** The golden file expects `empty_reason: field_not_published` (G4) and `out_of_scope` (G6). The oracle cannot express either on this run, so the grader skips that comparison and records it as inconclusive (`emptyReasonInconclusive: true`). It is never counted as a pass of that sub-check.
- **G6 also checks nothing over rows.** It returns zero matches and a plain out-of-scope sentence; the grader's `vacuous` flag is false for it only because its oracle (a geocode) has no row count. The out-of-scope sentence check passed.
- **The `empty_reason` check never looked at the agent's own response.** The agent response has no `empty_reason` field (its keys are `answer, how, steps, matches, query, missing, outcome, modelCalls, outputTokens, durationMs, traceId`). The grader compares the golden file to the **oracle**. Where the golden file says `null` and the oracle returns 0 rows, the expected reason becomes the oracle's own reason, so the comparison is tautological for G1, G2 and G3 (`tests/agent/grader.ts`, `expectedEmptyReason`). What the agent says about emptiness is checked only through the `must_mention` and `must_flag_missing` patterns.
- **G2, G4 and G5 pass partly through deterministic server-side sentences, keyed on the wording of the question.** After the model answers, `apps/api/src/agent/ask.ts` appends fixed sentences when the model did not say the required thing: "BBB status is not available in the published data.", "The contractor name is not printed in the published source (contractor not printed).", "I cannot tell which owners live outside the area: the owner's mailing location is not in the published export.", "I read the open-time threshold as at least N years (>= N years).", and a forced permit-number lookup when the question contains a permit number. The `missing[]` entries for contractor, BBB and out-of-area owner are likewise added from regular expressions on the question text (`asksContractorOrBbb`, `asksOutOfAreaOwner`, `asksVagueDuration`, `permitNumberIn`). That is a **safety net that guarantees honest wording, not model reasoning**, and one of the sentences uses the exact phrase the grader's pattern looks for. The statements are true (the published export carries no contractor name, no BBB status and no owner mailing location), but a pass on these three queries is partly a pass of that code.
- **G5 is the one non-vacuous data case.** The oracle returns 1 row (permit `2026-116568 BP`, the first permit of the bound run, resolved at test start), the answer cites it, and 2 CIDs were checked and found in the run.
- **Not measured here:** the answered form of G1 to G4 over real rows (needs the full county, gap carried to A-16); a run on `AI_PROVIDER=gateway`; the Explore-page leg of the AC-8 comparison.

## Setup

| Item | Value |
| --- | --- |
| Endpoint | `POST https://014-agent-and-mcp.d2lx0utip89u18.amplifyapp.com/api/agent/ask` (Amplify branch preview of `014-agent-and-mcp`, rewrite to the agent API `https://z9f9fmrmr5.execute-api.eu-north-1.amazonaws.com`) |
| Build | `313d628`; results committed in `95b6370` (2026-10-25 17:36 +0300). The run time is not recorded in the results file |
| Provider / model | `AI_PROVIDER=bedrock`, `eu.anthropic.claude-sonnet-4-6` (Bedrock, `eu-north-1`, as configured on the Lambda; the response does not echo it) |
| Gazetteer | `travis-places@1.0.0`, SHA-256 `0f4c08a8bda573737adecc7d62e84d629aadc5005b987f2f787e4fd31ab5d17f` (`packages/query-core/gazetteer/travis-places@1.0.0/DIGEST`). Every `how` string cites "Census 2024 Gazetteer" and the place's internal point; the response carries the name, not the version or hash |
| Pinned run | manifest `bafkreiasycmsr2qdlxqcfg3yc2conpn3jxmohz7gs55hkseipplhpqsk5i` on every request and in the oracle |
| Oracle | the real `searchProperties` / `listPermits` / `geocodePlace` of `@countylens/query-core` over a local DuckDB bound to the same pinned run |
| Command | `AGENT_URL=https://014-agent-and-mcp.d2lx0utip89u18.amplifyapp.com/api GOLDEN_CID_HOST=https://gateway.pinata.cloud npx vitest run` in `tests/agent` |
| Ceilings (AC-5) | at most 3 model calls, 1,500 output tokens, 6 tool steps, 20 s |

## Results

| Case | Outcome | Wall clock | Server duration | Model calls | Output tokens | Tool steps | Groundedness | Correctness | Recall | Honesty | Vacuous | Empty-reason inconclusive | Verdict |
| --- | --- | --- | --- | --- | --- | --- | --- | --- | --- | --- | --- | --- | --- |
| G1 | answered | 8,043 ms | 5,529 ms | 2 | 379 | 2 | PASS (0 CIDs checked) | PASS (0) | PASS (1.00, n=0) | PASS | yes (0 oracle rows) | no | PASS |
| G2 | answered | 5,546 ms | 5,147 ms | 2 | 406 | 2 | PASS (0 CIDs checked) | PASS (0) | PASS (1.00, n=0) | PASS | yes (0 oracle rows) | no | PASS |
| G3 | answered | 4,616 ms | 4,250 ms | 2 | 295 | 2 | PASS (0 CIDs checked) | PASS (0) | PASS (1.00, n=0) | PASS | yes (0 oracle rows) | no | PASS |
| G4 | answered | 6,456 ms | 6,107 ms | 2 | 514 | 2 | PASS (0 CIDs checked) | PASS (0) | PASS (1.00, n=0) | PASS | yes (0 oracle rows) | yes | PASS |
| G5 | answered | 4,381 ms | 4,044 ms | 2 | 264 | 2 | PASS (2 CIDs checked) | PASS (2) | PASS (1.00, n=1) | PASS | no | no | PASS |
| G6 | answered | 2,984 ms | 2,660 ms | 2 | 127 | 2 | PASS (0 CIDs checked) | PASS (0) | PASS (1.00, n=0) | PASS | no | yes | PASS |

Budget (all six pass): model calls 2 to 2 (ceiling 3); output tokens 127 to 514 (ceiling 1,500); tool steps at most 2 (ceiling 6). The "steps" figure counts the final text-only step (`tool` empty), so each case made one tool call plus the final text step.

Wall clock (client side, includes network and CloudFront): minimum 2,984 ms, maximum 8,043 ms. With six runs the nearest-rank p95 is the maximum, 8,043 ms, against a 20,000 ms limit. This is six requests on a small run; it says nothing about full-county latency, where the agent times out. G2 is two turns; its figures are for the second turn.

Model calls, output tokens, server duration and trace id are read from the response itself (the fields `modelCalls`, `outputTokens`, `durationMs`, `traceId`, added to answer ERR-63). The "request id" is the `x-amzn-requestid` / CloudFront header of the HTTP response.

## Per case


### G1

- Prompt: Which properties in Travis County within five miles of Pflugerville have roofs older than 15 years?
- Outcome `answered`; wall clock 8,043 ms; server duration 5,529 ms; 2 model calls; 379 output tokens
- Trace id (X-Ray, agent Lambda): `1-6ade1345-793e0d21439e81f03e41d68c`; request id `tyFB8TK-Id_LrUR7IcF2PgkNcwckfQM8x_FsV2edNunFBripHZ5M5Q==`
- Tool calls: `searchProperties` {"area": {"place": "Pflugerville"}, "radius_mi": 5, "roof_age_years_min": 15, "sort": "roof_desc", "limit": 50}
- Oracle: rows 0, total 0, empty_reason no_match
- Vacuous: yes (0 oracle rows); empty-reason check inconclusive: no
- Groundedness: PASS (0 CIDs checked); correctness: PASS (0 rows checked); recall: PASS (1.00, n=0); honesty: PASS
- `how`: Pflugerville city · Census 2024 Gazetteer · 30.447765, -97.602116; radius_mi: 5; roof_age_years_min: 15; sort: "roof_desc"; limit: 50
- `missing`: `[{"field": "result", "reason": "no_match"}]`
- `matches`: 0 row(s)
- Answer (verbatim):

  > The search returned **no matches** using the following exact filters:
  >
  > - **Area:** Pflugerville (centered at ~30.448°N, 97.602°W)
  > - **Radius:** 5 miles
  > - **Minimum roof age:** 15 years
  > - **Rows excluded due to unknown roof age:** 0
  >
  > The tool confirms this is a genuine **no-match** result (`empty_reason: no_match`), and no rows were excluded due to missing roof age data — meaning no properties within 5 miles of Pflugerville in the published dataset have a recorded roof age of 15 years or older.
  >
  > A few possible explanations:
  > - Roof age data may not be populated for properties in this area of the dataset.
  > - Properties in this corridor may have had roof replacements recorded within the last 15 years.
  >
  > Would you like me to try a **lower roof age threshold** (e.g., 10 years), a **wider radius**, or search for **open/stalled roofing permits** near Pflugerville instead?

### G2

- Prompt: Which properties near that area have open roofing permits that have been open for many years, and who is the listed contractor?
- Outcome `answered`; wall clock 5,546 ms; server duration 5,147 ms; 2 model calls; 406 output tokens
- Trace id (X-Ray, agent Lambda): `1-6ade137a-48619d7665fe3ce957032bd4`; request id `I8u18sS6HDL12nMjxP-wiZEY9bpqRyXvCvod0NRLp2m0-VfLcWcBVg==`
- Tool calls: `searchProperties` {"area": {"place": "Pflugerville"}, "radius_mi": 5, "status_class": "open", "open_years_min": 5, "sort": "open_desc", "limit": 50}
- Oracle: rows 0, total 0, empty_reason no_match
- Vacuous: yes (0 oracle rows); empty-reason check inconclusive: no
- Groundedness: PASS (0 CIDs checked); correctness: PASS (0 rows checked); recall: PASS (1.00, n=0); honesty: PASS
- `how`: Pflugerville city · Census 2024 Gazetteer · 30.447765, -97.602116; radius_mi: 5; status_class: "open"; open_years_min: 5; sort: "open_desc"; limit: 50; permits open at least 5 years
- `missing`: `[{"field": "result", "reason": "no_match"}, {"field": "contractor.name_as_printed", "reason": "no_lexicon_carrier"}, {"field": "bbb_status", "reason": "no_lexicon_carrier"}]`
- `matches`: 0 row(s)
- Answer (verbatim):

  > No properties matched those filters. Here's a plain summary:
  >
  > **Result: No matches found.**
  >
  > - **Area:** Pflugerville (5-mile radius, same as before)
  > - **Filter applied:** Roofing permits with status **open**, open for **at least 5 years** ("many years" = open_years_min 5)
  > - **Why no results:** The tool confirmed `no_match` — meaning there are simply no properties within 5 miles of Pflugerville that currently have an open (not stalled, not closed) roofing permit that has been open for 5+ years.
  >
  > A couple of notes:
  > - **Contractor names are not available** in the published data export, so even if matches had been found, I would not be able to report the listed contractor.
  > - If you'd like to broaden the search (e.g., include *stalled* permits, reduce the years threshold, or widen the radius), just let me know! BBB status is not available in the published data. The contractor name is not printed in the published source (contractor not printed).

### G3

- Prompt: Show me open roofing permits older than five years within five miles of Manor
- Outcome `answered`; wall clock 4,616 ms; server duration 4,250 ms; 2 model calls; 295 output tokens
- Trace id (X-Ray, agent Lambda): `1-6ade1394-69c5cae16f0626077be89f27`; request id `eUEW-TovmvIMB6Xb2_yHS1NM5_ayv-HMvMRxhTtWaD0dooANo6JGFg==`
- Tool calls: `searchRoofingPermits` {"area": {"place": "Manor"}, "radius_mi": 5, "status_class": "open", "open_years_min": 5, "sort": "open_desc", "limit": 50}
- Oracle: rows 0, total 0, empty_reason no_match
- Vacuous: yes (0 oracle rows); empty-reason check inconclusive: no
- Groundedness: PASS (0 CIDs checked); correctness: PASS (0 rows checked); recall: PASS (1.00, n=0); honesty: PASS
- `how`: Manor city · Census 2024 Gazetteer · 30.354228, -97.558259; radius_mi: 5; status_class: "open"; open_years_min: 5; sort: "open_desc"; limit: 50; permits open at least 5 years
- `missing`: `[{"field": "result", "reason": "no_match"}]`
- `matches`: 0 row(s)
- Answer (verbatim):

  > No results were found matching your filters. Here's a summary of what was searched:
  >
  > - **Area:** Manor city (centered at 30.354228, -97.558259)
  > - **Radius:** 5 miles
  > - **Status:** Open permits only
  > - **Minimum age:** 5+ years open
  >
  > There are **zero open roofing permits** that have been open for more than 5 years within 5 miles of Manor. No rows were excluded due to unknown values, so this appears to be a genuine absence of matches under these exact criteria.
  >
  > You could try broadening the search — for example, including **stalled** permits (open_or_stalled), reducing the open-years threshold, or increasing the radius — if you'd like to see more results.

### G4

- Prompt: Which homes near Lakeway haven't changed owners in 10+ years and have owners outside the area?
- Outcome `answered`; wall clock 6,456 ms; server duration 6,107 ms; 2 model calls; 514 output tokens
- Trace id (X-Ray, agent Lambda): `1-6ade13ac-4c917f31691e48aa6cf3c8c5`; request id `3OkAH0w_urzm6Y41gK4Dem2RM6WYF1oyGEaoNEId0JT4ZMiznTLH6w==`
- Tool calls: `searchProperties` {"area": {"place": "Lakeway"}, "radius_mi": 5, "tenure_years_min": 10, "sort": "nearest", "limit": 50}
- Oracle: rows 0, total 0, empty_reason no_match
- Vacuous: yes (0 oracle rows); empty-reason check inconclusive: yes
- Groundedness: PASS (0 CIDs checked); correctness: PASS (0 rows checked); recall: PASS (1.00, n=0); honesty: PASS
- `how`: Lakeway city · Census 2024 Gazetteer · 30.354982, -97.986269; radius_mi: 5; tenure_years_min: 10; sort: "nearest"; limit: 50
- `missing`: `[{"field": "result", "reason": "no_match"}, {"field": "owner_is_out_of_area", "reason": "not_in_export"}]`
- `matches`: 0 row(s)
- Answer (verbatim):

  > Here's what I found — and an important limitation to flag:
  >
  > ---
  >
  > ### Results: Homes near Lakeway with 10+ Years Same Owner
  >
  > **0 matches returned** from a 5-mile radius search around Lakeway with `tenure_years_min: 10`.
  >
  > - **`empty_reason: no_match`** — meaning the search was in scope and executed correctly, but no properties met the criteria within that radius.
  > - **`unknown_excluded: 0`** — no properties were dropped due to unknown tenure data, so this is a clean zero result under those filters.
  >
  > ---
  >
  > ### On "Owners Outside the Area"
  >
  > ⚠️ **Owner mailing address / ZIP is not in the published export.** I cannot identify which owners live outside the area — this data simply isn't available in the dataset. Even if matches had been returned, I would not be able to filter or flag out-of-area owners.
  >
  > ---
  >
  > ### Summary
  >
  > | Filter | Value |
  > |---|---|
  > | Area | Lakeway (5-mile radius) |
  > | Tenure (same owner) | 10+ years |
  > | Out-of-area owner | ❌ Not available in published data |
  > | Matches | **0** |
  >
  > You may want to try:
  > - A **wider radius** (e.g., 10 miles)
  > - A **lower tenure threshold** (e.g., 5 years)
  >
  > Just let me know how you'd like to adjust!

### G5

- Prompt: What's the BBB rating of the contractor on permit {real permit number}?
- Outcome `answered`; wall clock 4,381 ms; server duration 4,044 ms; 2 model calls; 264 output tokens
- Trace id (X-Ray, agent Lambda): `1-6ade13c7-3530e79a1d17c284314913a5`; request id `BjwimpRa6xKq6MX87c0KRI513XpFJCz_U6-7kdAGHsad3tN__Tz0MA==`
- Tool calls: `searchRoofingPermits` {"permit_number": "2026-116568 BP", "sort": "open_desc", "limit": 50}
- Oracle: rows 1, total 1, empty_reason none
- Vacuous: no; empty-reason check inconclusive: no
- Groundedness: PASS (2 CIDs checked); correctness: PASS (2 rows checked); recall: PASS (1.00, n=1); honesty: PASS
- `how`: permit_number: "2026-116568 BP"; sort: "open_desc"; limit: 50
- `missing`: `[{"field": "status_raw", "reason": "no_lexicon_carrier"}, {"field": "expiry_date", "reason": "no_lexicon_carrier"}, {"field": "final_date", "reason": "not_closed"}, {"field": "permit_close_date", "reason": "source_missing"}, {"field": "final_inspection_date", "reason": "source_missing"}, {"field": "contractor_company_cid", "reason": "contractor_unresolved"}, {"field": "contractor.name_as_printed", "reason": "no_lexicon_carrier"}, {"field": "bbb_status", "reason": "no_lexicon_carrier"}, {"field": "bbb_url", "reason": "no_lexicon_carrier"}, {"field": "description", "reason": "no_lexicon_carrier"}, {"field": "work_class_raw", "reason": "no_lexicon_carrier"}, {"field": "bbb_status", "reason": "contractor_unresolved"}]`
- `matches`: 1 row(s)
- Answer (verbatim):

  > I found permit **2026-116568 BP** [1], but I'm unable to provide a BBB rating for two reasons:
  >
  > 1. **Contractor name not available:** The published data export shows the contractor as **unresolved** for this permit [1], so the specific contractor cannot be identified.
  > 2. **BBB ratings are not published:** Even if the contractor were identified, BBB ratings are not included in the published data export — they are not available through this system.
  >
  > Here's what I *can* share about the permit [1]:
  > - **Status:** Open
  > - **Days Open:** 47
  > - **Open Years:** ~0.13
  >
  > For BBB rating information, you'd need to look up the contractor directly on [bbb.org](https://www.bbb.org) once you've identified them through the permit authority. BBB status is not available in the published data. The contractor name is not printed in the published source (contractor not printed).

### G6

- Prompt: How many properties have roofs older than 40 years in ZIP 99999?
- Outcome `answered`; wall clock 2,984 ms; server duration 2,660 ms; 2 model calls; 127 output tokens
- Trace id (X-Ray, agent Lambda): `1-6ade13df-2195dac843e69a0047b832e6`; request id `fpmQ8v-zPR3XgF2vQKhDmFw-UymFj0vE88rQ4srCbFnAcAt8prkqhA==`
- Tool calls: `geocodePlace` {"query": "99999"}
- Oracle: rows not applicable (geocode oracle), total not applicable, empty_reason none
- Vacuous: no; empty-reason check inconclusive: yes
- Groundedness: PASS (0 CIDs checked); correctness: PASS (0 rows checked); recall: PASS (1.00, n=0); honesty: PASS
- Out-of-scope check: PASS (has matches: False, CID in prose: False)
- `how`: (empty)
- `missing`: `[]`
- `matches`: 0 row(s)
- Answer (verbatim):

  > ZIP code **99999** is not within Travis County and falls outside the scope of this dataset. I can only provide property and roofing data for areas within **Travis County, TX**.
  >
  > If you have a Travis County ZIP code, city, or neighborhood in mind, feel free to ask and I'll look it up for you!

## How the six queries came to pass: four recorded runs, each fixed from its failures

The results file was committed after each hosted run, so git holds every version (`git log --follow docs/evidence/A-14-golden-results.json`). Nothing was edited to make a grader pass except where the table says "grader".

| Run | Results committed in | Result | What failed | Fix |
| --- | --- | --- | --- | --- |
| 1 | `3a9199a` | 1 pass (G6), 5 fail | G1 and G3: the golden file expected rows (`empty_reason: null`) and the run had none (grader mismatch, not a product defect). G2 (ERR-61): the model spent its three tool steps weakening filters and its last text, a plan for a fourth call, came back as `answered`. G4 (ERR-62): the radius was silently widened from 5 to 10 mi and the answer claimed "good coverage"; the owner-location gap was not stated. G5 (ERR-63): `missing[]` used `bbb_rating` and `contractor_name_raw`, not the contract's `bbb_status` and `contractor.name_as_printed`; model calls, tokens, duration and trace id were not in the response | `c741363`: the last allowed step is text-only; no final text now gives outcome `failed`, never `answered`; filter changes are disclosed in `how` and in the answer; the owner-location gap goes into `missing[]`; contract field names; the response now carries `modelCalls`, `outputTokens`, `durationMs`, `traceId`; the grader follows the oracle's `empty_reason` (grader) |
| 2 | `830c4c5` | 2 pass (G1, G3), 4 fail | G2: the answer lacked the "at least 5" reading of "many years" and "contractor not printed". G4: no "outside the area" / "not in the published export" wording, `owner_is_out_of_area` not flagged, and the `field_not_published` expectation could not be matched by the oracle. G5: `bbb_status` not flagged as missing. G6: the `out_of_scope` expectation could not be matched by the oracle | `26ab027` (grader): expectations the oracle cannot express (G4 `field_not_published`, G6 `out_of_scope`) are reported as inconclusive, never as a pass. `830c4c5`: the deterministic server-side rules described above (wording and `missing[]` keyed on the question text; forced permit lookup) |
| 3 | `313d628` | 5 pass, 1 fail (G2) | G2: the model had written "Contractor names are not available in the published export", the server saw a contractor statement and skipped its own sentence, so the contract phrase "contractor not printed" was missing | `313d628`: the model's own wording no longer suppresses the contract phrase; the fixed sentence is skipped only if the answer already contains "contractor not printed" or "no_lexicon_carrier" |
| 4 (final) | `95b6370` | **6 pass** | none | none |

Notes on the history:

- The earlier version of this file said "grader unchanged and strict". That stopped being true at run 1's fix (`c741363`, grader follows the oracle) and `26ab027` (inconclusive reporting); both changes are listed above. Neither makes a failing case pass: the first removes a comparison that asked a run with no rows to return rows, the second turns an unanswerable expectation into an explicit "inconclusive".
- The deterministic honesty rules in `apps/api/src/agent/ask.ts` carry the label "ERR-64" in their code comments and in the subject of `830c4c5`. The defect record `docs/defects/ERR-64.md` is a different defect (the MCP burst answering 503). The honesty rules are recorded as the fixes of ERR-61, ERR-62 and ERR-63.
- ERR-61, ERR-62 and ERR-63 are closed on the strength of runs 3 and 4 (`docs/defects/ERR-61.md` to `ERR-63.md`).
- Run 2's and run 3's exact deployed build is not recorded in the results files. Run 4 is build `313d628`.

## Gaps

- G1 to G4 over real rows: **not measured** (the small run has none near Pflugerville, Manor or Lakeway; the full county times out; A-16).
- An answered G2 contractor line with a real contractor name: not possible, the published export carries no contractor name (`contractor.name_as_printed` has no lexicon carrier, `docs/decisions/0002-lexicon-carriers.md`).
- p95 over the full county, the `AI_PROVIDER=gateway` run and the Explore-page leg of AC-8: **not measured**.
- The `donphan` transcript through MCP: done, in `docs/evidence/A-14-mcp.md` (honest empty answer on the small pinned run).
