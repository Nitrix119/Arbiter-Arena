# D&D Auto-Battler — Codebase Review

_Last updated: 2026-08-08. A critical-but-fair health review to orient contributors
(human or agent) and to anchor the repair roadmap. Read alongside [CLAUDE.md](../../CLAUDE.md)._

## Bottom line up front

- The project is **Python** (a FastAPI engine under `src/`) with a thin **JS browser client**
  under `web/static/js/`. The git-log "battle.js / ES modules" refactor was frontend-only.
- **The spell system is sound. Iterate, do not rebuild.** It is a data-driven `EffectPipeline`
  of typed steps with effectively zero spell-name special-casing, and weapon attacks are
  unified into the *same* pipeline. This is the strongest part of the codebase.
- The real risks are **wiring gaps and silent dead features**, not architecture. The three most
  serious (below, E1–E3) have been **fixed** as of this review; the rest remain as a roadmap.
- Despite the name, **nothing auto-battles yet** — there is no AI turn loop; every action is
  driven manually by the frontend/client.

---

## 1. Orientation

| Aspect | Reality |
|---|---|
| Language | Python 3.9+ engine; JS only in `web/static/js/` (rendering/input client) |
| Entry (web) | `uvicorn web.app:app` → `http://localhost:8000` (`serve.bat` on Windows) |
| Entry (lib) | `Entity(StatBlockLoader.load_from_json(...))` + `CombatSystem` (see [README.md](../../README.md), `examples/example_combat.py`) |
| Packaging | `pyproject.toml` — zero core deps; `fastapi/uvicorn/jinja2` under `[web]`; `pytest/black/flake8/mypy` under `[dev]` |
| Tests | Large, real pytest suite (535 tests as of this review) — a genuine strength |
| Ignore | `build/lib/…` is a **stale, untracked** duplicate tree; read engine logic only from `src/` |

## 2. Architecture overview

**Two-layer data model (clean):** immutable template + mutable state.
- `src/models/stat_block.py` `StatBlock` — immutable creature template (abilities, HP max, AC,
  actions, damage modifiers, spell-slot/legendary defaults).
- `src/models/entity.py` `Entity` — mutable combat state wrapping a StatBlock (`current_hp`,
  `temporary_hp`, conditions, `stat_modifiers`, `granted_actions`, `resources`, `x/y/z`,
  concentration). Identity by `entity_id`. Computed `ac`, `spell_save_dc`, `spell_attack_bonus`,
  `bounding_box`.

**Combat is a facade over focused collaborators.** `src/combat/combat_system.py` `CombatSystem`
orchestrates and delegates to: `TurnManager` (round/turn lifecycle, condition-based skip),
`InitiativeTracker` (d20+DEX), the resolvers, `DamageProcessor`, and an `EventBus`.

**The spell/attack engine — the core idea.** Both weapons and spells run through one
`src/combat/effect_pipeline.py` `EffectPipeline`: a sequential list of typed steps
(`attack_roll`, `saving_throw`, `damage`, `healing`, `add_entity_effect`, `apply_condition`,
`add_modifier`, `grant_temporary_hp`) sharing an ephemeral `context`. Earlier steps write
results (`context.hit`, `context.damage_dealt`, `context.save_success`) that later steps read
via **sandboxed Python expressions** (`src/rules/expressions.py` — AST whitelist,
`__builtins__={}`, no dunder access). Weapon attacks are translated into pipeline steps by
`AttackResolver._default_program`. This unification is the design's best feature.

**Rules & effects are data-driven too.** `src/spells/rules.py` loads global
rules (`rules/global/`: crits, concentration, damage modifiers) and named entity effects
(`rules/entity_effects/`: colossus slayer, the condition library) as JSON. Each is a block
`program` of `trigger` blocks that the engine installs on the block engine — it is a loader
seam, not a dispatcher. Cross-cutting behavior (resistance multipliers, concentration saves,
crit rules, conditions) subscribes to bus events rather than being hardcoded into resolution.
A trigger supports a `when` expression guard so one rule can serve multiple events.

**Web layer.** `web/app.py` builds process-global spell/effect registries at startup by scanning
`examples/spells/` and `rules/entity_effects/`. `web/routers/combat.py` exposes creature/spell
HTTP endpoints and a `/ws/combat` WebSocket whose handlers (`start_combat`, `attack`,
`cast_spell`, `move`, `legendary_action`, `end_turn`) map 1:1 to engine calls and broadcast a
full state snapshot each time. The JS client is reactive: `state.js` holds a single shared
mutable state object (a deliberate ES-module live-binding workaround), and
`renderer/input/websocket/ui-panels` modules read/write it.

**Two loops, no AI.** The engine turn lifecycle (`TurnManager.end_turn`) and the WebSocket
message loop both exist, but **there is no autonomous action-selection loop** — monster turns are
not auto-played. "Auto-Battler" is currently a turn-enforced *manual* tactical client.
LLM-driven action selection is a README "Future Goal."

## 3. Spell-system verdict — sound; iterate, do not rebuild

**Why it's sound:**
- **No spell-name special-casing anywhere** — no `if spell.name == …`, no per-spell switch.
  Behavior is JSON pipeline steps + a `step["type"]` dispatch + a name→handler registry.
  Adding a spell = a JSON file; adding a mechanic = one handler + registry entry.
- **Weapon/spell unification** removed a whole class of duplication (one implementation of
  attack rolls, crits, damage).
- **Correct handling of the two trickiest 5e rules:** AoE "roll once, apply to all"
  (`SpellResolver._preroll_pipeline_damage`) and half-damage-on-save.
- Sandboxed expression evaluator is a thoughtful safety choice.

**Real weaknesses are wiring/coverage, not structure:** silent under-implementation of declared
spell riders (e.g. Chill Touch's no-heal, Ray of Frost's slow are absent from the JSON); two
parallel effect vocabularies bridged by synthetic stub events; and no structured upcasting.
_(The two vocabularies and the stub-event bridge are gone as of 2026-09-03; one block
catalogue remains.)_

## 4. Significant missing features

1. **No autonomous AI / auto-battle loop** — the defining feature of an "auto-battler." Biggest
   product gap. (README Future Goal: LLM action selection.)
2. **Spell upcasting / level scaling** — `higher_level_scaling` is **prose only**; explicit TODO
   at `src/models/action.py`. No way to spend a higher slot for more dice.
3. **Reactions & opportunity attacks** — the `reactions` resource is tracked and spendable, but
   *nothing triggers a reaction* off the event bus. No Shield, no OA.
4. **Multiattack** — no field or handler; not in any creature JSON.
5. **Death saves / dying / stabilization** — none; `is_alive()` is binary at 0 HP.
6. **Split multi-target spells** (Magic Missile darts, Eldritch Blast beams, Scorching Ray) —
   only "same effect to a list" or true AoE is expressible.
7. **Forced movement** (Thunderwave push), **cantrip auto-scaling by level**, **component
   enforcement**, **monster traits** (Pack Tactics, regeneration), **innate/limited-use
   abilities**, **speed variants/senses**, **cylinder AoE + sight/unlimited ranges** (enum values
   exist, unimplemented).
8. **Damage `bonus_to_hit`/`amount` are hand-authored**, not derived from ability + proficiency.
9. **Save auto-fail** for paralyzed/stunned/petrified/unconscious (STR & DEX auto-fail) — the
   save-modifier mechanism now exists (see E3) but auto-fail is a distinct effect not yet wired.

## 5. Problems (severity-rated)

**CRITICAL — fixed in this review:**
- **E1. Damage resist/immune/vulnerable was unreachable from JSON.** `StatBlockLoader.from_dict`
  never passed the three modifier lists, so JSON-declared modifiers were silently dropped even
  though the rules/multipliers were correct and unit-tested against hand-built StatBlocks.
  **Fixed:** the loader now parses `damage_vulnerabilities/resistances/immunities` (with a
  friendly error on unknown types) and round-trips them; `stone_golem.json` gained
  `damage_immunities` as a live example; covered by `tests/test_loader_damage_modifiers.py`.
- **E2. `grant_temporary_hp` pipeline step crashed** — it called a non-existent
  `Entity.gain_temporary_hp`. **Fixed:** now calls `add_temporary_hp`; covered by
  `tests/test_grant_temporary_hp.py`.
- **E3. Saving throws ignored advantage/disadvantage** — `roll_saving_throw` always rolled a
  single d20, so conditions only affected attacks. **Fixed:** `_handle_saving_throw` now emits a
  `SAVING_THROW_DECLARED` event that effects can flag; `roll_saving_throw` honours
  advantage/disadvantage; `restrained` grants disadvantage on DEX saves; covered by
  `tests/test_save_advantage.py`.

**HIGH:**
- **E4. Loader brittleness on bad content — fixed.** `json.load` is now wrapped (naming the
  file), and every enum lookup (`DamageType`, `RangeType`, `TargetingType`, `AOEShape`,
  `CastingTimeType`, `DurationUnit`) goes through a `_enum_lookup` helper that reports the bad
  value and the valid options. Covered by `tests/test_loader_validation.py`.
- **E5. Loader regex vs. dice parser mismatch — fixed.** `_FORMULA_RE` now full-matches
  multi-term formulas (`2d6+1d8+5`, `1d20-2`) that `dice.py` can roll, while still rejecting
  garbage; covered by `tests/test_loader_validation.py`.
- **E6. RuleEngine swallowed `AttributeError` in condition eval — resolved.** It DEBUG-logged and
  skipped, so a genuine typo in a rule expression was silently ignored, indistinguishable from a
  field legitimately absent on a wrong event type. **Fixed:** a per-event field schema
  (`EVENT_DATA_CLASSES` / `event_fields` in `src/combat/event_data.py`) now backs a load-time check
  that rejected any `event.<field>` reference no trigger carried, so typos failed loudly at load.
  _(Re-homed 2026-09-03: when the legacy `triggers`/`effects` shape was deleted, the check moved
  onto the block program — `spells.validate._check_event_refs` now checks every `event.<field>`
  under a `trigger` against that trigger's declared event, reusing the same `event_fields` schema.
  Necessary, not cosmetic: at fire time `triggers._passes` swallows the AttributeError and returns
  False, so a typo reads as "did not fire". It found a live instance on its first run —
  `petrified`'s DAMAGE_INCOMING trigger guarded on `event.attacker`, so its damage halving had
  never fired.)_ Nested entity-attribute typos like `event.defender.typo` are still swallowed at
  runtime — that needs an Entity attribute schema and was always outside E6's scope.

**MEDIUM:**
- **E7. Return-shape drift vs. docstrings — fixed.** `resolve_attack`/`parse_dice_formula`
  docstrings now match; the fragile per-target spell 6-tuple is a `NamedTuple`
  (`SpellTargetResult`) — still positionally unpackable, now self-documenting.
- **E8. Broken logging call — fixed.** The stray `logger.info("DC set as:", …)` in
  `spell_resolver.py` was removed.
- **E9. Dead code — fixed.** WebSocket reconnection (commented backend branch + orphaned session
  store, and the matching frontend `rejoin_combat` send/handler) was fully removed; the commented
  `resolve_saving_throw` and the deprecated `ModifyAC` handler are gone.
- **E10. Misleading `target: "for_each_defender"` — fixed.** The inert field was removed from all
  AoE spell JSONs and the `SPELL_DEFINITION_GUIDE`; the guide now explains AoE fan-out is
  automatic and `damage`/`saving_throw` steps take no `target`.
- **E11. Non-seedable RNG — fixed.** `dice.py` now routes all rolls through a single
  `random.Random` with a `seed_rng()` helper, so a whole battle is reproducible without
  monkeypatching; covered by `tests/test_dice_seed.py`.
- **E12. Cross-language duplication / process-global state — partially addressed.** `CELL_FEET` in
  Python and JS now carry explicit "keep in sync" comments (no shared source exists across the
  boundary). Still open: the spell registry is a process-wide singleton shared across web
  sessions — a concern once more than one battle runs concurrently.
- **E13. License contradiction — resolved.** The project is now licensed under
  **PolyForm Noncommercial 1.0.0** (`LICENSE`); `pyproject.toml` (`license = { file = "LICENSE" }`)
  and the README agree — free for any noncommercial use, no monetization. The
  `egg-info/PKG-INFO` "Future Enhancements" note is a regenerated build artifact and refreshes on
  the next build.

## 6. Prioritized repair roadmap

- **P0 — done:** E1 resistance loader · E2 `grant_temporary_hp` · E3 save advantage/disadvantage.
- **P1 — done:** E4 friendly loader validation (enum lookups + `json.load`) · E8 logging fix ·
  E7 reconcile return shapes / update docstrings · E9 delete dead code (reconnection removed) ·
  spell schema + linter — originally `src/rules/step_schema.py` for the legacy `effects` shape,
  now `src/spells/validate.py` for the block `program` that replaced it (design stage 1).
- **P2 — mostly done:** E11 seedable RNG · E5 multi-term formula validation · E10 dropped
  `for_each_defender` · E12 CELL_FEET sync comments · **E6 resolved** (per-event field schema +
  load-time rule validation). _Still open: the per-session spell registry. E13 (license) resolved:
  PolyForm Noncommercial._
- **Then net-new features:** structured upcasting → reactions/OA → multiattack → death saves →
  the AI/auto-battle loop.

## 7. Appendix — file index for fast re-orientation

- **Engine core:** `src/combat/effect_pipeline.py` · `combat_system.py` · `attack_resolver.py` ·
  `spell_resolver.py` · `damage_processor.py` · `turn_manager.py` · `initiative.py`.
- **Rules:** `src/rules/expressions.py` · `rule.py` · `rule_loader.py` ·
  `effect_registry.py` (data); `src/spells/rules.py` (install).
- **Data/loading:** `src/loaders/stat_block_loader.py` · `src/models/entity.py` ·
  `stat_block.py` · `action.py` · `spell_properties.py`.
- **Web:** `web/routers/combat.py` · `web/app.py` · `web/static/js/*`.
- **Content:** `examples/spells/*.json`, `examples/creatures/**`, `rules/**`.
- **Authoring guides:** `examples/creatures/CREATURE_DEFINITION_GUIDE.md` ·
  `examples/spells/SPELL_DEFINITION_GUIDE.md` · `examples/spells/ANIMATION_GUIDE.md`.

## 8. Follow-on

The "implement a new spell" **skill** is well-supported by this architecture: a skill that reads
`SPELL_DEFINITION_GUIDE.md` + `ANIMATION_GUIDE.md`, writes a JSON file to `examples/spells/`, and
adds an execution test would be low-risk precisely *because* spells are pure data. Best built
after P1 adds a spell-JSON schema validator (E4) so the skill gets structured feedback.

### Arena adjacent problems (noted, not yet fixed)

- **A1. ~~`OpenRouterAgent` crashes on a malformed API response.~~ Fixed 2026-09-21** (`6a83459`).
  *The live-model preflight it called for exists since 2026-09-24 (`study run` preflight).*
  `_first_message` refuses a broken envelope as a `ProviderError` — a `NoToolCallError` subclass,
  so the turn driver's existing counted-failure handling applies unchanged. It is a *subclass*
  rather than a plain `None` return because the study must tell infrastructure (a §3.5 exclusion)
  from a model with nothing to say (never an exclusion); the two are recorded as `provider_error`
  and `no_tool_call`. The live-model preflight noted below is still outstanding. Original report:
  `openrouter_agent.py:_request_action` does `response.choices[0].message` unguarded; a free model
  that returns `choices=None` (error/empty payload — observed live with
  `nvidia/nemotron-3-super-120b-a12b:free`, 2026-09-15) raises `TypeError` and aborts the whole
  match. Free-model APIs are flaky (rate limits, error bodies, truncation); the adapter should treat
  a missing/empty `choices` as "no tool call" (return `None`, which the turn driver already handles
  as a counted failure) rather than crash. Belongs with the batch-runner robustness work — a batch
  must survive one flaky response. Same fragility class as the dead default model
  (`DEFAULT_MODEL = nvidia/nemotron-nano-9b-v2:free` 404s; needs a live-model preflight).

#### Interface-study ledger (C1 work, opened 2026-09-24)

Problems noticed while building the conditions, logged here so they are fixed deliberately in
a later slice or the final cleanup rather than folded silently into unrelated commits. Each
names where it should be addressed. Append; strike through and date an item when fixed.

- **A2. ~~First-attempt validity must count the correction re-prompt as a failure.~~
  Implemented 2026-09-24** in `study_report` (`first_attempt_valid` = accepted in one
  request), and defined in PREREGISTRATION §6. Original note: A decision
  whose first response contained no action gets one free re-prompt (`decide_one_action`), so a
  decision can succeed "eventually" after a failed first attempt that no rejection records. The
  H1 metric must treat `request_count > 1` *or* any rejection as first-attempt invalid, in
  every condition alike. → slice 3 (analysis script).
- **A3. `cast <area spell> at <creature>` sends `target_ids` to an AoE spell.** C1 reads that
  phrasing into exactly the call a C2 model would send (parity holds), but how the engine
  answers an AoE spell given targets and no point is unverified — if it is `engine_error`, both
  conditions are being charged for an engine gap rather than a model error. → checked in C1
  slice 2 (parser corpus); outcome recorded here.
  *Checked 2026-09-24:* not an engine gap — the engine refuses with a **typed** code,
  `unknown_target` ("Fireball is an AOE spell and requires a target point"), identically for
  C1 and C2. Open only as a taxonomy question: `invalid_target_relation` may be the truer
  category. → decide with the other taxonomy splits at the freeze (prereg §6).
- **A4. Identifier tie-break with duplicate names.** The resolver tries ids before display
  names, so with two creatures named "Goblin" (`goblin`, `goblin-2`) the spelling `Goblin`
  resolves to `goblin`, though a reader might call it ambiguous. No study roster can hit this
  (`test_every_identifier_in_a_scenario_has_its_own_key`); revisit if duplicate names enter the
  study.
- **A5. ~~Multiple tool calls are handled differently per provider.~~ Fixed 2026-09-24**
  (`4fd3358`): both adapters count `extra_tool_calls` per request. Original note: Anthropic disables parallel
  tool use; OpenRouter's adapter silently takes the first of several calls. That is a provider
  asymmetry inside C2/C2+M/C3 and discards evidence. Record the count of extra calls per
  request so the analysis can see it. → final cleanup (before the pilot).
- **A6. ~~Capability entries carry an empty `description`~~ Fixed 2026-09-24** (`4fd3358`).
  Original note: for every scenario attack
  (`_serialize_action` reuse) — token noise in every prompt. Drop empty descriptions. → final
  cleanup (changes prompt hashes; do before the freeze).
- **A7. Repo hygiene.** CI lints `src/` and `web/` but not `tests/` (one pre-existing E501 in
  `tests/arena/test_interfaces.py:1`); working copies have mixed line endings (LF/CRLF warnings
  on files written by tooling) — add a `.gitattributes`. → final cleanup.
  *Measured in the Phase 1 review (2026-09-24):* `flake8 tests/` reports 109 findings (67 E501,
  31 F401, 5 F841, 2 E731). There are also 4 F821s from a `dir()`-based name hack in
  `tests/test_block_entity_effects.py` that works at run time but should simply use the bound
  name. `tests/arena/test_heuristic_score.py::test_hidden_capabilities_fall_back_to_generic_threat`
  builds a hidden-capability policy and never uses it, so it checks `features.threat` directly
  rather than the policy path its name claims. Line endings: 4 files are mixed.
- **A8. C1 reads a trailing justification into the final name.** `ACTION: attack raider-1
  with Dagger since it's adjacent` parses with the weapon "Dagger since it's adjacent", which
  the executor refuses as `unknown_action`, though a reader would find the action. Pinned in
  the corpus as a known boundary rather than patched with a clause heuristic before any real
  output exists. → Phase 2 pilot: if it occurs, add a published tolerance before the freeze
  (and it is exactly what the §7 audit's false-reject rate would expose).
  *2026-09-24:* the **lenient bound** now drops a trailing justification, so the study's
  upper bound already credits these lines. The primary parser is unchanged, pending pilot
  evidence.
- **A9. ~~A call's arguments reach the transcript unscrubbed, in every condition.~~ Fixed
  2026-09-24** (`4fd3358`). The fix is wider than first logged: the raw `tool_call`, and the
  referee's result (which echoes a bad id back), were also unscrubbed. Everything now passes
  `scrub_value` at the transcript boundary. Original note: The secret
  scrub runs on `RequestRecord` fields at serialisation, but `Transcript.action` logs
  `call.arguments` as-is — so a model that echoes a key-shaped string into an end-turn `note`,
  a name, or (C1) an unreadable line's `text` would write it to disk. C1's `interpretation`
  field is scrubbed (added with it, 2026-09-24); the arguments path is older and shared.
  → final cleanup: scrub string arguments at the transcript boundary, with a test that writes
  a real transcript and greps it (the 2026-09-21 lesson).
- **A10. ~~Menu length was never recorded.~~ Fixed 2026-09-24.** Prereg §2 records menu length
  per decision as a cost covariate, but nothing wrote it, and a report could only have
  recovered it by replaying. `DecisionTelemetry.menu_length` now holds the number of legal
  options shown (menu conditions only), set by `ActionInterface.menu_length`.
- **A11. Plots deferred.** V1_PLAN asked the report for 2–3 plots. They would add matplotlib,
  and the study's claims rest on the tables, so the report is text and CSV only for now.
  → Phase 4 (write-up): plot from `report/*.csv`, ideally in a separate script.
- **A12. Two older modules import `random` directly**, against CLAUDE.md §7 ("`dice.py` is
  the only module that touches `random`"): `src/arena/agent.py` (RandomAgent's own stream)
  and `src/arena/heuristic/ga.py` (the GA). Both are seeded, so determinism holds, but the
  stated invariant does not. → final cleanup: route both through `dice.new_rng`, or amend the
  rule to say what it actually protects (game RNG versus agent or analysis streams).
- **A13. `openrouter_agent.DEFAULT_MODEL` is the known-dead free model**
  (`nvidia/nemotron-nano-9b-v2:free` 404s). The study never uses it, because grids name their
  models, but the example scripts default to it. → final cleanup: drop the default, or point it
  at a live model and say so.
- **A14. ~~Real-world malformed output crashed the harness.~~ Fixed 2026-09-24** (Phase 1
  review). Unparseable or non-object tool arguments (`json.loads` unguarded in the
  OpenRouter adapter), `null`/wrongly-typed argument values (`TypeError` uncaught in
  `ToolExecutor.apply`), and a move by `option_id` in C2/C2+M (a dual path the schema had
  closed but the executor still honoured). The first two stopped the grid as "harness
  bugs"; the third was a between-condition confound. Coded as `malformed_output`
  (prereg §6); `mock_model`'s `hostile` stumble style and a hostile offline smoke keep
  them covered. The review's other findings (per-request provider retry, fresh-decision
  H1, paired decision rules, out-of-range area aim, pilot readiness) are the next slices.
- *(Known and declared in code, not duplicated here: multi-target spells are enumerated
  nowhere — `enumeration.multi_target_spells_not_enumerated`.)*

