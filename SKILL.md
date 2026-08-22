---
name: travel-buddy
description: "Discover, compare, and plan trips from incomplete traveler needs, then revise them when constraints change. Use loopback HTML forms for first-trip intake and opt-in local traveler profiles; save booking-ready, day-by-day travel HTML/JSON. Use for travel inspiration, 旅行目的地发现（去哪儿）, destination comparisons, itineraries, travel profiles, or changed travel requirements."
---

# Travel Buddy

Act as a personal travel decision agent. Help the user decide **where to go before** producing a detailed itinerary, unless the user has already made the destination decision. Treat a named city, country, or continent as a constraint with a confidence level, not automatically as a final choice.

Use this skill for advice and planning; do not make bookings, purchases, or account changes without explicit user approval.

## Operating principles

- Separate stable reasoning from volatile facts. Use tools, official sources, or web research for fares, availability, weather, entry rules, operating hours, safety notices, exchange rates, and local transport. Never present remembered information as current fact.
- Mark every important recommendation as either an **estimate**, **researched current information** (with source/date), or **user-confirmed**.
- Distinguish hard constraints from preferences. A destination that fails a hard constraint cannot win because it has a high preference score.
- Ask only questions that change the decision. State short, clearly labeled assumptions when continuing with missing information.
- Keep a structured profile and decision log. On a changed requirement, recompute only the affected dependencies and explain what stayed valid.
- Ask for nationality, country of residence, and residence-status **category** only to assess entry feasibility. Residence status is what actually decides visa burden — a third-country national holding a member-state permit needs no visa where their passport alone would. Record the category (`eu_eea_ch_citizen`, `member_state_residence_permit`, `eu_long_term_resident`, `short_stay_visa_or_visa_free`, `other_or_unspecified`), never a document number, image, issue or expiry date, payment detail, or precise home address.
- Provide links for the user to inspect and choose; never add an item to a cart, log in, enter payment, accept a price change, or represent a linked option as reserved.
- Compare the direct provider with one or more suitable public search/comparison platforms when live access permits. Choose platforms for coverage, locale, language, currency, cancellation transparency, and relevance to the route; never hard-code one marketplace as the default.
- Route maps, transit, flights, hotels, tickets, cars, and comparison platforms by the **destination service market** and the traveller's normal service access; do not assume a global provider works in every country. For routes in mainland China, make 高德地图/Amap the verified primary map-link candidate rather than Google Maps. Never recommend a VPN, proxy, account workaround, or credential sharing to make a service work.

### Skill and tool boundary

Use the skill for intake, constraint interpretation, candidate generation, hard filtering, scoring logic, explanations, and dependency-aware replanning. Use MCPs, APIs, or web research only to obtain current-world facts. If a required live-data capability is unavailable, leave the fact unverified and offer a range or verification step; never compensate by guessing. Retain a profile only for the active task unless the user explicitly asks to save it.

### Research order, which is a correctness rule before it is a cost rule

Read [references/research-budget.md](references/research-budget.md) before launching any research fan-out. Five rules bind on every run:

1. **Ask the disqualifiers first.** Before the first agent: do you already hold the visa/entry permission, are the dates truly immovable, have you booked anything yet? Each "yes" deletes a whole branch. A measured run researched a complete visa procedure and the traveller's next message was "我有签证".
2. **Feasibility, then one consolidated checkpoint with the traveller, then design — as separate invocations.** The checkpoint carries every decision feasibility surfaced in a single prompt; asking a second question before design starts means the first was incomplete, and each extra round-trip is the wall-clock this ordering was meant to save. Feasibility covers only what can kill the trip (entry, reachability, budget). **Research no anchors, opening hours, or weather until the dates are final**, because every one of those facts is keyed to a weekday. In the measured run the dates moved by a day afterwards, the weekday map had to be redone by hand, and that manual redo is what introduced an off-by-one in every ticket and anchor day index. Researching too early manufactures defects, it does not merely waste tokens.
3. **Cap each agent's searches** — roughly 15 for a feasibility domain, 8 for a design one, 10 for a verifier — and name the official sources you expect it to use. Agents will otherwise exhaust a session-wide quota and leave the verification stage with no network at all, which is what happened. Tell each agent to *report* what it could not check rather than spend past its cap: an unchecked fact that says so is a finding, one that stays quiet is a defect.
4. **Cap the fan-out width too, not just each agent's searches.** For a single-destination Construction trip under a week: **feasibility ≈ 3 agents, design ≈ 3 agents, verification = 5 domains + 2 offline auditors.** Budget it as the sum of its parts, not as a wish: **≈220k research + ≈700k verification ≈ 900k–1.1M**. Past ~1.3M the overrun is research nobody asked for — stop and say so rather than economising on the pass that catches trip-breaking defects. Rule 3 caps how deep each agent digs and says nothing about how many you start, which is exactly how a measured run reached **1.18M tokens on a 4-day single-city trip** — 17 agents where 13 was the target, with the overrun entirely in research the traveller never asked for. A second research agent on a domain the first already covered does not make the answer safer; it makes the same answer twice and spends the quota verification needs.
5. **Never challenge a user-confirmed fact.** The adversarial pass is for claims you produced. Verify its *consequences* if they are checkable; do not re-litigate the traveller's own statement.

None of this applies to the verification stage, which is not the place to save money — see that reference's "What not to economise on". It also separates **tokens from minutes**: every budget rule above buys tokens, and a fan-out's wall-clock is its slowest agent, so trimming agents saves tokens and no time at all. What the traveller actually waits on is the round-trip to them. Wrap each phase in `python scripts/trip_timer.py start|stop <phase> --workspace "<ws>" --run <slug>`, naming traveller-facing waits `checkpoint...`, so that claim stops being a guess — nothing in this skill has ever measured a minute.

### Reusable profiles and local deliverables

For a first Travel Buddy use, or whenever no valid reusable profile exists, start the one-time reusable-profile HTML form after explaining its local storage and consent checkbox. Do not silently create a profile: the user must explicitly confirm local storage in that form. If the user declines, do not persist a profile and use a per-trip form only for that active request. Store a consented profile in the user-selected Travel Buddy workspace, which defaults to a `Travel Buddy` folder directly inside the user’s home folder and contains `profiles`, `plans`, and `html`; never put profile data in a shared cloud service by default.

- Use [templates/personal-travel-profile.json](templates/personal-travel-profile.json) and read [references/profile-and-storage.md](references/profile-and-storage.md) before creating, loading, updating, or forgetting a profile. Reuse `digital_travel_access` only as a convenience preference: map/booking apps, services to avoid, normal Google-service access, and non-sensitive booking-access notes; never store account context.
- Initialize a workspace with `python scripts/travel_workspace.py init`; create a consented empty profile only after opt-in with `python scripts/travel_workspace.py create-profile <profile-id> --consent`; validate it before use.
- For the normal guided flow, start `python scripts/start_intake_workflow.py --assistant auto` **as a background/non-blocking command**, and provide the loopback link printed in the terminal. It starts the one-time profile HTML only when no valid profile exists; after save, it starts the current-trip service first and redirects the same browser tab to its prefilled HTML. The terminal prints the second local URL as a fallback. After a valid current-trip submission the service prints `TRAVEL BUDDY TRIP INPUT: <path>`, and **you continue from that file yourself** — under `auto` it deliberately launches nothing while an assistant is already driving the workspace.
- **Background is not a preference, it is the only way this command can work.** The server flushes the link and then blocks in `serve_forever()` until the traveller submits, which is minutes of real form-filling. Run it in the foreground and your own tool call is what holds the link hostage: the URL never reaches the traveller, and the harness's command timeout eventually kills the server mid-fill and takes the unsaved form with it. Use the harness's non-blocking form (Claude Code `run_in_background`, otherwise a backgrounded shell command with its output going to a file you poll), then read the link out and hand it over. Poll that output for `TRAVEL BUDDY TRIP INPUT:` rather than re-running the script — a second run opens a second server on a second port, and the traveller is already typing into the first.

That is the whole point of `auto`, and it reads backwards until you see the incident: it used to spawn a non-interactive child whenever `CLAUDECODE` was set — i.e. it treated *proof that an assistant was already handling the trip* as the signal to start a second one. A measured run produced two plans in one workspace differing only by origin city in the filename, and the unattended one had the wrong origin, a superseded budget cap, no allergy data at all, and a traditional Brauhaus dinner for a traveller with a severe dairy allergy — saved as `verification_status: verified`, so its page carried no warning. `auto` now stands down by default and hands the intake path back to you; it launches a child only on positive evidence of a bare interactive terminal — stdin *and* stdout both a tty, and no `CLAUDECODE`/`CLAUDE_CODE`/`CODEX_THREAD_ID` set — which is the only case automatic continuation was ever for. The first fix tested this the wrong way round, by naming the assistants it knew and treating everything else as a bare terminal: under any other harness — Gemini CLI, Cursor, Copilot CLI, opencode, an SDK agent — `auto` still resolved to `codex` and spawned the second planner, because a list of assistant names is only current on the day it is written and "did a human open this terminal" never goes stale. One residual gap, stated rather than hidden: a harness that allocates a full pty still looks like a terminal, so pass `--assistant none` (or export `TRAVEL_BUDDY_ASSISTANT=none`) if you are in one. Force a detached run with `--assistant codex` or `--assistant claude` when you genuinely want one. Never resume the generic “last” CLI session because it may be an unrelated trip. If multiple profiles exist, ask the user to choose one by ID and rerun with `--profile PROFILE_ID`. Do not ask the user to download, move, upload, paste JSON, or type “continue”.
- When exactly one valid profile exists, the workflow reuses it silently. Do not let that pass unnoticed: **summarize the loaded profile's relevant fields and ask whether anything changed before starting the trip form.** If the traveller wants changes, rerun with `python scripts/start_intake_workflow.py --edit-profile`, which reopens the profile form preloaded with the saved values and then continues to the trip form. A stable default the traveller never saw is a default they never agreed to.
- A saved profile supplies only stable context; it never replaces current dates, party, budget, destination scope, or confirmation of every current traveler’s entry eligibility. The automatic task receives the named trip input and optional profile and begins discovery without waiting for another user message. It is a separate CLI task rather than an unsupported attempt to resume the hidden desktop chat; show its terminal result and saved result/log paths. Use a concise chat intake only if the traveller cannot or explicitly does not want to open the local form, and record that choice in the plan's `intake_context` — `save_trip_deliverables.py` refuses a plan that will not say how its requirements were collected.
- Treat `excluded_places` marked `never_recommend` as hard filters. Treat visited places as diversity context, not a ban, unless the profile says not to revisit. Treat wish-list places as preferences, not commitments. Let the user’s latest request override every saved preference. The intake workflow carries these forward for you: `never_recommend` places prefill the trip form’s exclusion field, and saved dietary needs prefill its dietary field, so they land in the trip intake instead of staying in a profile file the shortlist may never open.
- Never store passport/document numbers or images, credentials, payment data, exact addresses, or private account context. On an explicit “forget” request, delete only the named local profile after confirming the exact file.
- **Final-delivery gate:** A Construction task is not complete until a self-contained final HTML and its source plan JSON both exist in the user’s Travel Buddy workspace. Build the final-plan contract, run `python scripts/save_trip_deliverables.py <plan.json> --workspace "<workspace>" --verification "<report.json>"`, and report the exact `Plan JSON:` and `Final HTML:` paths. Those two lines are the only outward sign the gates ran at all — every check in this skill is a script, and a script runs only when it is called, so a hand-written page bypasses all of them and otherwise looks identical. The saved page now carries the gate stamp itself (`data-gates-checks`, rendered as a visible line in the source register), so a page without one did not come through this path; `validate_trip_html.py` prints a note saying so. Never hand the traveller a page you assembled yourself. That script validates the plan, its internal consistency, the verification report, and the rendered HTML before saving; without `--verification` it refuses to save unless you pass `--unverified`, which both records the gap in the saved plan and prints a **visible "not fact-checked" banner at the top of the page itself** — the traveller books from the page, so a gap recorded only in JSON is a gap they never see. When destination/date/entry/transport essentials are still undecided, label the result **intermediate discovery** and state the one blocker; never mislabel it as a final itinerary or invent a booking-ready HTML.
- **Verification gate:** Structure gates prove the page is well-formed, never that it is true. Before delivering any Construction plan, read [references/verification.md](references/verification.md) and run its verification concurrently: **five truth domains** (`entry`, `transport`, `sights_and_hours`, `booking_and_lodging`, `seasonality`) **plus two network-free auditors** (`consistency`, `completeness`) — seven blocks, and the gate rejects a report missing any of them. The report carries the five in `domains` and both auditors in `audits`, and each block's `claims_checked` is a list of plan pointers that must resolve, not a count. Then resolve every `wrong` and `misleading` finding. The auditors cost the least and find the most: in the measured run they produced 27 of 55 findings and 5 of the 6 criticals, which is why they are required rather than encouraged. Run the five truth domains for Discovery only when a candidate's entry or seasonality could eliminate it. Verification splits into five because the domains share no state, and because one pass asked to check all of them at once gives each a fifth of its attention — which is how a dinner gets booked at a restaurant that closed three hours earlier. Fan them out when the runtime offers it (Workflow or parallel Agent calls in Claude Code, one `codex exec` child per domain in Codex); when it does not, run the five as separate sequential passes rather than one combined prompt. The benefit is concentration, not wall-clock, so sequential-but-separate keeps it.

### Context-resolution order

Resolve every planning choice in this order: the user’s explicit current-trip answer, then a compatible stable profile default only when that current field is empty or unspecified, then researched destination/route feasibility. Never infer how far the traveller wants to go from nationality, residence, language, or currency; `trip_geography.scope` is the current-trip authority. Nationality and residence status answer a different question — what entry a given destination requires — and never set the scope. Use selected current-trip transport modes to select the research and booking branches. Apply saved self-drive, seat, map, and booking preferences only when compatible with the actual destination market and the current-trip selection. If an explicit trip scope conflicts with a named destination, surface the conflict and ask the smallest clarification instead of silently changing either value.

## Work mode

Choose the mode before researching:

| User state | Mode | Required result |
| --- | --- | --- |
| No destination, or only a broad continent | **Discovery** | Generate, filter, and rank destinations. |
| Country/region named but city not chosen | **Constrained discovery** | Compare suitable subregions/cities before planning. |
| Destination deliberately selected | **Construction** | Build a feasible trip plan and budget. |
| Existing plan plus a new constraint | **Incremental replanning** | Change only affected elements and show the impact. |

Do not collapse Discovery into Construction. A user who says “I have seven days and €1,500” needs destination options and trade-offs, not an invented day-by-day itinerary.

### Choose the verification tier here too, from the plan's own fields — never from how thorough you feel

Construction has two tiers, and picking the wrong one is expensive in one direction and dangerous in the other. Decide once, at this table, and say which tier you chose.

**Light — four blocks: `sights_and_hours`, `transport`, `consistency`, `completeness`.** Allowed only when *every* one of these holds: the traveller stays inside their country of residence or the plan's `entry_context.status` is `not_required`; no flights, ferries, rental cars or ticketed rail/coach/ferry legs; `trip.traveler_constraints.allergy_severity` is `none` or `preference` and `max_continuous_walking_minutes` is null; and the trip is three nights or fewer in one city. Roughly 300k rather than 700k. `check_plan_consistency.py` computes this from the plan's own fields, so do not argue with it — read what it printed.

The three that drop out drop out for a reason, not to save money: `entry` re-litigates a fact rule 5 of the research budget forbids re-litigating; `booking_and_lodging` verifies whether dates are sellable and whether search URLs prefill, and a light-tier trip by definition carries no bookable transport product for that to bite on — the moment a `ground_transport` card exists it asserts a fare, an availability status and a search URL, which is exactly that domain's subject, and the tier is lost; `seasonality` matters where the plan schedules a sunset or depends on a seasonal service, and a two-night city break with indoor anchors does neither. The four that stay are the ones that caught real defects: opening hours are weekday-keyed and wrong hours close a door in the traveller's face, a city break is mostly local transport, and the two auditors need no network at all while producing, in the measured run, 27 of 55 findings and 5 of the 6 criticals.

**Full — all seven blocks.** Everything else, and specifically: any flight, ferry or rental car; any entry question that is not already settled; a severe allergy or a stated walking cap, because those are the constraints whose violation is a medical or a stranding risk rather than a disappointment; four nights or more; more than one city.

**When in doubt, full.** The light tier is a floor for the genuinely simple trip, not a default — and a plan that qualifies for it today stops qualifying the moment a flight or an allergy enters, so re-check the tier after any replan.

## 1. Collect the initial profile progressively

**The loopback HTML form is the intake path. Chat questioning is not an alternative you may choose — it is a fallback the traveller chooses, by declining the form.** For a first-time traveller, or any traveller without a valid reusable profile, your first action is to start `python scripts/start_intake_workflow.py --assistant auto` **in the background** (see the background rule above — run in the foreground it blocks until submission and the link never reaches the traveller), give the traveller the printed link, and wait for its sequence: one-time profile form when needed, then current-trip form, then `TRAVEL BUDDY TRIP INPUT: <path>`. Because you are an assistant already driving this workspace, `auto` will *not* launch a discovery task for you — that path is yours to continue, from that file, in this session. Do not repeat the questions as a long prose questionnaire or instruct the user to type “continue”.

None of these is a reason to switch to chat, and each has been used as one: the form feels slower; you already have most of the answers; the traveller seems in a hurry; you would rather not manage a background process; chat feels more natural in this harness. **Offering chat instead of the form, or asking "form or just tell me here?" as if the two were equivalent, is itself the defect** — the traveller cannot weigh what the form does that chat does not. Skipping it loses the intake server's outright rejection of document, payment, password and exact-address fields; its refusal of a destination scope that contradicts the work mode; the profile's `never_recommend` exclusions and dietary needs prefilling into this trip's answers; and the saved intake file that `check_shortlist_consistency.py --intake` computes the hard-constraint roster from — without it that gate refuses to run at all unless you pass `--no-intake`, which stamps a `NO INTAKE` banner saying the shortlist was never tested against the traveller's stated constraints. If you genuinely cannot run a background command in this harness, say exactly that to the traveller and let **them** pick; do not decide it for them by never mentioning the form.

Chat intake is legitimate on exactly two conditions: the traveller declined the form (or declined profile storage), or they already supplied the information another way. Both are recorded, not remembered — the plan carries `intake_context` naming the method, and for `chat_fallback` the traveller's **own words** declining it plus the date. `save_trip_deliverables.py` refuses to write any plan whose `intake_context` is missing, invented, or unevidenced, and there is no bypass flag, because the three methods already cover every legitimate route. Retain chat-collected facts only for the active task.

### First-turn essentials

When a consented profile is available, first summarize only the relevant saved constraints and ask whether anything changed. Do not re-ask confirmed stable fields. The HTML trip form must collect or confirm these seven fields before claiming a destination is a strong fit. First ask one yes/no: **does this trip need a visa the traveller does not already hold?** Do not ask "domestic or cross-border": geography is a bad proxy for entry burden, and it misfires for exactly the travellers it matters most to — someone holding a member-state residence permit crosses into the Schengen area with no visa at all. Do not ask about visa *effort* either. Effort only matters to someone who still has to apply, and asking it first spends the expensive research on a traveller whose own passport had already settled the question.

The two answers are different constraints, not two points on one scale:

- **No — I can already enter what I want to enter.** Collect two fields and skip the rest of the entry panel: `feasibility.held_entry_documents` (what they enter *on* — a held multi-entry visa, a residence permit, visa-free, or simply being at home), and `passport_validity_status`, which is **still required here**. A held visa does not make an expired passport board a plane, and this answer also covers travellers who are leaving the country, so the domestic opt-out (`not_applicable_domestic`) must be chosen rather than assumed. Set `entry_status: traveler_asserts_can_enter`. The document string also constrains destinations: candidates are limited to what it actually admits them to, so this answer is a hard filter on the shortlist, not a free pass.
- **Yes — I am willing to apply.** Now the effort sub-question is worth asking (e-visa/visa-on-arrival only, or a full application), and only now collect per-traveller identity and a yes/not-sure/needs-renewal passport-validity confirmation.

The reason this ordering matters is measurable. A real run researched a complete Japan visa procedure for a PRC passport — consular jurisdiction, designated-agency rules, fee schedule, processing times, roughly 100KB of output — and the traveller's next message was "我有签证". One yes/no, asked first, deletes that entire branch. Entry burden follows from **destination country × traveller status**; status lives in the profile (`identity_and_language.residence_status`), not in a per-trip question. Always collect maximum one-way journey time, applicable climate constraints, and transport modes—including high-speed rail, conventional/night rail, intercity bus, ferry, flights, and self-drive where relevant. Accept rough answers and mark them as approximate.

1. **Starting point** — current city and country; acceptable departure airports or willingness to use a nearby airport. A city is enough; never ask for an address.
2. **Travel window** — exact `start_date`/`end_date` when the traveller has them, otherwise month/season plus duration; date flexibility; and any fixed commitment the trip must fit around (a return-to-work date, a wedding, an event). Exact dates are authoritative: a Construction task cannot start without them, so never downgrade a supplied date pair to a month.
3. **Travel party** — solo/couple/group, number and relevant ages; any mobility, health, child-care, or accessibility needs; and dietary or religious food restrictions. Dietary needs are a hard constraint on every meal recommendation, not a nicety: never leave `feasibility.dietary_or_religious_needs` empty by assumption.
4. **Budget** — always collect a **per-person** range, currency, target versus absolute cap, and whether it includes transport, lodging, food, activities, insurance, and visas. Derive a party total only as a separately labeled calculation; never mix it into the user’s stated range.
5. **Destination scope** — ask which is true: a fixed country/region, an approximate continent, or no destination yet. A `fixed` or `anchored` scope must name at least one actual place; a fixed scope with no named destination is blocked, not a Construction task.
6. **Trip purpose** — leisure, sightseeing, food, outdoors, family, visiting people, a celebration, or work-adjacent. One answer changes what a good day looks like more than most preference fields.
7. **Experience direction** — ask the user to choose **natural**, **human/cultural**, or **a balance**, then select 2–4 specific scenery/activity types and rank the top two. Use the taxonomy in [references/initial-intake.md](references/initial-intake.md); allow free-form answers.

After the form returns or the user answers, read the saved intake and summarize it in a compact “What I heard” block. Label unknowns and assumptions. Treat the saved budget range as per-person; show any party total only as an explicit calculation. Do not silently turn “October” into fixed dates or “Europe” into a visa-safe region.

### Second-turn filters

Ask these only when they can change the short list or feasibility. Prioritize the unknown with the greatest expected impact.

- When the trip may leave the country of residence: each traveller's passport nationality, country of residence, residence-status category, and whether every traveller’s passport stays valid at least six months past the trip (`valid_through_trip`, `not_sure`, or `needs_renewal`); visa tolerance, which is derived from the scope answer rather than asked again. Ask for the status category, never a document number, image, or expiry date. Do not request any of it, or treat it as a blocker, when the traveller is staying inside their country of residence.
- Maximum one-way travel time, tolerance for connections/overnight flights, preferred cabin/airport, and reluctance to drive.
- Climate and season: preferred temperature, beach/swim need, rain tolerance, snow/heat avoidance, and whether weather is a deal-breaker.
- Travel rhythm: slow/deep versus multi-stop, rest days, nightlife, early starts, guided tours, and willingness to self-drive.
- Ground transport and delivery: public transport versus self-drive, rental-car need, driving-license/age constraints if relevant, luggage, and the preferred final-page language/currency.
- Regional service access: usual map and booking apps, any services to avoid, whether Google services work normally without a workaround, and non-sensitive booking limitations (for example “avoid channels requiring a local phone”). Ask only when the destination or accessibility is not already clear; never request account or payment information.
- Comfort and risk: lodging level, crowd tolerance, language independence, safety concerns, dietary requirements, and connectivity/work needs.
- Explicit avoid-list: activities, environments, countries, transit patterns, or costs the user does not want.

When several details are missing, ask at most three high-impact follow-ups in a turn. If the user prefers not to answer, proceed with conservative assumptions and say how they may alter the ranking.

### Convert answers into decision-ready fields

Record each value as one of `hard`, `strong_preference`, `nice_to_have`, `avoid`, `unknown`, or `assumption`. Preserve the user’s original wording alongside the normalized value. Start from [templates/trip-profile.json](templates/trip-profile.json) for the active-trip structure; merge consented stable values from the reusable profile only after stating the applied fields.

Read [references/initial-intake.md](references/initial-intake.md) before designing a multi-question intake or interpreting the natural/cultural preference branches. Read [references/regional-service-routing.md](references/regional-service-routing.md) before selecting map, transport, or booking providers.

## 2. Discover and evaluate destinations

For Discovery and Constrained discovery:

1. Generate a diverse candidate pool from the normalized profile. Do not prematurely optimize around famous destinations or one transport hub.
2. Apply hard filters first: calendar feasibility, entry feasibility, reachable travel time, essential accessibility needs, clear climate deal-breakers, and a conservative budget baseline.
3. Research each surviving candidate using current sources. Obtain comparable evidence for transport, typical lodging/food/local transport costs, seasonal conditions, entry requirements, safety/health notices where relevant, crowding/seasonality, and fit with the user’s requested experiences.
4. Normalize price estimates to the user’s currency and state the date range, party size, inclusions, and uncertainty. Do not compare a flight-only figure with an all-in figure.
5. Score only candidates with sufficient evidence. Keep the score explainable, retain uncertainty, and record why excluded options were removed.
6. Present only the best 3–5 options, unless the user explicitly requests the broader pool. Include one credible alternative with a different trade-off when useful.

### Constraint-conflict exit

If no candidate survives the hard filters, stop before scoring. State that no recommendation is currently feasible, name the smallest set of conflicting constraints, and ask the user which one may relax. Offer conditional examples only as “possible if X changes”; never disguise an infeasible destination as the winner.

**Write the shortlist as JSON — [templates/discovery-shortlist.json](templates/discovery-shortlist.json) is the envelope and [templates/destination-evaluation.json](templates/destination-evaluation.json) is one candidate inside it — and run `python scripts/check_shortlist_consistency.py <shortlist.json> --intake <workspace>/plans/intake-<stamp>-<slug>.json` before presenting it.** `--intake` is not optional: with neither it nor `--no-intake` the gate refuses to run, because omitting it used to print an accurate note and **exit 0**, and an exit 0 is what an assistant reads. It computes the hard-constraint roster from what the traveller actually declared and requires every candidate to answer each one — the check that catches a winner that cleared the four constraints someone remembered and was never tested against the fifth. `--no-intake` runs without it when no intake file exists and prints a `NO INTAKE` banner; when you use it, say so as you present the shortlist and never describe a winner as having cleared the traveller's requirements. A roster written by hand into the shortlist cannot do this — it reports full coverage on exactly the run that motivated it. Declare `outcome.state` (`shortlist` / `constraint_conflict` / `blocked`) on every Discovery artifact: an unfinished filter and a real conflict produce the same empty pass set, and only one of them justifies asking the traveller to give up a requirement. A shortlist is a *comparison*, and its worst defects live between candidates rather than inside one: each record can be impeccable while the ranking is meaningless — one figure priced per person beside one priced for the whole party, or one covering flights beside one covering everything. The traveller picks the smaller number and it was never the smaller trip, and nothing inside either record is wrong. So every priced candidate declares `cost_estimate.cost_basis: per_person` beside its own figure rather than relying on one declaration at the top, states the same currency and party size as the shared `trip_context`, and accounts for every category in `trip_context.budget_scope` — priced, or declared in `not_applicable_categories` / `unverified_categories` **with a reason**, because a silently absent category is indistinguishable from one nobody priced. A candidate shown without a figure gives `not_priced_reason`. Arrival modes (flight, rail, ferry, bus, car) count as one cost surface, so a rail-reached candidate compares against a flown one with no declaration from either. The gate also refuses a winner that fails a hard constraint or whose filter never ran, and a winner named when no candidate was feasible — an empty feasible set is an outcome, not a scoring error.

Read [references/decision-and-research.md](references/decision-and-research.md) **before the first research call of either mode**, not only before scoring: besides the scoring and evidence rules it carries the record-once habit that decides whether a page gets opened once or twice, and a Construction task that skips it meets every required field at the end, when the pages are closed. Use it for scoring, research, evidence, and output rules. Start each candidate record from [templates/destination-evaluation.json](templates/destination-evaluation.json).

### Decision-support response

Lead with a recommendation, then a compact comparison containing:

- destination and fit/confidence;
- comparable estimated all-in cost and key assumptions;
- strongest reasons it fits;
- principal compromises or risks;
- important evidence and its date;
- the one condition most likely to change its rank.

Explicitly answer “why this, not that?” and “what was filtered out, and why?” when those questions matter. Do not hide visa, weather, transport, or budget compromises behind a single score.

## 3. Construct the trip only after the decision is ready

Once a destination is selected or intentionally fixed, research and assemble transport, lodging areas, local mobility, activities, daily pacing, meals, reservations, and a line-item budget. Ensure that every daily route is geographically and physically feasible. A city stay of three or more days must include at least three destination-specific experience anchors across at least two days when they fit the traveller’s stated interests; do not substitute a list of famous sights for real fit.

Set a regional service context before producing a live link: trip market, normal Google-service access, primary map provider, checked alternatives, local transport authorities, booking-platform rationale, and a non-sensitive access check for every booking category shown. A mainland-China route uses a verified Amap primary link unless the user asks for and can access another verified local provider; do not render Google Maps as its default. For multi-country trips, select by route/segment and show the provider change.

Separate:

- **essential bookings / timing-sensitive items**;
- **recommended options with price ranges**; and
- **flexible, low-commitment activities**.

Use live sources for bookable or time-sensitive claims. If live data is unavailable, give a planning range and a verification checklist, not a false confirmation.

## 4. Deliver a booking-ready final HTML page

After the destination and trip inputs are decision-ready, create one self-contained, responsive HTML page rather than an unstructured prose itinerary. A fresh skeleton fails its own gate on purpose, and the errors are a **worklist, not a defect
list**: one line per card nobody has filled in yet, plus the walking figures that have to be
derived. A four-day skeleton reports about thirteen. They used to be thirty-eight, because the
content rules ran on placeholder values and reported things like *"rated 0/5, below the 3.5/5
floor. Replace it"* about a restaurant nobody had chosen — an error that sends the author hunting
for a problem that does not exist is worse than no error, because it costs a round trip and
teaches distrust of the gate. Content rules now stay quiet on a card that still carries a `TODO:`
marker, and `validate_trip_html.py` refuses to ship one regardless, so nothing is lost.

**When the plan follows an intake file, start it with `python scripts/new_plan_skeleton.py --from-intake <workspace>/plans/intake-<stamp>-<slug>.json > plan.json`** rather than retyping the flags. It carries across origin, dates, party, currency, `budget.cap_per_person`, and the two *list* fields of `trip.traveler_constraints` (dietary needs, mobility notes), printing every field it copied and every one it could not derive. **It does not set `allergy_severity` or `max_continuous_walking_minutes`** — the intake collects those as prose and nothing converts a sentence into a severity enum or a number, so the skeleton leaves them at `none` and null and says so on stderr. Type them yourself before delivering: the verification tier reads exactly those two fields, and a plan that leaves them at their defaults while its own prose says 「anaphylactic」 is a plan claiming there is nothing to avoid. That matters more than the typing it saves: built from flags alone, `cap_per_person` stays null and the budget cap-overrun check has nothing to compare against, and `max_continuous_walking_minutes` stays null so every per-leg and per-activity walking check silently no-ops — the traveller's three most dangerous constraints collected by the form and then measured by nothing. Without an intake file, the flag form still works: `python scripts/new_plan_skeleton.py --start <date> --end <date> --origin <x> --destination <y> --language <zh|en> --currency <c> --travellers <n> --mode <public-transit|self-drive> --stops-per-day <k> > plan.json`. Then fill it. The skeleton already obeys the structural rules a template cannot express — segments mirroring `stops_in_order` by exact string equality, a non-empty `service_or_line` on walking legs, the booking-access enums, a breakfast card on the departure day, distinct flight review_urls — so the render loop is spent on facts instead of rediscovering the contract; one measured run lost three edit-render round-trips and 21 structural errors to that. Every unfilled value is a `TODO:` marker that `validate_trip_html.py` refuses to ship, so a faster start cannot become a hollow page. Use [templates/final-trip-plan.json](templates/final-trip-plan.json) as the field-by-field data contract and [assets/final-trip-template.html](assets/final-trip-template.html) as the structural starting point. Prefer the safe renderer for a repeatable result: `python scripts/render_final_trip_html.py <plan.json> <final.html>`. For every completed Construction task, persistent delivery is mandatory: run `python scripts/save_trip_deliverables.py <plan.json> --workspace "<workspace>" --verification "<report.json>"` (or `--unverified` for a deliberately labelled draft — the script refuses outright without one of the two) and report both output paths. Do not end a completed trip-planning task with prose alone.

The page must include a trip summary, comparable budget, every day’s timed route, accommodation, activities, map representation, source register, and only verified outbound links. For each required purchase, show browse-and-choose options rather than purchasing:

When `trip.language` is Chinese, render every renderer-owned heading, action label, status, unit, and fallback in Chinese; when it is English, render those elements in English. Retain another language only for a proper name, platform name, or deliberately user-supplied/source text. `validate_trip_html.py` enforces this: on any page whose `<html lang>` is not English it fails on renderer-owned English, including enum values printed as visible text. That is why `plan_status`, `ticket_status`, `budget.breakdown[].category`, `budget.included_categories`, `budget.unverified_categories`, `dining[].meal`, `trip.arrival_transport_mode`, and `transport_preference.mode` are closed enums rather than free text — an arbitrary category string cannot be translated, so it would leak. Use `budget` categories from `flight, rail, intercity_bus, ferry, rental_car, fuel_tolls_parking, accommodation, food, local_transport, attractions, tours_and_activities, insurance, visa_and_entry, shopping_and_misc, contingency`, and booking states from `idea, researched, held, booked`.

When entry feasibility was assessed, put the conclusion on the page through the optional `entry_context` block (`status`, `summary`, `traveler_basis`, `source_url`, `checked_at`). State the basis as a status category, never as a document detail: a traveller rereading the page a month later needs to know *why* no visa was required, not merely that none was.

The page must also render what the plan already collects, because a required field that is never displayed is research the traveller paid for and cannot see: each day’s `route.fallback_plan` and `route.walking_burden`; each flight’s `material_conditions`; any `single_option_reason` explaining why only one option is shown; `budget.unverified_categories`; `plan.assumptions`; and `regional_service_context.booking_platform_selection_note`. Group booking options by type rather than mixing flight and hotel cards in one grid, and give the page a sticky in-page navigation with one link per day.

- flights, when air travel is used, compared on like-for-like cabin, bags, connection, and fare conditions; normally show two candidates, with a researched reason if only one exists. Show each candidate’s outbound and return flight/service identifier, local times, duration, stops, transfer burden, price basis/status/check time, availability status, and airport-to-city transfer note. Render a verified external **round-trip search** button whose machine-readable prefill fields include origin, destination, outbound/return dates, and travellers;
- **rail, coach or ferry, whenever a ticketed intercity leg exists** — in `booking_options.ground_transport`, held to exactly the flight standard because the traveller asks the same questions: which service, when it leaves and arrives, how long, how many changes, what the fare lets them do, whether it is still sellable, and how they get from the arrival station into town (`station_transfer_note`, the ground analogue of an airport transfer, so a cheap fare cannot hide an impractical arrival). Render a verified round-trip search button whose prefill fields carry origin, destination, both dates and travellers. This category exists because a rail trip's largest and most time-sensitive purchase previously had no card at all: the page compared three hotels and offered no way to reach, price or availability-check the train. `validate_plan` derives the requirement for you when `trip.arrival_transport_mode` is `rail`, or is `road` between two different places on public transit; a mid-trip city hop on a fly-in trip is invisible to that test, so pass `--require-booking-type ground` yourself in that case. Carrying the card also costs the plan the light verification tier, on purpose — see the tier table above.
- normally two to three suitable accommodation options in the same stay group, compared on dates, guests, room basis, taxes, cancellation, exact area, airport/planned-area access, current price basis/status, and availability. A single option needs a researched reason. Render a verified platform search button with destination, check-in/out, guests, and rooms already included. Treat the departure day as checkout or no overnight stay, never an implied extra hotel night. Use Booking.com when it is an appropriate researched platform, but do not make it mandatory or invent its query URL. **Scope that search to the property, not to the city** — put the property's own name in the destination field so the button lands on the one hotel with the trip's dates already applied. A city search satisfies the prefill rule while answering none of the questions the card exists to answer, and the cost is not tidiness: a delivered plan gave both of its hotels a byte-identical Booking.com city search, so no button ever opened either property on the platform that sells it, and nobody saw that one cost **€1,256** for the week — over the traveller's entire budget cap, before flights — while the other had **no availability on those dates at all**. Two unbookable recommendations shipped because the link that would have exposed them did not exist. Do **not** hand-build a property path instead: Booking's slugs are underivable (Hotel Cristina by Tigotan lives at `/hotel/es/las-palmas.html`), and the bare `/hotel/<cc>/<slug>.html` returns an error page unless it carries the session parameters this skill forbids embedding — a property-scoped *search* is the form that is stable, shareable and tracker-free. Check availability and the total-for-the-stay on that page before the card claims either;
- official attraction ticket links only for attractions that require booking or paid entry;
- rental-car options only when self-driving is selected, with pickup/dropoff place and time, vehicle/driver/insurance/fuel/restriction terms, price basis/status/check time, and a user-opened search link whose pickup/dropoff details are prefilled; otherwise public-transport directions, transfer time, and a researched fare/range.

For every shown booking category, expose its access status (`available`, `limited`, or `unknown`) and non-sensitive requirement/caveat in the page's booking-access check. Treat a visible search result as a shopping lead, not evidence that the traveller can complete the booking. For rail, intercity bus, ferry, transit, attractions, and rental cars, verify the official/operator conditions that can alter ticket eligibility, payment/deposit, required local phone, or licence feasibility; never ask the user to supply credentials, payment details, or document images.

### The plan must carry what the traveller asked FOR, not only what they cannot have

`trip.traveler_constraints` and `trip.traveler_preferences` come off the same intake form, and for
a long time only the first survived into the plan: the skill remembered the allergy and forgot the
reason for the trip. Everything downstream inherited that. The renderer counts experience anchors —
three minimum on a multi-day city trip — but nothing ever asked whether an anchor *answered*
anything, so rewriting every one of them as "somewhere / no particular reason" produced zero
findings from any gate. "Do not substitute a list of famous sights for real fit" had a headcount
behind it and nothing else.

So carry `ranked_must_haves`, the natural and cultural subtypes, the pace and the avoid list into
the plan — `new_plan_skeleton.py --from-intake` now does it — and **point an anchor at each
must-have through `satisfies_preference`, quoting the traveller's own words.** Only the ranked
must-haves bind; the softer preferences produce a note, because "prefer mild warmth" is a quality
of a choice already made rather than a thing the days must contain, and a rule that failed on it
would fire every winter. When the season or the place genuinely cannot deliver a must-have, say so
in `unmet_preferences` with the reason — that is a different act from ignoring it, and the page
shows the traveller which of their own words each anchor is answering, because they are the only
reader who can tell whether "old-town lanes" is what they meant.

Every entry in `avoid_list` needs an `avoid_list_handling` entry saying what keeps it out. Asked
rather than pattern-matched: deciding from a plan's own fields whether it contains a red-eye, a
crowd or a long transfer needs a different fact for every avoidance a traveller might write, while
asking how each was honoured needs none.

All of it renders, and that had to be fixed rather than assumed. Measured with canary strings run
through the whole save path: `avoid_list`, every `avoid_list_handling.how_avoided`, and the natural
and cultural subtypes were present in the plan JSON and reached the HTML **not once** — the gate
demanded an answer and the page never showed the traveller it had been given. They now render in a
`What you asked for` panel beside the constraints one, which is the same principle this skill
already applies to ratings: stored and never shown is the same defect as never gathered. When you
add a field the traveller stated, check the rendered page for it rather than the JSON.

### Write the page like a person who went there, not like a form being filled in

The prose in the delivered plans is already specific and reason-led — no "vibrant tapestry", no
"nestled in the heart of", every rationale tied to a real opening time or the traveller's own
walking limit. It still reads generated, and measuring it showed why. The tell is not vocabulary,
it is **sameness**.

- **Half the narrative fields were built as fact — dash — significance.** Measured: 50% of them.
  Wikipedia's [Signs of AI writing](https://en.wikipedia.org/wiki/Wikipedia:Signs_of_AI_writing)
  lists em-dash overuse for exactly this reason, alongside the rule of three, "not only X but
  also Y", and copula avoidance ("serves as", "boasts", "stands as" where "is" was the word).
  The dash is a good device; it is the *default sentence shape* that reads mechanical.
  `check_plan_consistency.py` refuses a plan where more than 35% of narrative fields lean on it.
- **The same sentence appeared twice under two headings.** `focus` and `route_logic` came back
  byte-identical on 4 of 5 days of one shipped plan and 5 of 8 of another, and `fallback_plan`
  duplicated `contingency` on nearly every day. Each field alone looked filled in. Now refused
  within a day; across days it is a note, because two days can honestly share a wet-weather
  fallback.

So: **vary the shape.** Some rationales are one blunt sentence. Some are two. Some name the
constraint first and the consequence second, some the reverse, and some just state a fact and
stop — not every line owes the reader a moral. Cut the closing flourish that explains why what
you just said matters; if it needed explaining, the sentence was wrong. Where two fields want the
same sentence, one of them has nothing to say, so leave it out rather than pad it.

What not to do: swap the banned words for synonyms. A word list is satisfied by "bustling" →
"lively" while the writing stays exactly as hollow, and it fires on the traveller's own phrasing.
Structure is what these checks can see honestly, and structure is what actually reads wrong.

### Illustrate the page, but never with a picture you cannot vouch for

The page is read on a phone in a city the traveller does not know, and it was 96KB of unbroken
text. Two things fix that, and they are not the same kind of thing.

**Figures are free and always on.** `plan_visuals.py` draws each day's stops at their true
relative positions, minutes on foot per day, budget composition against the cap, and where the
day's fixed points fall on a clock — all from numbers the plan already carries, so they need no
network, no licence and about 15KB. They also answer the questions text cannot: a list of stops
gives you the order, only a map gives you the shape.

**Photographs are earned, and optional.** Run
`python scripts/fetch_plan_imagery.py <plan.json>` **during the verification stage, not after
it** — it is network-bound and independent of every verification block, so it costs no extra
wall-clock when it runs alongside them, and about 13 seconds when it does not. It fills only the
destination hero and the experience anchors; restaurants are left alone because Commons coverage
of an individual restaurant is near zero and the only way to fill those slots would be a generic
photo of food, which is decoration pretending to be information.

**A photograph that cannot be verified is not added.** Coordinate proximity proves "near the
place", never "of the place": a real search for "Alicante Central Market" matched the article
*Bombing of Alicante*, 400 m away, whose lead image genuinely is the market — and that provenance
would have been printed under the photo. So the article's title must also be about what was
asked for, a search that falls through to the destination's own article is refused, and no file
appears twice. When a slot cannot be filled to that standard it stays empty. Never substitute a
stock image, and never hot-link one: the page must keep working on a phone with no signal, which
is exactly when it is needed.

### A map or venue URL parameter is a geocoder query, not a caption

This is the highest-severity defect the skill has shipped, it is invisible to every structural
gate, and it stays inline for that reason. A delivered plan wrote its own display labels into its
Google Maps URLs — `origin=酒店（拉斯坎特拉斯海滨）`, literally the word "hotel" plus a description,
and `destination=圣安娜广场：主教座堂钟楼与哥伦布之家`, which carries no place name in any script a
Spanish geocoder reads. Google resolved the first to **Taiwan** and offered a 65-hour drive to the
Canary Islands; the second returned "destination not found". Six of that plan's fifteen distinct
endpoints could not geocode, four contained no Latin-script token at all — and
`check_link_targets.py` reported all 25 map links `ok`, because the host was right, the status was
200 and no parameter had been dropped. Nothing measured whether an endpoint named a place.

So: **the string a button shows and the string its URL carries are two different fields, and one
may never be copied into the other.** Write the endpoint the way you would type it into that
provider's own search box.

- **Coordinates, always.** `origin=28.1025,-15.4135` cannot mis-geocode, is language-independent,
  and returns real transit and walking directions. Record `lat,lon` for every stop as you research
  it — the place page that gave you the venue's rating and opening hours put the pair in its own
  URL. Free text is refused outright, and the reason is that the first version of this rule only
  *warned* about it: a plan rebuilt with the original captions and one line changed passed clean.
  A name sometimes resolves (`Mercado de Vegueta`) and sometimes lands on another continent
  (`酒店（拉斯坎特拉斯海滨）`), and no offline check can tell those apart — only a geocoder can, and
  it is not in the gate.
- **The coordinate order comes from the provider, never from the numbers.** Google, Apple and
  OpenStreetMap read `lat,lon`; Amap reads `lon,lat,name`. Guessing by range was tried and broke
  the one market this skill mandates a non-Google provider for: Ürümqi written correctly as
  `87.6168,43.8256` was read as latitude 87.6 and reported 4,946 km away, and an author who
  followed the error message and "fixed the order" got a green gate with every button pointing at
  the Arctic. Kashgar and Shigatse were out by 4,439 km and 6,691 km the same way.
- **The provider must be one the traveller can open where they will be standing, and this is a
  separate failure from where the link points.** A link can carry perfect coordinates in the right
  dialect and still be useless. The renderer has long refused a Google map link on a
  `mainland_china` plan, but only for three route fields and only on an exact market string, which
  left the trip's own top-level map button, every `venue_url`, every booking URL, and any market
  spelled `中国大陆` outside it. `check_link_targets.py` cannot close that either: it asks whether
  a host answers *the machine running the check*, and that machine is never inside the blocked
  market. So
  `regional_service_context` is now binding rather than decorative: fill
  `destination_service_market`, and set `google_services_access` to `available` or `unavailable`
  after actually establishing which — `unknown` is refused once the plan ships Google links,
  because it means nobody checked a button the traveller is being asked to press. A plan that
  declares a mainland-China market must declare Google `unavailable`, and may then carry no Google
  link at all. Mixing map providers is allowed but must be a decision: write why in
  `primary_map_exception_reason`, a field that existed in the contract for three versions while no
  check read it.
- **Declare `trip.destination_coords`** — one object, or a **list of them for a multi-city trip**,
  since each endpoint is judged against the nearest base. New York plus Los Angeles is 3,936 km
  apart and Beijing plus Ürümqi 2,411, so a single anchor rejected trips that were perfectly real. The leg-length rule is *relative*, so it cannot see a
  consistently reversed pair: writing `lon,lat` at both ends of a Las Palmas leg leaves the points
  4.73 km apart instead of 4.70 while moving every pin to southern Africa. One absolute reference
  turns every endpoint check from "do these two agree" into "is this where the trip is".
- The venue link on a dining card is the same defect in a second field: `venue_url` must be a place
  lookup keyed on the venue's **real registered name**. A plan shipped `query=酒店自助早餐（Hotel
  Cristina by Tigotan）` and `query=Puerto de Ons` for a restaurant Google lists as *Restaurante
  Ons* — one searches for the phrase "hotel buffet breakfast", the other for a name that resolves
  nowhere.
- `route_map_scope: "multi_stop"` prints the button as a full-day route. It is only true when the
  URL carries every intermediate stop as a waypoint. Eight days of one plan claimed it while
  carrying two endpoints; if you have no waypoints, the scope is `primary_leg`.

When geography genuinely forces a long way round, say so in the segment's `detour_reason` and the
leg passes. The Grand Canyon rims are 18 km apart and 350 km by road; a Norwegian fjord crossing
runs 5.0x its straight line — and a leg whose endpoints pointed at the wrong pair of stops ran 5.1x.
No ratio separates those, so the author does, in one field.

`check_plan_consistency.py` now fails on the arithmetic rather than the wording: the straight-line
distance between a leg's two coordinate endpoints cannot exceed the `distance_km` that leg claims
(Taiwan→Gran Canaria is 12,537 km against a declared 6.2). It also lists every free-text endpoint
for you to open, because only a geocoder can tell a real name from a caption — read that list.

For each day, render an accessible, clearly labeled **schematic** route map (not for navigation), a verified full-day directions link, and a separate verified map button for **every route segment** (for example hotel → station, station → attraction). A route button must encode the actual endpoints and primary mode, never a POI page; mainland-China Amap buttons must use the documented `uri.amap.com/navigation` URI with `from`, `to`, and `mode`. Choose one researched primary mode rather than “metro/bus/taxi (choose one)”; show the alternative only as a fallback. Label each button with the actual provider (for example “在高德地图打开此路段”), plus only a checked alternative when useful. For self-drive, include the overall driving sequence, distance/time, likely toll/fuel/parking considerations, and rental-car links. For public transport, include the operator/line, boarding or exit instructions, transfers, walking burden, service caveats, time, fare basis, and fallback.

For every full sightseeing day, add researched lunch and dinner cards; arrival/departure days include the relevant realistic meal. Each card must name a specific venue, style, area, price per person, queue/reservation note, rationale, safe venue link, and a backup when material. A restaurant’s POI link is permitted only as a venue reference, never as a route button.

**A venue with no quality signal is a taste assertion, not a finding — and the schedule is a claim about opening hours.** Both halves stay inline because both failed silently on a delivered plan whose every gate was green. It shipped a dinner at *El Chiringuito del Sur*, which returns no listing on Google, TripAdvisor or any Canarian directory — it came from a blog listicle and does not appear to exist. It scheduled lunches at 13:15 and 12:30 at two restaurants that do not open until 20:30 and 20:00. It priced a farewell dinner at €55–90 where the venue bills €100+, and it keyed a map button on "Puerto de Ons" for a restaurant Google lists as *Restaurante Ons*.

So every dining card carries:

- `rating_value` with its `rating_scale` (5 or 10 — a bare 4.4 is not comparable between Google and TheFork), `rating_count`, `rating_source`, `rating_url`, `rating_checked_at` — or `rating_status: "none"` plus a reason, which is the honest answer for a market stall or a hotel breakfast. The count is required beside the value because 4.8 from 12 reviews and 4.3 from 2,000 are different claims. Below 3.5/5 fails; below 4.0 is reported and needs a sentence saying why it still earns the evening.
- The venue's **registered name**, the one the map provider indexes — verify it by opening the place page, which also hands you the rating, the price band, the address and the hours in one read.
- `hours_status` of `verified` or `researched` whenever the card names a `time_window`. Putting a meal on the clock *is* the claim that the venue is open then; `unverified` beside `13:15–14:30` is that claim with its evidence deleted, and it reads as researched to the traveller and as compliant to the gate. Verify the hours for that weekday or drop the venue.
- A backup that is a **named venue** whose own hours cover the same slot, not a category like "长廊沿线餐厅". One plan's lunch backup opened at 16:30.

Below the floor is a decision, not a wall: write `rating_below_floor_reason` (or
`guest_rating_below_floor_reason`) and the card ships. The only place in town serving a dietary
need, a legendary stall whose score is all queue complaints, the village's one accessible room —
those are real answers. The reason has to be its own field rather than a sentence in the rationale,
because the message used to promise that escape while no code read it: the honest author who wrote
the justification was rejected anyway, and the one who flipped `rating_status` to `"none"` walked
straight through with the low score still in the card. Both halves are now enforced.

Hours have no equivalent escape, and the asymmetry is deliberate. A market genuinely has no single
score, so `"none"` is an honest answer about a rating. Nothing is an honest answer about hours once
the card names a seating time — a traveller standing at a closed door is not an information gap.

`check_plan_consistency.py` enforces all of this; it cannot tell you a venue is good, only that you never looked.

**A hotel is judged the same way, and for longer.** Somebody sleeps there for a week, so
`guest_rating_value` with its `guest_rating_scale` (Booking and Agoda publish out of 10, Google and
TripAdvisor out of 5 — a bare 8.5 means nothing without it), `guest_rating_count` and
`guest_rating_source` are required, or `guest_rating_status: "none"` with a reason for a property
too new to have reviews. **Below 7.0/10 fails**: on Booking's own published wording 7 is "good" and
6 is "pleasant", which is the polite end of the scale where the complaints begin. Between 7 and 8 is
reported rather than failed, and needs a sentence in `selection_rationale` saying what makes it
worth a week of nights. The score costs nothing extra — it is printed on the same page you opened to
read the price and check the dates are sellable.

Neither floor can tell you about **the reviews underneath the average**. A 4.3 from 3,000 diners
hides 300 unhappy ones, and whether that matters depends entirely on what they were unhappy about:
"slow service" is noise for this traveller, "a 20-minute walk from the nearest bus stop" is
disqualifying for one with a stated walking limit. No gate can read that. Skim the recent negative
reviews of anything you are about to recommend for a whole week or a farewell dinner, and if the
complaints land on a constraint this traveller actually stated, say so on the card or pick something
else.

Read [references/booking-html-output.md](references/booking-html-output.md) before researching booking links, using OpenCLI, or producing the page. Run `python scripts/check_plan_consistency.py <plan.json>` before rendering: it decides in code what prose cannot be trusted to hold — route totals summed from their own segments, walking figures derived rather than asserted — and where the traveller stated a `max_continuous_walking_minutes` cap, **every activity must declare `on_foot_minutes`**, because an undeclared value and a measured zero are the same number and the gate used to reward the silence: a capped plan whose activities said nothing saved clean reading “20 min” while the same plan with the walking honestly written as 180 was refused. Writing 0 for a concert is an answer; writing nothing is not. No timestamp may still hold the skeleton's `1970-01-01` sentinel either, since a `checked_at` **is** the evidence somebody opened the page. Every ticket a day actually schedules declares a `sale_opens_at` — `always_available`, `scheduled_release` with the moment, `at_the_door` or `sold_out_or_unavailable`, plus one sentence of `basis` — because a ticket the traveller cannot be at a screen to buy is not a ticket they have, and the gate refuses a release that lands while the plan's own timeline still has them in transit; only tickets a day uses are held to it, and the sentence is what separates a rule somebody read from an `always_available` somebody assumed. The gate also computes every meal anchored to a stop on that day's route and checked against the venue's opening hours, calendar coverage without gaps over a window that runs forwards, a departure day that is a checkout rather than an extra night, budget totals that match the rows they claim to sum, every category the total claims to include actually itemised in the breakdown, no negative leg quietly cancelling a real one, and a day that never claims fewer interchanges than its own segments declare. Fix what it reports rather than arguing with it. Run `python scripts/validate_trip_html.py <final.html> --expected-days N` before delivery; add `--require-booking-type flight`, `ground`, `hotel`, and/or `ticket` only when those choices are required, and add `--transport-mode self-drive` or `public-transit` to enforce the selected mobility branch. It also fails any button whose named provider is not the host its URL opens, and prints a `note:` for each button whose provider name has no matchable token — read those notes, because they are the only links the gate could not decide for you. Fix every reported issue. Then run `python scripts/check_link_targets.py <final.html>`, which follows every outbound button and reports where it actually lands: a page that names the right provider and carries every required attribute can still open a dead host or redirect onto someone else's site. It fails only on what survives any user agent — a hard 4xx/5xx or an off-domain redirect — and reports everything else as `unverified`, because a provider's answer depends on the agent that asked: the same Google Flights URL returns 200 unredirected to a browser and an `unsupported` page to a script, and an earlier check called that broken when it was not. Read every `unverified` line and resolve it by opening the link yourself; do not let a clean exit stand in for that. Do not output a booking-ready HTML page while essential dates, party size, budget basis, entry feasibility, or mobility mode remains unknown; return to targeted intake instead.

## 5. Replan incrementally

When the user changes a constraint, first restate the delta. Trace dependencies rather than rebuilding everything:

- budget or dates → fares, nights, accommodation, paid activities, sequence;
- mobility/health → walks, transfers, elevation, accommodation location, pacing;
- weather/season → outdoor activities, clothing, alternative locations;
- passport/entry change → destination eligibility and transit;
- traveler count or preferences → rooms, transport, activity choices, budget allocation.

Keep unaffected, still-feasible choices. Return a concise change log: retained items, replaced items, new total/risk, and any decision that needs user approval.

**When the change moves the dates, run `python scripts/replan_trip.py <plan.json> --shift-days N --out <new.json>` rather than editing the plan by hand, and read [references/replanning.md](references/replanning.md).** Dates are the dangerous delta because almost every researched fact under them is keyed to a *weekday*, not to a date: opening hours, closure days, market days, Sunday retail law, a museum that shuts Mondays. A one-day shift silently invalidates all of it while the plan still looks complete. That is not hypothetical — a measured run moved the window by one day, redid the weekday map by hand, and introduced an off-by-one in every ticket and every anchor day index. The script rewrites only what is a pure function of the shift (trip and day dates, accommodation windows, dated booking fields, ticket day links), never prose — a sentence like "Saturday is the only full shopping day" becomes false when the dates move, and rewriting the weekday token inside it would turn a stale sentence into a confident lie. Everything it cannot safely recompute lands in `replan_context.must_reverify`, and `check_plan_consistency.py` refuses the plan until each entry is resolved. It also clears `verification_status`, because a plan whose dates moved was never verified on those dates.

Use [templates/replan-request.json](templates/replan-request.json) as the shape of that `replan_context` block.

## Quality gate

**When the traveller asks about a trip they already have saved — to reuse it, revise it, or ask
whether it still holds — run `python scripts/audit_workspace.py --workspace "<workspace>"` first,
and read the result before answering.** Every gate here was written against the plan being built
at the time and nothing ever looked back: on a real workspace of eleven saved plans, only the most
recent passed, the rest carrying 25–126 findings each. Most were not newly-required fields but the
defects the traveller had reported — map endpoints that could not geocode, opening times asserted
with no evidence, walking legs whose implied speed was a run. Those pages are still openable and
say nothing. The tool reports and never edits, because re-plan, re-verify or discard is the
traveller's decision; surface what it found and let them make it.

Before delivering a recommendation or plan, verify:

- the record-once rule in [references/decision-and-research.md](references/decision-and-research.md) was applied while the pages were open — every venue's coordinates, registered name, weekday hours and rating captured in one visit, every property's price, availability and guest score in one — rather than reconstructed at construction time from memory;
- the disqualifier questions in [references/research-budget.md](references/research-budget.md) were asked before any research fan-out, and no anchor, opening-hour, or weather research was launched before the travel dates were final;
- the fan-out stayed inside that reference's agent-count target (≈3 feasibility, ≈3 design, 5+2 verification for a single-destination trip under a week), or the reason for exceeding it was stated to the traveller — an overrun nobody names is indistinguishable from thoroughness, and the measured run spent 1.18M tokens that way;
- origin, dates/duration, party, budget basis, destination scope, and experience direction are either known or visibly assumed;
- first-time intake used the loopback HTML form unless the traveller already supplied the information or explicitly chose the chat fallback, and the plan's `intake_context` says which — with the traveller's own declining words when it was `chat_fallback`. Offering chat as an equal option, or switching to it because the form felt slower or a background command felt awkward, is the defect this field exists to make visible;
- human/cultural and natural preferences have been decomposed into useful subtypes rather than treated as vague labels;
- hard constraints were checked before scoring;
- a no-feasible-result outcome was handled as a constraint conflict, not forced into a ranking;
- when the trip leaves the country of residence, every traveller’s entry eligibility and passport validity were verified against their residence status — not their nationality alone — before describing a trip as bookable, and the conclusion reached the page via `entry_context`; when the traveller stays home, entry information was neither requested nor treated as a blocker;
- volatile facts are researched and dated, or honestly marked unverified;
- the final page carries no renderer-owned English when the trip language is not English; `validate_trip_html.py` fails the page rather than leaving this to inspection;
- every collected-and-required field reaches the page: route fallback and walking burden, flight fare conditions, any single-option reason, unpriced budget categories, planning assumptions, the booking-platform rationale, and the traveller's own avoid-list with what keeps each item out plus the scenery and culture subtypes they picked — confirmed by looking at the rendered page, not at the plan JSON;
- costs use the same scope and currency, with uncertainty explained;
- every outbound booking link is HTTPS, source-labeled, date-checked, opens only for the user to review, and identifies whether it came from a direct provider or an appropriate comparison platform; **the provider a button names is the provider its URL opens** — a card's `provider`/`map_provider`/`official_or_authorised_provider` labels the button *and* is the destination it must resolve to, so a comparison platform belongs in `round_trip_search_*` or `comparison_searches`, never behind an airline's name. `validate_trip_html.py` fails the page on a mismatch rather than leaving it to a human clicking each button;
- every shown flight, accommodation, ticket, car, and essential rail/ground booking category has a dated, source-linked booking-access check that distinguishes available, limited, and unknown access without collecting credentials or payment data;
- the final page exposes a per-person budget breakdown for every included category, with a price status and check time; totals and accommodation shares are not presented as unexplained black-box ranges;
- each day has a feasible route order, route-mode cost/time, accommodation, researched meals, and direct directions links whose visible provider matches the verified URL; every segment has one primary mode, a concrete service/instruction, walking/transfers, fare basis, and fallback; a live map is labelled “full-day route” only when it contains all waypoints, otherwise it is explicitly a route overview and the segment buttons are the navigation source of truth; POI pages are rejected as navigation; maps and booking platforms are chosen for destination-market coverage and normal traveller access, not brand familiarity; mainland-China routes use verified Amap directions URIs by default rather than Google Maps;
- daily cards cover every calendar date in the confirmed trip window without gaps, and the assigned accommodation check-in/out dates cover each day it is used;
- saved-profile use was explicitly consented, exclusions were applied as hard filters, and the newest user instruction took precedence;
- the answer preserves choice and makes trade-offs legible;
- `python scripts/check_plan_consistency.py <plan.json>` exits clean, so no route total, walking figure, meal placement, calendar date, or budget line contradicts the data it is derived from;
- every map URL endpoint is a **coordinate pair**, never a display label, and `trip.destination_coords` is declared so a reversed pair cannot pass; no day claims `multi_stop` scope without waypoints, and no transit URL carries waypoints at all (Google returns no route for those);
- every dining card's rating is **visible on the page**, not merely present in the JSON — `validate_trip_html.py` fails a card that prints none, because a rating stored and never shown is the same defect as a rating never gathered;
- every dining card carries a rating with its scale, count and source (or `rating_status: "none"` with a reason), names the venue as its map provider indexes it, and has verified hours for the weekday it is scheduled on — a scheduled meal is a claim the venue is open;
- every accommodation option has a **property-scoped** booking link, and its price and availability were read off that page rather than estimated;
- every search button carries the trip's own dates, so it opens a filled-in search rather than a blank form — and where a provider cannot be deep-linked with dates at all, the dated comparison button is the first one on the card and the provider's own link says on the card that it is a channel entry;
- hotels carry a guest rating on the same terms as restaurants, and nothing below 7.0/10 is recommended without a reason;
- the parallel verification in [references/verification.md](references/verification.md) ran concurrently before delivery, its report covers all five truth domains **and both auditors** (`consistency`, `completeness`) with every `claims_checked` a list of pointers that resolve, and every `wrong` or `misleading` finding is either fixed in the plan or explicitly accepted by the traveller — a plan saved with `--unverified` carries `verification_status: unverified` and renders a "not fact-checked" banner on the page, so never describe such a page as booking-ready;
- a date change went through `scripts/replan_trip.py` and [references/replanning.md](references/replanning.md) rather than a hand edit, every `replan_context.must_reverify` entry it raised is resolved, and the plan was re-verified — a shifted plan carries the *old* verification, which was never true of the new weekdays;
- no irreversible action is represented as completed without user approval.
- a completed Construction task has a paired, validated source JSON and self-contained final HTML saved under the user’s workspace, with both exact paths reported; otherwise it is explicitly labeled as intermediate discovery or blocked pending one essential decision.
