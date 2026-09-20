# Los Panaderos

HackSpain wildfire response demo: a configurable fleet follows missions decided in HappyRobot.

112 CECOP wildfire operations demo for Brunete, Madrid. HappyRobot remains the only mission decision-maker; the dashboard presents coordinated fleet orders, five population groups and the simulation's observations.

## Run

```sh
python3 -m simulator.server
```

Open [the local demo](http://127.0.0.1:8765). In **Preparar incidente**, choose 0–3 trucks, scouts and Squirtle (extinguisher) drones, then **Aplicar flota**. At least one vehicle is required; the default is one of each. Place and ignite the fire, choose/apply wind, then send **Aviso de humo**. The report starts automatic playback and agent decisions. Reset preserves fleet counts; during deliberation, Reset queues a fresh incident and discards the in-flight result and queued ignitions.

- **East:** scout, then contain visible fire.
- **North:** scout, then warn the farm's 100 assumed occupants before returning to containment.
- **West:** scout, then warn threatened town neighbourhoods independently.

These describe exposure scenarios, not scripted outcomes. HappyRobot chooses investigation, containment and independent district warnings from the available information.

## 112 dashboard

Start with the [adaptation and experience guide](docs/adaptation-and-learning.md) for a walkthrough of the **Adaptación** strip, case labels, replay, result metrics and the reasons behind the design.

The dark CECOP console keeps two illustrated Brunete maps: ground truth on the left, and current/remembered observations with delayed synthetic satellite detections and district overlays on the right. The maps are not georeferenced. The people board, verbatim radio-order ticket and communications log remain visible around the map workspace; setup and recording tools collapse for the pitch. ES/EN changes interface labels, never agent missions or reasons. Cesium/FIRMS and the Sierra de Gata helpers remain dormant compatibility code, not the live map or simulated fire. The gitignored .env is retained, and the unused /api/config endpoint remains localhost-only.

Use Pause, +1 step, speed selection, and Ask agents for manual control. The timeline supports backward/forward scrubbing and replay playback. **Live** returns to the latest state; press Play to continue. Replay is read-only and never repeats platform calls. Up to 1,500 compressed frames are retained in memory, cleared by Reset/restart. Playback pauses when the operator view confirms no active fire remains and no evacuation group is still moving or blocked; this is not an agent all-clear.

## Model and observations

An 80×56 custom educational grid, **not SimFire or PROPAGATOR**. The default map uses the approved illustrated Brunete landscape, with four neighbourhood-inspired town response areas and one farm district. Scale is an approximate demo convention (48 m/cell), not a georeferenced survey. Station: (12,32); farm: (73,21); ignition: (76,41). Roads, land cover, refuge points and district boundaries are schematic and registered to the illustration. Old aerial recordings retain their original background and geography.

Brunete's [municipal census total is 11,261 for 2025](https://brunete.org/nuestro-pueblo/datos-estadisticos/), corroborated by the [Comunidad de Madrid/INE series](https://gestiona.comunidad.madrid/desvan/desvan/AccionDatosUnaSerie.icm?codMun=0262&codTema=1929381). For this scenario, that whole municipal total is allocated as Casco Histórico 3,942 (35%), Prado Alto 2,815 (25%), Prado Nuevo 3,378 (30%), and Valle de los Rosales 1,126 (10%). These are **estimated scenario allocations, not measured district populations or official boundaries**. Farm occupancy is **100 assumed visitors and staff**; the farm website does not establish a verified resident or current occupant count. Farm occupants are separate from the official total. Each district is one independently moving group, not individual residents/household locations. See [population provenance](docs/population-provenance.md).

Eight-neighbor ignition uses a 50% base probability multiplied by target terrain, source intensity and diagonal distance. Multiple neighbors give one draw using strongest exposure. Roads/bare ground block surface spread, including diagonal corner crossing; there is no ember spotting. At wind X=1, Y=0, attempts occur downwind every two steps, crosswind every 10 and upwind every 20; stronger wind accelerates downwind attempts. Failed attempts retry on the next eligible step. Intensity grows from 0.25 toward 1, consumes fuel at terrain-specific rates and fades as fuel runs out. Seeded randomness (default seed 9) makes identical scenarios reproducible while creating uneven fronts. No meters/seconds or operational forecasting accuracy are implied. The drone travels three cells/step and sees radius twelve. The drone has one jet: each step it attempts one observed burning cell within eight cells, with a 40% success chance. Drone targets are safe flight positions, at least three cells from observed fire, selected from safe_containment_positions; routes avoid locally detected fire and retreat if fire approaches. It never deliberately flies to a burning target. Successful jets reduce intensity by 0.20 and wet the cell for 8 steps. Wet cells cannot regrow or ignite; remaining fuel can reignite after drying. Battery and suppressant budgets are removed.

Evacuation requires the drone to reach the settlement and warn people. Groups travel to fixed refuges at 0.8 cells/step and stop if fire blocks their route. This is a simplified group movement model, not route planning. Station dispatch mobilizes an actual moving truck for eight steps after the farmer report. It travels at two road cells/step or 1.6 off-road cells/step from the station (80% road speed), avoids detected fire, and uses five jets, each attempting a distinct observed burning cell per step with 60% success within a ten-cell hose radius. There is no timed teleport or remote suppression. Its position, route, status, local fire observations and route-based arrival estimate are shared with both HappyRobot agents every decision. An obstructed route may invalidate that estimate. Truck movement and local navigation are deterministic; suppression uses seeded randomness; HappyRobot controls the drone mission and its truck attack-sector orders; local navigation handles individual vehicle steering.

Roads are schematic access tracks, not a real transport network. Fire spread is deliberately simplified, without calibrated fuels, slope, atmospheric turbulence or spotting. This update adds operational constraints, not a validated wildfire/flight model.

Left map is ground truth. Right map shows local observations and remembered sightings, plus synthetic satellite hotspots in 8×8 blocks, captured every 12 steps and delivered 12 steps late. Forecast and smoke report are synthetic. Resident movement/status is treated as reported telemetry. Global fire cells and simulation-only ignition logs never enter agent inputs.

The clock animates at 1–8 steps/second, but **pauses during HappyRobot deliberation** so API latency cannot change the outcome. Automatic decisions occur every 16 steps and on farmer reports/forecast changes. No scripted decision fallback.

## HappyRobot integration

[Los Panaderos development workflow](https://platform.eu.happyrobot.ai/hackspainteam9/workflows/mg9barxt86w3/editor/njn4x0maqj9y)

```text
Simulator Event
└─ Central Command (Reasoning Agent)
   └─ Central Coordination Logic
      └─ delegate_extinguisher(mission)
         └─ Drone Agent (Reasoning Agent)
            └─ Drone Local Reasoning
               └─ report_to_central(command, target, reason, mission)
                  └─ Drone Command (AI Extract: serialization)
```

Central sends a mission into the nested drone agent; the drone reasons from local observations and returns a decision through the tool result. The backend executes its command and provides updated observations, prior decisions and outcomes in the next run. This is bounded per-event coordination with simulator-provided memory, not persistent online learning.

The backend uses the authenticated stdio MCP proxy in `.cursor/mcp.json`, server `happyrobot-mcp-eu-all`. On another machine configure the proxy and OAuth, or set `HAPPYROBOT_MCP_CONFIG` and `HAPPYROBOT_MCP_SERVER`. Python standard library only. Credentials stay in the proxy, no public tunnel is needed, and the browser receives no credentials. The farmer call is a simulated text transcript, not a phone call.

Completed run outputs are fetched explicitly, parsed and checked for coordinate bounds, visibility, incident identity, tick freshness and duplicate commands. A rejected model command is returned as feedback for one corrective decision; a second rejection pauses the demo. The simulator never silently substitutes a different AI target. Latest run evidence is in `.runtime/last-run.json` and the page's inspection panel. [Agent prompts](docs/mvp-agent-prompts.md).

## Self-healing loop: black box, oracle, reflection

[Post-mortem Los Panaderos workflow](https://platform.eu.happyrobot.ai/hackspainteam9/workflows/tigrukwx7c5y/editor/tvpspqgw92vp)

```text
decision applied ──► BlackBox (SQLite, .runtime/blackbox.sqlite)
                      │  frozen pre-decision world, payload, decision, outcome after 16 ticks
                      ├─► Telemetry harvester   reasoning / tool calls / timings per agent
                      ├─► Hindsight oracle      counterfactual rollouts with the hidden fire → regret, gap type
                      ├─► Reflection agent      HappyRobot post-mortem → root cause, evidence, proposed rule
                      └─► Healing tiers         1 lesson in next payload · 2 northstar on recurrence · 3 staged patch
```

Every applied, rejected or failed decision is frozen before the simulator mutates and analysed in a background thread; the clock never waits for it. The oracle re-simulates the same world with hindsight (it knows fire the sensors had not seen) for the actual command and a small set of candidates, and reports regret plus a gap type: `information` (best command needed hidden facts), `judgement` (facts were visible), `execution` (rejected command, tool loop, timeout) or `none`. It never chooses a command for the live incident; it only measures.

The reflection is a separate HappyRobot workflow that reads telemetry, the oracle verdict and the prompt section, and returns a structured diagnosis. Tier 1 gates rules on confidence and gap type, stores contextual lessons and annotates the run; tier 2 creates a Northstar on recurrence; tier 3 forks and patches a version, **automatically publishes it to staging**, runs a replay and writes a report in `.runtime/patches/`. Development/production promotion remains human. An explicit gate before staging publication is still pending; the earlier claim that nothing publishes automatically was incorrect. Lessons persist across resets. **Post-mortem** shows the commands, regret, gap, latency, loop signals and reflection.

Reference case: run `58a5e3dc` (development v25) had the Scout Agent call `report_scout_plan` twelve times over four minutes because the tool result was empty and it read that as failure. From the recorded telemetry the harvester flags the loop, the oracle grades it as an execution gap, and the live post-mortem run `90242a22` named the empty tool result as root cause with a rule to treat an empty result as success (`tests/test_reference_case.py`, fixtures under `tests/fixtures/`). The oracle's cost function is a demo heuristic (exposed people, unwarned downwind, burning cells, invalid or looping runs), not an operational standard. Design notes: `docs/superpowers/specs/2026-09-20-self-healing-blackbox-oracle-reflection-design.md`; HappyRobot-side contract for experience, futures and the optional plan-evaluation workflow: `docs/happyrobot-experience-contract.md`.

## Possible worlds: forecast before acting, replan when reality disagrees

```text
decision requested ──► belief world (sensor memory, delayed satellite, smoke report; hidden fire excluded)
                        │  8 reseeded rollouts × 16 ticks in a process pool (~1 s) → world_state.possible_worlds
 decision applied  ──► same ensemble for the plan in force → BlackBox forecasts table, dashboard fan overlay
 every 4 ticks     ──► surprise = distance(observed belief, forecast medoid) restricted to cells seen since
                        │  distance > max(0.05, 2×dispersion) capped at 0.30 → forecast_divergence event → agent replans
```

`simulator/worlds.py` forks the world the agents can see (never the ground truth), runs it under the current orders with different random seeds, and summarises the ensemble: dispersion, expected burning cells, per-cell burn probability, and for each district the probability of fire within 8 cells and the distribution of population outcomes. The same world distance (tolerant fire-front and burned masks, population status ranks, district threat, fleet displacement) that measures ensemble spread also measures how far the observed world has drifted from the forecast; when the drift exceeds what the ensemble itself explains, the controller logs why (`what_changed`: wind, an unexpected front, a district newly threatened) and raises `forecast_divergence` so the next HappyRobot decision names the invalidated assumption. Hidden fire the sensors have not reached can never trigger it. Forecasts and surprise checks are stored next to the decision in the black box and appear in the **Futuros** panel and the post-mortem view. Frequencies are model-consistent, not an operational fire forecast.

## Learning from experience: case memory, lesson credit, learning curve

```text
decision requested ──► situation signature (belief only: wind, believed fire, per-district status/distance/downwind, idle fleet, minutes since alarm)
                        │  k=3 nearest graded past decisions by signature distance → world_state.similar_cases
                        │  active lessons ranked by the situation they were learned in → world_state.lessons_learned
 decision recorded ──► cases table (signature) + lesson_uses (which lessons this decision saw)
 oracle graded     ──► lesson credit: regret of decisions shown the lesson vs not shown → retire when it hurts
```

The black box is the replay buffer; the policy is a frozen language model, so experience feeds back *in context* instead of by gradient. `simulator/experience.py` builds a small, interpretable signature of the situation as the agent sees it (hidden fire excluded) weighted toward what matters in the first minutes — who is unwarned and downwind, what is idle, whether the fire is confirmed — and retrieves the closest past decisions that the oracle has already graded. Each case tells the agent what was done, what the oracle preferred, the regret, the outcome and any lesson drawn from it; cases from the current incident are excluded so no decision grades itself, and cases further than `MAX_CASE_DISTANCE` are not shown. Cases are evidence, not orders: current observations and telemetry override them.

Lessons are ranked by contextual similarity, with a confidence ≥0.5 gate at creation. Every decision records which lessons it was shown; `review_lessons` compares exposed/unexposed mean regret and can retire a lesson after at least three uses. These are observational comparisons, not proof of causation; recurrence and relevance-cutoff gates remain pending. The top **Adaptación** strip asks what might happen, whether the plan needs to change, which experience is available and what results were measured. Cases and results open separate views in a dialog; technical details, incident history and lesson retire/restore controls are available through disclosures. `/api/learning` exposes the same data.

Retrieved cases now include versioned situation labels, shared labels and current-versus-historical differences, including fleet counts. These explain the existing numeric ranking; they do not establish improved retrieval effectiveness. Explicitly truncated evaluations and invalid regret values are excluded from case retrieval. Old stored signatures gain labels on retrieval without a database migration. See the [guide](docs/adaptation-and-learning.md#how-historical-retrieval-works) for weights, thresholds, limitations and the next improvements to evaluate.

`python3 -m simulator.episodes --episodes 3 --fresh` demonstrates same-scenario replay with a mock policy that copies an oracle-preferred historical plan. It does not establish that HappyRobot learns. SQLite is the only database needed or planned.

`python3 -m simulator.evaluation --output .runtime/learning-evaluation` runs held-out matched snapshots with frozen training memory, three common future RNG seeds, hold/random/warning/replay comparators, wind changes, changed ignition location and reduced fleet. It saves the training SQLite database and complete results JSON without touching the live store, rejects truncated oracle searches and refuses to overwrite results. See [evaluation results and limitations](docs/learning-evaluation.md).

The [proposal audit](docs/proposal-audit.md) tracks all earlier suggestions, evidence and unfinished integration work, including input triage, two-way communication and live experience attribution.

## Verify

```sh
python3 -m unittest discover -s tests -v
node --test tests/test_dashboard.cjs
node --check simulator/static/app.js
```

Tests cover spread timing, wind, containment, local knowledge, satellite latency, evacuation, blocked routes, stale/invalid commands, immutable replay, MCP parsing, the black box, telemetry signals, the oracle, the reflection client, the healing tiers, the reference loop case, the belief-world ensemble and forecast divergence, situation signatures, case retrieval, lesson credit and the episode harness. Live HappyRobot calls are mocked in tests. Restart the server after Python changes; no hot reload.

[Recorded validation cases](docs/demo-validation.md) include the real HappyRobot run IDs and physical outcomes.

Wind panel: set X/Y independently from -3 to +3 and press Apply wind. Positive X is east, positive Y is south; (0,0) is calm. Values are relative simulation units. Each direction uses the vector projection to determine its spread interval; agents receive the full vector, magnitude and directional attempt intervals and the terrain-adjusted ignition rules.

Interactive setup: before ignition, click the left map to choose the fire origin. Drag the wind compass or use the X/Y sliders. Run & record applies the preview wind, ignites the selected location and starts the farmer report plus HappyRobot loop. Stop recording pauses the simulation; an in-flight decision may still finish. Play recording replays captured states without calling AI; Live exits replay. Download recording saves a simulation JSON file (not a video); Open recording loads it after a restart. Capture is limited to 1,500 frames; a new recording replaces the previous in-memory capture. Reset preserves the last recording until a new one starts.

Forecast-led strategy: HappyRobot treats wind magnitude ≥2 as strong in demo units. If a credible smoke report places unwarned residents downwind, Central sends the drone to warn/evacuate immediately, before thermal confirmation or containment. Strong wind away from residents does not trigger unrelated evacuation. The agent considers both wind components, report uncertainty, people status, drone capacity and actual truck availability. This strategic choice runs in HappyRobot, not a local command-selection rule.

Downwind containment: HappyRobot Central and its nested Drone agent prioritize safe positions covering the advancing downwind fire edge. Candidate telemetry reports leading-edge coverage and signed downwind offset. If containment is inadequate or warning time is short, they prioritize threatened downwind residents. Unknown flanks require scouting; the simulator still enforces fire clearance. Calm wind has no preferred side.

Population exposure: each group occupies one grid cell. When fire reaches that cell, its entire population is counted as burnt once and stops moving. The per-group counter and total are stored in replay frames; reset clears them. This is a simplified demo outcome, not an injury model.

Truck routing minimizes travel time using road and off-road edge costs. Fractional movement carries between steps, giving eight off-road cells per five steps; no time accumulates while parked or blocked. Arrival estimates use the same weighted route.

Drone and truck routes support eight directions. Diagonal edges cost √2 times the distance/time of cardinal edges; fractional movement carries between ticks. Neither vehicle cuts diagonally across blocked corners. Road-corner shortcuts count as off-road unless the whole corner is road.

Drone navigation uses optimistic A* with an octile heuristic. Unknown cells are assumed traversable; a valid route is reused until newly observed fire (including its safety buffer) blocks it or the destination changes. Observed fire remains in local memory until re-observed clear. This is local navigation; HappyRobot chooses the mission and destination.

After warning delivery, residents move independently and the drone becomes available immediately. Automatic mode requests a fresh HappyRobot assignment on that event: prioritize remaining urgent warnings, otherwise scout/contain to support the truck rather than waiting at the settlement.

Observation circles: drone radius 12 (solid), truck radius 9 (blue dashed). The agent view shows both vehicles’ detected fires. Both vehicles share timestamped fire and clear-cell observations. Truck suppression can use a current drone sighting anywhere within its 10-cell hose range, even beyond its own 9-cell sensor radius. It follows shared active sightings within the assigned sector. Stale or unseen fire is never a suppression target. Each vehicle reports its sensor radius to HappyRobot.

Drone-to-truck commands: the nested drone agent returns truck_command (attack_sector or continue), truck_target_x/y and truck_reason alongside its own command. The backend validates both before applying either. Sector orders persist and are visible in truck telemetry and the decision trail. Both agents explicitly treat the truck as the main suppression resource (five jets at 60% success each versus one at 40% per step).

Close scouting and context: first smoke investigation prefers candidate points 3–4 cells from the report, with 3 preferred and detected-fire clearance enforced. Urgent evacuation still takes priority. Each HappyRobot run receives a fog-of-war text grid of current/stale sensor observations (not a screenshot or hidden ground truth), plus the last 12 mission records and measured outcomes. The incident retains up to 128 records; replay frames include recent mission context. Reset starts fresh context. This is in-context adaptation, not training or cross-incident learning.

Suppression context: agents receive current observed intensity, land cover, burned fraction and wetness, plus static terrain. With enough targets, expected successful cooling hits are 0.4 per step for the drone and 3 for the truck; these are not guaranteed extinguished-cell rates. Intense fire needs repeated hits. Counters count complete extinguishments only. The continuous appearance comes from overlapping soft fire and burn fields; physics still uses the 80×56 grid.

Fire spread control: choose 0.25×–4× in the wind panel (default 0.5×). This divides wind-dependent ignition attempt intervals by the factor, rounded to whole steps with a one-step minimum. It leaves the base ignition probability, vehicle speed and suppression unchanged. Agents receive the factor and resulting intervals; recording frames preserve it. Reset restores 0.5×. Fire intensity grows by 0.04 per dry step and terrain burn durations are multiplied by 2, slowing both growth and natural burnout. Distance axes and scale bars use approximate ground distances.

Bundled map: `simulator/static/maps/brunete.jpg`; bounds, source URL, attribution and traced roads in `brunete.json`. Work derived from PNOA máxima actualidad, [CC BY 4.0](https://creativecommons.org/licenses/by/4.0/) scne.es, retrieved 2026-09-19. Map imagery works offline without an API key. Both views share the historical basemap; only observed simulated fire appears in the agent view. Legacy recordings retain the illustrated background.

Wind-directed response: initial scout candidates now prefer the downwind side of the smoke report, approached around detected fire. Central and Drone prioritize the advancing front for truck orders and containment; truck local targeting prioritizes leading cells within its assigned sector. Calm wind has no preferred direction.

District selection: HappyRobot receives all five district IDs (town, town_north, town_south, town_rosales, farm), neighbourhood geometry, population, status, refuge and wind exposure. These represent Casco Histórico, Prado Alto, Prado Nuevo, Valle de los Rosales and El Álamo Farm respectively. Evacuation commands require an explicit district_id and warn only that district. Missing or invalid IDs are rejected; there is no nearest-district fallback. Duplicate warning reservations are reconciled without inventing new strategic destinations: one assignment is retained, redundant vehicles are held, and HappyRobot is asked to reassign them.

## Configurable fleet and additional fires

Before ignition, use the **Medios de respuesta** panel to choose 0–3 trucks, scouts and Squirtle drones independently, then click **Aplicar flota**. At least one vehicle is required. Counts persist on Reset; reset before changing a running fleet. Toggle **Añadir fuego en el mapa** and click the ground-truth map during an active incident to add a hidden ignition. New fires become agent evidence only through sensors or delayed satellite. The first extinguisher is displayed as Squirtle; its command ID remains drone-1.

While HappyRobot is deciding, additional map clicks queue validated ignitions without advancing the clock or changing the world seen by the in-flight decision. The duty banner shows the queued count; they are applied after deliberation. Reset clears the queue. New fires become agent evidence only through observations; the dashboard does not assign local missions.

Los Panaderos development v21 nests Scout Agent alongside the extinguisher under Central. Central consults Scout Agent first, reviews its assessment, then issues coordinated orders. Scouts follow 1–6 agent-selected patrol waypoints, move 4 cells/step, see radius 12 and have loudspeakers for district evacuation but no suppression jets. A separate observed focus (at least 12 cells from the original report and prior scout alerts) generates a simulated radio report and triggers reassessment. This is a digital event, not a telephone call. Patrols continue between frozen decision runs; replay stores every scout. Central ranks observed/reported fires by district exposure, wind and warning time.

Scouts can receive `evacuate_town` / `evacuate_farm` with an explicit `district_id`. They fly to the selected district, deliver the warning, and become available while residents travel to refuge. HappyRobot chooses the warning vehicle using positions and competing tasks. Duplicate warnings for one district retain an existing warning assignment when present, then prefer a scout and a stable vehicle ID. Redundant vehicles are held and reported to HappyRobot through a coordination_conflict event for reassignment.

Every extinguisher and truck receives its own ID-specific order in `extinguisher_orders` and `truck_orders`. Empty roles use empty arrays, have no sensor coverage and perform no actions. Commands validate as one transaction before any vehicle changes. Fleet counts, positions and missions are included in recordings and agent context.

Scout confirmation of the original fire triggers immediate mission reassessment, without waiting for Squirtle to arrive at its old waypoint. A newly blocked target similarly requests a replan once; remembered fire remains excluded from safe containment positions. New destinations and strategic missions still come from HappyRobot. The fire-placement cursor appears only while Add fire is armed and placement is available; busy-state clicks retain the existing ignition queue behavior.
