# Roofing CRM, Travis County TX: all five stories built and proven on a hosted URL

> Stories B-01, B-02, B-03, B-07 and B-09 are built, reviewed and merged (`--no-ff`, one merge per story). Since 2026-10-26 the app serves Task A's full-county **Run 3.1** (contract v1.2: street addresses and owner mailing ZIPs) at **https://crm.aldarraj.com**. A whole-repo review by eight kit agents and an evaluator self-score ran on 2026-10-26 (see Progress since the last update); the fixes it found are on the branch. Still to do before this is ready for final review: the demo video and marking the PR ready.

## Outcome

A Roofing CRM that turns published Travis County property and permit data into roofing leads: a three-pane map with radius search, aged-roof and open-permit filters, a county overview, saved leads with status and notes, a browsable candidate and lead list, and an AI agent inside the map that answers plain-language questions with numbered, verified citations. Every value comes from the Oracle task's (Task A's) published CIDs, with provenance; a missing value says why. Live on real published data: **441,961 properties and 15,025 Austin roofing permits** (Task A run `travis-full-run2-20261024`).

## Links

| What | Where |
| --- | --- |
| Runtime (all five stories) | **https://crm.aldarraj.com** (Amplify, `eu-north-1`; certificate issued by Amazon, DNS at Namecheap). The build it serves is named at `/build.json`. Branch preview of the story branch: https://009-agent-hardening.d1zmhc6kkyzsbe.amplifyapp.com |
| Test credentials | Username `admin@roofing-crm.test`. The password is in AWS Secrets Manager (`roofing-crm/admin-user`, `eu-north-1`) and is shared privately with the assessor, never in this PR |
| Demo video | Not recorded yet (release step, listed in [`docs/pending-items.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/pending-items.md)) |
| Data source (Task A) | Run 3.1 manifest CID `bafkreidbqsav3rsbxqy5fx3li73uskfth254nz5zw34xwac5w3fd4tmbai`, run `travis-full-run3-1-20261025` (contract v1.2; 441,961 properties, 15,025 Austin roofing permits, 4,552 with a printed contractor name; Run 3 `bafkreifndsdibdllvgpzwmif6getzwvc6rupk5tgeak4eypccaw3t7vlfm` is kept as `previous` for rollback). The sync reads the manifest named by `DATA_MANIFEST_CID`, checks every part's SHA-256 against it, and promotes the index only if the checks pass. Requests never go to Task A at run time |
| CI | GitHub Actions runs on the fork, so they do not appear in this PR's checks list: [all runs on `feature/roofing-crm`](https://github.com/HebaGaber/roofing-crm/actions?query=branch%3Afeature%2Froofing-crm). The last full run on the story branch (lint, type-check, unit tests, secret scan, and Playwright on the hosted URL: 152 passed in the parallel phase, 80 in the isolated phase, 0 failed) is [40167849532](https://github.com/HebaGaber/roofing-crm/actions/runs/40167849532) |

## Progress since the last update (2026-10-26)

| What | Result |
| --- | --- |
| Data switched to Task A Run 3.1 | Manifest `bafkreidbqsav3rsbxqy5fx3li73uskfth254nz5zw34xwac5w3fd4tmbai`, promoted 2026-10-26 05:16Z, then rebuilt with Task A's review changes (fa6771a). Counts read from the served index: 441,961 properties, 15,025 permits, 4,552 with a printed contractor name (none verified, BBB blocked). Owner area: in county 346,950, regional 7,399, out of area 41,953, unknown 45,659. Street address text is published; situs city and ZIP read `source_missing`. Run 3 stays as `previous` for rollback ([`docs/runbook.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/runbook.md)) |
| Index build memory | Run 3.1 failed at the old 2,400 MB DuckDB limit. The limit is 2,600 MB inside the 3,008 MB Lambda (the account cannot raise Lambda memory); 3 of 3 full builds passed in a 3,008 MB arm64 container (51 to 88 s) |
| Screens | Street address is the title everywhere, owner mailing location with a Local / Regional / Out-of-area pill, exact street-address search in the search box, owner filters (tenure over 10 years, out of area, tenure N years or more), lead confidence, recent and saved searches, similar properties, Assign to me |
| Whole-repo review by the kit agents (read-only, 2026-10-26) | First round: `audino` 84, `metagross` 82, `espeon` 82, `ash` 82, `alakazam` 78, `porygon` 78, `machamp` 68, `smeargle` 66. The two below 75 were fixed and re-scored on the fixed code: `machamp` **79** (alerts for failed, held and memory-high sync runs, runbook, a one-command rollback script, a named failure state) and `smeargle` **83** (responsive tests for the drawer actions, Filters owner group, search suggestions, radius control and GPS-denied card; CI fails instead of skipping without the password). Every reviewer is now at 75 or higher |
| Evaluator self-scores (`slowking`, live app at 390 / 768 / 1440 px) | **Final measured: 80 / 100 with the demo gate treated as passed** (first measured 75; the earlier estimate was about 68); **0 / 100 as scored**, solely because the demo video is not recorded (the PR, hosted runtime and credentials gates pass). Final breakdown: Functional 36 of 40, Runtime and demo 15 of 20, Evidence 9 of 12, Access boundaries 8 of 8, Implementation 4 of 7, Kit usage 4 of 5, Reproducibility 3 of 4, Speed 1 of 4. The evaluator exercised the whole demo transcript on the live site at all three widths, created three test leads (two removed with Undo, one removed afterwards from the table), and asked the agent 8 questions: the out-of-area and email-the-owners questions were refused, card and suggestion clicks asked immediately, Ask results appeared in the List view, and the drawer showed everything inline including why a property is a lead. It found these remaining gaps, handled in this round: the README example city (Manor) has no matching permits (the example is now Austin), a first pin-mode click zoomed instead of dropping the pin (fixed), "Ask about it" misread a TCAD id as a place and counted one property twice (fixed), permit-only answers had no map pin (fixed), stale evidence notes (updated). Not fixable: BBB scores (the data has none) and elapsed time |
| Fixes on the branch from that review | Permit filters now run in SQL before the page and the counts (they used to cover only the nearest 100 properties); "Open" includes stalled permits; Ask keeps the permit condition of a question; failed, timed-out, aborted and held sync runs raise alarms; shared main-permit rule used everywhere; "over 10 years" tenure means the same in the map and the agent; agent-created leads are titled with the street address; the architecture constitution is reconciled with the amended owner-name decision; drawer Close and BBB link tap targets; new responsive tests for the drawer, the Filters owner group, search suggestions and the GPS-denied card; CI fails instead of skipping when the test password is missing |
| Independent README and demo walk-through (live, read-only) | Met: default county, GPS and pin drop, configurable radius, roof-age and permit filters, long-open emphasis, candidate list, lead controls, disabled sections, out-of-scope items. Gaps it found, now handled or stated: the Ask agent was paused by the daily spend cap (cap raised); permits labelled Stalled that were already finaled (see next row); no preselected roof-age threshold (15 is a chip); BBB scores never appear (the data has none: shown as not available with a search link); long-open sorting only in the List view; test leads in the live Leads list; the agent plans a structured query rather than vector retrieval |
| Finished permits no longer counted as live | Task A classes a permit with no status as stalled whatever its final date: 952 of the 1,674 stalled permits and 7 of the 80 open ones carry a final date. The CRM treats a permit as live only when it has no final date: 722 stalled and 73 open on Run 3.1. The drawer and chips label such a permit "Finaled {date} (status not in source)". Question 15 for Task A asks them to change the classification ([`docs/task-a-questions-run3.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/task-a-questions-run3.md)) |
| Verified after the fixes | Deployed commit named at `/build.json` (the web build, the API and the sync stack come from the same commit). CI was green on the previous deploy `299fb1b` (secret scan, workspace checks, hosted Playwright); on `098fb75` it showed three hosted-spec failures that were test problems, not product bugs (a loose selector in two specs, one CI timing blip), fixed in the specs; a clean CI run on the final commit is pending. All six sync alarms exist and read OK. Golden queries on the deployed agent: 48 of 48 on Run 3.1 final, 48 of 51 after the self-score fixes (X2 failed 3 of 3), then 51 of 51 at commit `098fb75` after the named-place gate (see B5). The agent's daily spend cap per user was raised from $3 to $10 on 2026-10-26 so a demo plus the golden runs fit one day. Still to do: the demo video and a fresh evaluator self-score on this commit |

## Evaluation points

| Point | Story | Status | Evidence |
| --- | --- | --- | --- |
| B1 Location search | B-01, B-03 | Built and proven | [`docs/evidence/B-01.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/evidence/B-01.md), [`docs/evidence/B-03.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/evidence/B-03.md) |
| B2 Aged-roof leads | B-02, B-03 | Built and proven. On Run 3.1 (same counts as Run 3), 88 % of properties have a roof age, but 98 % of those are the year built (confidence Low, shown as "estimated from year built"); only 9,510 come from a closed roofing permit. Land parcels say "No building on this parcel" | [`docs/evidence/B-02.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/evidence/B-02.md), [`docs/evidence/B-03.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/evidence/B-03.md), [`docs/evidence/B-09.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/evidence/B-09.md) |
| B3 Open permits, contractor, BBB | B-02, B-03 | Built and proven; the contractor shows as printed on the permit (unverified, 4,552 permits) with a BBB search link; no BBB rating exists (BBB blocks the lookup) and every missing value shows its reason | [`docs/evidence/B-03.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/evidence/B-03.md) |
| B4 CRM leads (create, no duplicates, status, notes) | B-07 | Built and proven: 20 of 20 executed cases pass; 20 concurrent creates give exactly 1 lead; lead creation, bulk create and Undo also work from the agent | [`docs/evidence/B-07.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/evidence/B-07.md), [`docs/reports/TR-B-07.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/reports/TR-B-07.md) |
| B5 RAG agent | B-09 | Built and proven on Run 2; golden queries re-run on Run 3.1 under the live rule (a finished permit is never open or stalled): 16 of 16 passed in each of 3 repeats (48 of 48) at commit `299fb1b`. Re-run on the 17-query suite at commit `8e8e9e0` (X5, refusing to email owners, is new and passes 3 of 3): 16 of 17 pass in each of 3 repeats (48 of 51); X2 ("within 5 miles of Houston") failed in all 3 because the agent answered for Austin. Fixed by the named-place gate (a place named in the question that is not in Travis County is refused with `out_of_scope`, never replaced): at commit `098fb75` all 17 queries pass in each of 3 repeats (51 of 51), X2 refused 3 of 3, X3 (typo "Pflugervile") still resolves to Pflugerville. Every cited row checked against the index (615 of 615); p95 15.1 s, max 15.8 s | 
| B6 Candidate list, combined filters, scale, responsive, observable | B-07, B-09, B-01 | List and filters proven on the full county; radius searches take about 1 s at p50 and 1.3 s at p95 (6 to 25 mi); responsive checks at 360, 390, 600, 768, 1280 and 1440 px; DLQ alarm fired and recovered. The test cases that are not proven are listed in Known gaps | [`docs/evidence/B-07.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/evidence/B-07.md), [`docs/evidence/B-09.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/evidence/B-09.md) |

The README criterion-by-criterion matrix is [`docs/traceability.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/traceability.md).

## Story status

| Story | Status | Merge commit | Gate |
| --- | --- | --- | --- |
| B-01 CRM shell | Done | `fcd6d6a` | G7 |
| B-02 Lead search index | Done | `d01c06e` | G7 |
| B-03 Map search (radius, roof age, permits, detail) | Done | `80873e1` | G7 |
| B-07 Leads and lead list | Done | `8b13240` | G7 approved with exceptions |
| B-09 Agent and hardening | Done | `ab6f520` | G6 and G7 approved with exceptions (below) |

## Verification

| What | Result |
| --- | --- |
| Unit and integration tests | 2,693 passed, 0 failed on the branch head (see Validation and testing); new code at or above 80 % coverage ([`docs/reports/UT-B-09.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/reports/UT-B-09.md)) |
| Hosted end-to-end, mobile 390 / tablet 768 / desktop 1440 | 152 passed in the parallel phase and 80 in the isolated phase, 0 failed (run 40167849532); fixtures were refreshed to Run 3.1 on 2026-10-26 (CI run on the Run 3.1 build was green: workspace, secret scan and hosted Playwright) and a fixture-validity spec fails with refresh steps if the served data changes |
| Golden queries on the deployed agent | Run 3.1 after the named-place gate (commit `098fb75`, 17 queries): 51 of 51 (100 percent), 17 of 17 in each of 3 repeats. X2 ("within 5 miles of Houston") is now refused with `out_of_scope` (no plan area, no rows) in all 3 repeats; it had failed 3 of 3 at `8e8e9e0` (48 of 51) by answering for Austin. X3 (typo "Pflugervile") still resolves to Pflugerville (28,062), and G1, G2, G4, G5 and A1 to A5 return the same counts as before. 615 of 615 cited rows verified; latency p95 15.1 s, max 15.8 s on 54 timed asks; about US$1.1 of Bedrock (estimated from 87 model calls); details in [`docs/evidence/B-09.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/evidence/B-09.md) |
| Code review | B-09 final re-score: `alakazam` 84, `ash` 87, `metagross` 88, `audino` 82, `porygon` 84, plus `/code-review medium` on the final code (8 follow-ups, none Critical); no open Critical ([`docs/reviews/CR-B-09.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/reviews/CR-B-09.md)) |
| Defects | Every recorded defect is closed ([`docs/defects/`](https://github.com/HebaGaber/roofing-crm/tree/feature/roofing-crm/docs/defects/)). Found only on the live stack and fixed in this round: lead Undo failed on the real table (a DynamoDB reserved word), the agent could not check or propose leads (lead repository missing from the Lambda context), the sync failed on a result-size limit, and whole-county searches ran out of memory |

## How it was built

The work follows the assessment guide's gated, story-by-story loop. Nothing was built before the vision, feature list, plan and architecture were approved by the product owner.

| Stage | What happened | Where |
| --- | --- | --- |
| Planning gates G0 to G3 | Vision, feature list, high-level plan and architecture constitution were written, pre-checked by the `developmentsupport-*` skills (which only report gaps) and approved by the PO | [`docs/gates/`](https://github.com/HebaGaber/roofing-crm/tree/feature/roofing-crm/docs/gates/), [`docs/architecture-constitution.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/architecture-constitution.md) |
| Per story (B-01, B-02, B-03, B-07, B-09) | Ready check (G4), `/speckit-specify` and `/speckit-clarify`, design agents consulted read-only (answers saved per story), `/speckit-plan`, `/speckit-tasks`, `/speckit-analyze`, test cases written before code (G6), build by kit builder agents in at most four task groups (some fix rounds ran on general-purpose agents, which `docs/kit-usage.md` records), one review round, deploy and Playwright on the hosted URL, `/speckit-converge` once, then G7 and a `--no-ff` merge | [`specs/`](https://github.com/HebaGaber/roofing-crm/tree/feature/roofing-crm/specs/), [`testplans/`](https://github.com/HebaGaber/roofing-crm/tree/feature/roofing-crm/testplans/), [`docs/reports/`](https://github.com/HebaGaber/roofing-crm/tree/feature/roofing-crm/docs/reports/) |
| Kit agents | Each story names its design, builder, reviewer and verifier agents (`metagross`, `espeon`, `alakazam`, `ash`, `machamp`, `porygon`, `audino`, `smeargle`, `donphan`, `mew`); reviewers score 0 to 100 and a story needs 75 or more before G7 | [`docs/kit-usage.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/kit-usage.md), [`docs/reviews/`](https://github.com/HebaGaber/roofing-crm/tree/feature/roofing-crm/docs/reviews/) |
| Reuse of Task A | Task A's published contract and view code are vendored read-only and logged with a content hash; the CRM reads Task A's data only through its published manifest and parts by CID | [`docs/reuse-log.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/reuse-log.md) |
| Rules that held throughout | Atlas tokens and components only; every data display shows its source and every missing value its reason; no invented or synthetic data; CDK only; the Vercel AI SDK for models; no secrets in git or logs; the PR is never merged by the author | [`.specify/memory/constitution.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/.specify/memory/constitution.md) |
| Run 3.1 switch (2026-10-26) | Task A published Run 3.1 (street addresses, owner ZIPs). The contract and views were re-vendored, the index schema extended, the build memory limit measured in a 3,008 MB arm64 container (the Lambda size) before changing it, the new manifest promoted and then rebuilt with Task A's review changes. Run 3 stays as the one-step rollback | [`docs/runbook.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/runbook.md) |
| Whole-repo review and self-score (2026-10-26) | Eight kit agents reviewed the whole repository read-only; the assessor's own evaluator agent exercised the live app in a browser. Everything below 75 and every functional bug it found was fixed and re-tested | Progress table above, [`docs/pending-items.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/pending-items.md) |

## Validation and testing

| Layer | What is checked | Result (2026-10-26, branch head) |
| --- | --- | --- |
| Static checks | TypeScript strict type-check of 14 workspace tasks, ESLint, Prettier, secret scan (gitleaks), cdk-nag on every stack | All pass |
| Unit and integration tests | Vitest across 16 packages and apps: web 1,226, API 588 (including real-Parquet search tests), sync 133, vendored Task A views 302, infra 90, plus domain, shared, schema, contract, config, observability, UI, agent tests | **2,693 passed**, 0 failed (25 skipped by design: live-only suites that need the hosted runtime) |
| Data pipeline | Manifest bytes checked against the CID; every part checked against its SHA-256 and fetched CloudFront, then Filebase, then Pinata; profile-digest guard; cost gate; 5 % drop rule; unverified-part hold; Validate before Promote; a conditional pointer flip | Run 3.1 built and promoted; 441,961 properties and 15,025 permits equal the manifest counts |
| Index build | The full Run 3.1 build run three times in a linux/arm64 container capped at the Lambda's 3,008 MB | 3 of 3 passed in 51 to 88 s at a 2,600 MB DuckDB limit (2,400 MB failed) |
| Hosted end-to-end | Playwright on https://crm.aldarraj.com at phone 390, tablet 768 and desktop 1440 px: sign-in and lockout, map search by pin, GPS and radius, roof-age filter, open-permit filter, drawer, lead create / status / notes / duplicates (20 concurrent creates give exactly one lead), the Ask agent, filters, "coming soon" sections, layout and overflow, the Atlas token audit | CI run on the Run 3.1 build was green (workspace, secret scan and hosted Playwright). New responsive tests (drawer actions, Filters owner group, search suggestions, GPS-denied card) pass at all three widths on the deployed commit `df584e5` after two tap-target CSS fixes |
| Fixtures | A fixture-validity spec fails with refresh steps when the served run no longer matches the pinned values | Pass on Run 3.1 |
| Agent | Golden queries G1 to G7 and A1 to A5 with strict pass rules (an honest empty must carry zero claims, citations and rows); every cited row is re-checked against the live index under the same manifest CID; scope gate, spend cap and rate limit in code | Passed on Run 2. Re-baselined on Run 3.1 and run live: 48 of 48 (16 queries, 3 repeats), 690 of 690 cited rows verified, p95 12.5 s |
| Performance | NFR-001 targets p95 under 3 s. Radius searches measured about 1 s at p50 and 1.3 s at p95 for 6 to 25 mi on the full county; the permit filter on the Run 3.1 index runs in 0.1 to 1.0 s in tests | Agent latency p95 12.5 s on 51 timed asks (target under 20 s). Map search on the deployed Run 3.1 index, measured 2026-10-26: p95 1.11 s and p50 0.86 s over 20 timed radius changes from 6 to 25 mi (target under 3 s); the first search after a cold start of the API can take 4 to 10 s (the index is downloaded once per sandbox), listed under known issues |
| Independent checks | Per-story reviewer agents (every final score 75 or higher, recorded in `docs/kit-usage.md`) and the whole-repo round of 2026-10-26 (66 to 84 before the fixes) and an evaluator self-score that exercised the live app | Findings and fixes in the progress table |
| Defects | Every recorded defect has a file, a root cause and a regression test; the ones found only on the live stack are listed in the Verification table | [`docs/defects/`](https://github.com/HebaGaber/roofing-crm/tree/feature/roofing-crm/docs/defects/) |

What was **not** proven is listed under Known gaps, not hidden: the demo video is not recorded, nine test cases from B-09 were approved by the PO as exceptions, and the BBB rating and verified contractors do not exist in Task A's data.

## How to redeploy and where the data comes from

The data is Task A's published manifest, named by `DATA_MANIFEST_CID` (currently `bafkreidbqsav3rsbxqy5fx3li73uskfth254nz5zw34xwac5w3fd4tmbai`, run `travis-full-run3-1-20261025`). The sync fetches it and every part by CID (CloudFront, then Filebase, then Pinata), checks each against its SHA-256, and promotes the index only if every check passes; the manifest CID is recorded on every index row and every lead. Requests never go to Task A at run time.

To deploy from a clean checkout (AWS profile `assess`, account 515618610572, region `eu-north-1`):

```text
eval "$(aws configure export-credentials --profile assess --format env)"
cd infra
AWS_REGION=eu-north-1 CDK_DEFAULT_REGION=eu-north-1 CDK_DEFAULT_ACCOUNT=515618610572 \
DATA_MANIFEST_CID=<manifest cid> AI_PROVIDER=bedrock AGENT_MODEL_ID=eu.anthropic.claude-sonnet-4-6 \
npx cdk deploy --all --require-approval never
```

The web app deploys from the branch through Amplify. A deploy starts one sync; moving to a new Task A run means changing `DATA_MANIFEST_CID` (also the GitHub variable) and deploying. Rollback, forced rebuild, alarms and the DLQ are in [`docs/runbook.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/runbook.md); `scripts/sync-ops.sh` gives one-command status, rollback and replay.

## Architecture

Decided and approved at G3: [`docs/architecture-constitution.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/architecture-constitution.md). Search runs in DuckDB over a CRM-owned Parquet index built by a Step Functions sync from Task A's published data; leads live in DynamoDB with a conditional-write transaction that refuses duplicates (key `{fips}:tcad:{request_identifier}`).

Golden Path: TypeScript · CDK (region from config; demo in `eu-north-1` because the demo AWS project is region-locked, company default `us-east-2`) · Turborepo · tRPC + Zod · Vercel AI SDK · Powertools + X-Ray · Vitest + Playwright in GitHub Actions.

## Delivery process

| What | Where |
| --- | --- |
| Vision, feature list, plan, architecture (G0 to G3, approved) | [`docs/01-intent.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/01-intent.md), [`docs/feature-list.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/feature-list.md), [`docs/plan.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/plan.md), [`docs/architecture-constitution.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/architecture-constitution.md) |
| Gate log | [`docs/traceability.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/traceability.md) § 3, pre-checks in [`docs/gates/`](https://github.com/HebaGaber/roofing-crm/tree/feature/roofing-crm/docs/gates/) |
| Story progress and git graph | [`docs/progress.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/progress.md) |
| Test cases and execution reports | [`testplans/`](https://github.com/HebaGaber/roofing-crm/tree/feature/roofing-crm/testplans/), [`docs/reports/`](https://github.com/HebaGaber/roofing-crm/tree/feature/roofing-crm/docs/reports/) |
| Code review logs and defects | [`docs/reviews/`](https://github.com/HebaGaber/roofing-crm/tree/feature/roofing-crm/docs/reviews/), [`docs/defects/`](https://github.com/HebaGaber/roofing-crm/tree/feature/roofing-crm/docs/defects/) |
| Per-story evidence | [`docs/evidence/`](https://github.com/HebaGaber/roofing-crm/tree/feature/roofing-crm/docs/evidence/) |

## Kit usage

See [`docs/kit-usage.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/kit-usage.md).

## Known gaps

Every recorded gap, with its cause and what closes it, is in [`specs/007-leads/known-gaps.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/specs/007-leads/known-gaps.md) and [`docs/pending-items.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/pending-items.md). The ones that matter most:

| Gap | Why | Next step |
| --- | --- | --- |
| Demo video | Not recorded yet | Release step R7 |
| Test cases not proven (9 of 33 in B-09): TC-002 Open on map, TC-017 throttled and paused states at three widths, TC-019b, TC-024 timeout state in the browser, TC-NF-01 as specified (39 asks times 3 repeats; run once per query), and four design sign-offs | Approved as exceptions by the PO on 2026-10-25 | Listed in [`docs/reports/TR-B-09.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/reports/TR-B-09.md) |
| Task A data gaps that remain in Run 3.1: no roof date from TCAD (built year stands in, confidence Low), situs city and ZIP not published (inside the address text), 7,945 properties without coordinates, 32,572 properties without an owner (15,410 confidential, about 17,160 names not parsed), contractors only as printed and unverified (4,552 of 15,025 permits), no BBB rating, permits for Austin only | Task A's published data | Answered by Task A on 2026-10-26 ([`docs/task-a-questions-run3.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/task-a-questions-run3.md)); the app shows "not published" with a reason |
| Final code review follow-ups (8, from the B-09 review): query timeout shares one database connection, four index methods without a time limit, and smaller items | Found by `/code-review medium` on the final code; none Critical | [`docs/reviews/CR-B-09.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/reviews/CR-B-09.md), [`docs/pending-items.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/pending-items.md) |
| Scale: AC-4 at 50+ leads and list-load timing with 50+ leads | Decided by the PO as deferred, not passed; the full county is now loaded, so these can be run | Run them on the follow-up branch |
| `leads.create` trusts the property details the client sends; no per-lead ownership checks | Not decided or built yet | The follow-up story |
| CI reaches AWS with a long-lived access key of a narrowly scoped IAM user (`crm-ci`) | The organization policy blocks the GitHub-to-AWS role, so OIDC is not possible | The key can only read and delete test leads and publish metrics; it is retired after the final CI run (listed in [`docs/pending-items.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/pending-items.md)) |
| The release steps R4 to R7 (release notes, PR ready, demo video) | Moved out of B-09 by the PO | Listed with their steps in [`docs/pending-items.md`](https://github.com/HebaGaber/roofing-crm/blob/feature/roofing-crm/docs/pending-items.md) |
| Incremental Task A runs are not followed | Task A confirmed on 2026-10-26 that every run is a full snapshot, so the CRM does not follow `previousManifestCid` chains | Revisit only if Task A publishes delta-only runs |
| Lambda concurrency is 10 on this Free-plan account | Raising it needs a paid plan | The 20-concurrent-create test retries throttled calls and still proves exactly one winner |

🤖 Generated with [Claude Code](https://claude.com/claude-code)
