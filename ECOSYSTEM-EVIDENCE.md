# ARC Ecosystem Evidence

This document preserves the public-safe measurement snapshot behind ARC's origin story.

It describes the **whole TBHRC / iMPLEMENTAi GitHub-era operating ecosystem that FolderDesk packages for reproduction**, not only the `tbhrc/folderdesk` repository.

## Measurement window

- Start: **27 August 2026 · 13:19 GST**
- End: **4 September 2026 · ~03:00 GST**
- Duration: **7.57 days / 181.7 hours**

The original internal/public-safe measurement artifact was the **iMPLEMENTAi.ae — GitHub Era Achievement Dashboard — V1**.

## Evidence rule

Metrics are deliberately separated into three classes:

- **Exact** — directly counted from repositories, Skills or mailbox queries.
- **Derived** — calculated from direct counts/timestamps or from an explicitly identified estimate.
- **Estimated** — triangulated historical range where no single cross-estate telemetry endpoint existed.

Do not turn an estimated historical figure into false precision.

## Headline snapshot

> **In 7.6 days: a 29-repository estate, 57 canonical Skills, ~1,000 governed GitHub work objects, 1,358 GitHub notification emails, seven named AI execution lanes and an 80% reduction in targeted router turnaround.**

## Quantified transformation

| Metric | Figure | Confidence / interpretation |
|---|---:|---|
| Measurement window | 7.57 days / 181.7 hours | Exact |
| Current repositories | 29 | Exact |
| Active repositories | 26 | Exact |
| Archived repositories | 3 | Exact |
| Private repositories | 21 | Exact |
| Public repositories | 8 | Exact |
| GitHub-era repository cohort | 12 | Derived: `gh-course` plus 11 additional repos |
| Canonical Skills | 57 | Exact |
| Named AI execution lanes | 7 | Exact |
| Conditional additional route | Gemini | Recorded conditional route |
| Issues created | ~530 | Estimated midpoint; range ~500–560 |
| Pull requests | ~470 | Estimated midpoint; range ~440–500 |
| Issue + PR work objects | ~1,000 | Estimated; range ~950–1,060 |
| Merged PRs | ~380–420 | Estimated range |
| Commits | ~1,500 | Estimated midpoint; range ~1,200–1,800 |
| AI / API / connector calls | ~6,000 midpoint | Estimated; range ~4,000–8,000 |
| Actions workflow runs | ~1,400 midpoint | Estimated; range ~1,000–1,800 |
| Repository lines touched | 120,000–200,000 | Estimated order of magnitude |
| Gmail messages | 1,477 | Exact, reporting window excluding Spam / Trash |
| GitHub notification emails | 1,358 | Exact |
| Non-GitHub Gmail traffic | 119 | Derived remainder |
| Sent from measured Gmail account | 9 | Exact |
| Known recruitment outreach emails | ≥16 | Documented minimum, separate Outlook workflow |
| GitHub share of Gmail traffic | 91.9% | Derived |
| GitHub notifications per day | ~179 | Derived |
| Approx. Issue/PR work-object velocity | 132/day | Derived from estimated work-object total |
| Approx. work objects per hour | ~5.5 | Derived from estimated work-object total |
| Approx. Issue/PR creation rate | one every ~11 minutes | Derived from estimated work-object total |

## Router benchmark

The targeted read-only status/router regression was measured repeatedly:

| Stage | Turnaround | Tool calls |
|---|---:|---:|
| Baseline | 92 sec | 20 |
| Pass 1 | 37 sec | 8 |
| Current measured result | 18 sec | 5 |

Derived impact:

- **75% fewer tool calls** — 20 → 5.
- **80.4% lower turnaround** — 92 sec → 18 sec.
- **5.1× relative speed** on that targeted task class.

This is a targeted benchmark, not a claim that every ecosystem task is 5.1× faster.

## Execution-mesh benchmark — 25 September 2026

A later production benchmark measured how FolderDesk/FD0 should route execution across the shared Talent Bridge + iMPLEMENTAi infrastructure.

| Node | Existing / comparator | Self-hosted Desktop Commander | Certified architecture |
|---|---:|---:|---|
| Home PC | reverse SSH mean **5,071.1 ms** across 3 trivial-command runs | **~557.5 ms** first simple-command proof | Desktop Commander primary; reverse SSH fallback |
| Mac M5 | reverse SSH mean **1,649.5 ms**, p50 **1,646.2 ms** across 8 runs | mean **310.6 ms**, p50 **302.3 ms** across 8 runs | Desktop Commander primary; reverse SSH fallback |
| VPS | native async subprocess mean **8.49 ms**, p50 **7.35 ms** across 12 runs | mean **33.97 ms**, p50 **32.40 ms** across 12 runs | keep native `vps_*`; Desktop Commander rejected |

The benchmark also tested failure behaviour rather than speed alone:

- Home-PC and M5 Desktop Commander providers were deliberately stopped.
- The unchanged public FD0 action automatically fell back to the already-certified SSH/reverse-SSH road.
- Restoring the provider returned the primary route without an FD0 restart.
- Timeout termination was proven without a surviving matching process.
- Commands are not replayed across providers after Desktop Commander has accepted them.
- The public FD0 surface remained **14 actions**.

The VPS result is equally important: Desktop Commander worked technically but duplicated a faster native execution path and added significant resource cost, so it was removed rather than standardised for architectural neatness.

Canonical benchmark: [FD0 Desktop Commander Execution Routing](https://github.com/tbhrc/workspace/tree/main/.folderdesk/benchmarks/fd0-desktop-commander-routing)

This is a targeted execution-routing benchmark, not a claim that every FolderDesk workflow is 5x–9x faster.

## Current Repository Router proof

On **6 September 2026**, [`tbhrc/skills#394`](https://github.com/tbhrc/skills/issues/394) recorded a point-in-time acceptance across **11 registered repository-root `AGENTS.md` files**: the shared Router body matched, only repository Fast Links differed, and all remained below the 80-line Router limit.

This is direct reference-ecosystem proof that multiple live repositories can use **one shared Router contract rather than separate agent manuals**. It is not an ARC deployment requirement and does not imply every future repository has already passed the same validation.

The central [`templates/agents-repositories.json`](https://github.com/tbhrc/skills/blob/main/templates/agents-repositories.json) registry has since expanded beyond that acceptance sample. Therefore **11 is the verified sample recorded by #394, not a claim about the current registry total**.

## Repository creation cohort

The measured post-`gh-course` cohort was:

1. `gh-course` — 27 Aug
2. `dsf` — 27–28 Aug
3. `drf-main` — 28–31 Aug
4. `now-hiring` — 31 Aug
5. `tb` — 1 Sep
6. `recruitment` — 1 Sep
7. `assessments` — 1 Sep
8. `skills` — 1–2 Sep
9. `ai-ops` — 2 Sep
10. `research` — 2–3 Sep
11. `ai-engine` — 3 Sep
12. `arc` — 3–4 Sep

The cohort represents approximately 41% of the 29-repository estate measured at that time.

## Named AI execution lanes

The measurement recorded seven named lanes:

1. ChatGPT — controller / direct execution
2. Copilot — GitHub-native coding / review
3. Jules J2 — exact-seat Google lane
4. Codex C2 — David profile lane
5. Claude — subscription-backed route
6. Codex C1 — Business profile lane
7. Jules J1 — exact-seat Talent Bridge lane

An **8th conditional route**, Gemini CLI/API, was recorded when quota and route were viable.

GitHub Actions, Mac, VPS, Microsoft Graph, Monid and Composio were treated as execution substrates/capability layers rather than AI agents.

## Canonical Skills snapshot

The measured 57 Skills were grouped as:

| Family | Count |
|---|---:|
| Foundational GitHub operations | 8 |
| Founder advisory | 1 |
| Automation | 4 |
| Infrastructure / runtime | 9 |
| Research / intelligence | 3 |
| Sales / marketing | 1 |
| iMPLEMENTAi | 8 |
| Talent Bridge / recruitment | 19 |
| Spreadsheet / file safety | 1 |
| Frontend design | 1 |
| Content / brand | 2 |
| **Total** | **57** |

The important architectural point is not the number 57 itself. It is that reusable operating knowledge had moved from scattered prompts into a versioned canonical Skills layer.

## Business outcomes observed in the same operating era

### Now Hiring signal engine

- 100+ fresh UAE vacancy signals reviewed.
- 12 deeply enriched.
- 10 qualified.
- 2 reached David Review.

### Recruitment outreach

- at least 16 known outbound recruitment emails through the controlled programme;
- first positive client response requesting CVs.

### Recruitment sourcing

- cited sourcing batch grew from ~80 records to 120 total;
- 119 active after deduplication/quality control.

### DRF / commercial opportunity architecture

- 27 DRF V3 opportunity parents;
- three-layer Revenue Opportunity Factory;
- 7/7 master stages completed at the measured point.

### Business Blueprints

- 82 opportunity records;
- the earlier Whop-centric concept was generalised into Business Blueprints, with Whop retained as a channel rather than the business definition itself.

### Reusable operating IP

- ~35 legacy-scope Skills → 57 canonical Skills;
- one editable GitHub Skill Bank became the reusable HOW layer.

## Infrastructure/capability proof present in the measured ecosystem

The measured operating estate had established or proven capability across:

- GitHub as durable work/governance control plane;
- Skills as reusable HOW / central nervous system;
- OneDrive / SharePoint as private evidence plane;
- Hindsight as derived memory;
- AI Engine as privileged runtime owner;
- self-hosted Mac execution;
- VPS execution and mirror/backup patterns;
- Microsoft Graph / OneDrive read/write route;
- Monid specialist tool/API gateway;
- Composio authenticated connected-app routing;
- GitHub Actions PR authority;
- exact-seat multi-agent routing;
- Issue-first governance and durable evidence.

## Transformation timeline

### 27 August

`gh-course` became the learning laboratory for Issue-first work, PR discipline, Wiki, Pages, SemVer and early AI-control-plane experiments.

### 28 August

Project/status automation, executor benchmarks and durable agent evidence moved GitHub toward an active operating control plane.

### 29–31 August

The model propagated to DSF and DRF. Now Hiring began turning vacancy research into a governed recruitment acquisition engine.

### 1 September

TB federation, Recruitment and Assessments established clearer domain ownership; DRF reached its 7/7 master-stage milestone; Now Hiring completed a 100+ signal run.

### 2 September

GitHub-first became operating canon. Skill Bank migration accelerated. Now Hiring progressed from lead identification into client response/candidate-delivery work.

### 3 September

Mac/VPS execution expanded; exact J1/J2 and C1/C2 routing seats became explicit; Monid and Composio entered the capability map; the router baseline measured 20 calls / 92 seconds.

### 4 September

The targeted router regression reached 5 calls / 18 seconds; the Skill Bank stood at 57 canonical Skills; ARC became the reproduction/recovery package for the accumulated architecture.

## Before → after

### Before

- processes scattered across chats, local workflows and legacy systems;
- agent capability strongly dependent on surface/account/model;
- knowledge duplicated between prompts, documents and notes;
- execution evidence difficult to reconstruct across sessions;
- business workflows and technical infrastructure loosely coupled.

### After

- GitHub owns durable work and governance;
- Skills own reusable methods;
- domain repositories/specialist systems own current truth;
- repository-root `AGENTS.md` Routers + progressive Fast Links reduce rediscovery and unnecessary preload;
- multi-agent orchestration avoids permanent provider dependence;
- normal connected capability executes directly when sufficient;
- Mac/VPS/trusted runtime fills bounded gaps;
- verification and durable evidence close the loop.

## Relationship to ARC v1

These statistics describe the **proven ecosystem ARC was created to reproduce**.

ARC itself then underwent an independent clean-room proof on 4 September 2026 and demonstrated:

- target-specific North Star;
- the historical machine-first routing proof that evolved into today's root `AGENTS.md` Repository Router + progressive Fast Links;
- independent Skills owner;
- durable Issue / Anti-Drift workflow;
- minimal external-system reconnection;
- a real source-backed workflow;
- non-secret estate snapshot;
- destructive recovery of the deployed `AGENTS.md` surface.

See [FolderDesk Core Proof #11](https://github.com/tbhrc/folderdesk/issues/11).

## Interpretation guardrail

Do not conflate these three statements:

1. **The ecosystem transformation was measured over 7.57 days / 181.7 hours.**
2. **ARC was created near the end of that transformation as the portable reproduction/recovery package.**
3. **The underlying founder/business/AI experimentation predates the GitHub measurement window.**

ARC v1 therefore packages accumulated operating architecture; it is not a claim that every idea, business process or founder lesson originated inside the ARC repository or within 181.7 hours.
