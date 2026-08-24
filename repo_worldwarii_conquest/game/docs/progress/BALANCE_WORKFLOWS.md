# Balance Workflows

This project should treat balance as a repeatable workflow, not a one-off stat edit.

## Workflow 1: Numeric Diagnosis

Use `python3 tools/balance_report.py` to regenerate `docs/progress/balance_report.md`.
Use `python3 tools/balance_report.py --baseline docs/progress/baselines/units_pre_balance_patch.json`
when reviewing the first balance patch against the pre-patch catalog.

The generated report covers:

- Unit catalog values.
- Damage and counter matrices.
- Terrain and dig-in damage matrices.
- Suppression / dig-in break matrix (`Sx/Dy`) for town + dig-in targets.
- Hits-to-kill under plain and town + dig-in 3 conditions.
- Optional baseline deltas for stat changes, damage changes, and hits-to-kill changes.
- Scenario unit and terrain exposure.
- Known rule risks.

This workflow should run before and after every proposed stat patch.

## Workflow 1.5: Validation Hook

Use `tools/validate_fast.sh` for validation that does not launch Godot:

- Godot 4.2 project-feature gate.
- JSON validation for unit catalogs.
- Python syntax checks for report, probe and validator tools.
- Regeneration of balance and scenario reports.
- Scenario balance report smoke checks for urban breach diagnostics.
- Regeneration of scenario probe report.
- Scenario probe smoke checks for breach-path diagnostics.
- Regeneration of tutorial probe report.
- `git diff --check`.

Use `tools/validate.sh` for the full standard validation sequence:

- Everything in `tools/validate_fast.sh`.
- Regeneration of the Godot AI trace report.
- AI trace report smoke checks for exposed objective-chain diagnostics.
- Regeneration of the Godot AI self-play report (full headless AI-vs-AI battles).
- AI self-play report smoke checks (clean resolution, difficulty-ladder verdicts).
- `bash tests/run_all.sh`.

Use `tools/install_hooks.sh` to install a local git `pre-commit` hook that runs
`tools/validate.sh` before every commit.

## Workflow 2: Rule Semantics

Current rules established before large number changes:

- Direct attack target selection requires current visibility and LOS.
- Indirect attack target selection requires current visibility but ignores LOS blockers.
- `indirect` means the unit cannot counter-attack while defending; it does not grant close-range immunity when attacking.
- ZoC cost is part of both movement range and path reconstruction.
- Damaging attacks apply suppression through `CombatEffects`; MG teams and artillery are the primary pinning sources.
- Damaging indirect fire gets +1 suppression when a same-faction light tank has LOS and vision to the target.
- Light tanks can also spend their action to mark a visible LOS target; the next same-faction active attack against that target consumes the mark and adds +1 suppression through `CombatEffects` only on non-lethal damage.
- Engineers can spend their action to mark a nearby visible entrenched LOS target; the next same-faction active attack against that target consumes the mark and adds +1 dig-in loss through `CombatEffects` on damaging hits.
- Pinned units cannot overwatch or build dig-in and do not project ZoC; heavier suppression reduces movement/attack, indirect fire strips one dig-in level on damaging hits, and engineers strip up to two dig-in levels on damaging attacks.
- Rally spends the unit's action to recover suppression; defensive cover improves the recovery amount.
- Secondary objectives are optional capture, hold-turn, recon-hex or destroy-unit tasks that can require earlier secondary completions, can belong to explicit mutually exclusive branches, grant one-time data-authored rewards such as XP, suppression recovery, repair, reinforcement timing or local enemy suppression, and do not alter victory resolution.

These semantics materially affect artillery, AT guns, overwatch, and fog-of-war balance.

## Workflow 3: Role Differentiation

Target identities:

- Infantry: durable terrain holder and ZoC anchor.
- MG team: anti-infantry lane denial and active suppression; MG overwatch uses full reaction-fire damage while normal overwatch remains half damage, and suppressive fire trades damage for short-range control.
- AT gun: anti-armor specialist with weak soft-target pressure.
- Tank destroyer: mobile anti-armor ambusher; it gets extra anti-armor only when firing from its authored standoff range.
- Light tank: scouting, flanking, capture pressure, wounded-target cleanup.
- Medium tank: general-purpose armored mainstay.
- Artillery: long-range suppression with clear close-range vulnerability.
- Engineer: close assault support that can strip up to two dig-in levels from entrenched defenders and can prepare a breach for a follow-up attack, but still has low raw damage and must accept counter-risk.

## Workflow 4: Scenario Pass

Use `python3 tools/scenario_balance_report.py` to regenerate
`docs/progress/scenario_balance_report.md`.
Use `python3 tools/scenario_probe.py` to regenerate
`docs/progress/scenario_probe.md` for suppression sources, artillery coverage,
spotter coverage, breach-path distance, terrain-aware breach tempo, artillery
reposition coverage, objective pressure, secondary pressure, reinforcement
deltas, secondary reward audits, secondary branch coverage, campaign in-battle
reward coverage, conquest region trait coverage, and the Stalingrad/Berlin
urban breach focus gate.

Evaluate scenarios in this order:

1. `03_stalingrad_1942`: town density and dig-in durability.
2. `05_bastogne_1944`: survival pacing and reinforcement timing.
3. `04_kursk_1943`: armor versus AT-gun interaction.
4. `02_kiev_1941`: artillery dominance and screening requirements.
5. `01_sedan_1940`: river/forest breakthrough tempo.

Urban breach gates before scenario edits:

- Check `urban breach tools` in `scenario_balance_report.md` before changing rosters.
- `03_stalingrad_1942` gives the Axis one engineer and one artillery unit, with the engineer forward enough to reach breach contact in about three turns (`eng min 7`, `eng turns 3`) and artillery able to cover one breach target after repositioning (`art move 1/6`); playtest whether this creates pressure without collapsing the Soviet defense too quickly.
- `east_10_berlin_1945` gives the Soviet assault group one engineer and one artillery unit, with the engineer forward enough to reach breach contact in about three turns (`eng min 7`, `eng turns 3`) and artillery able to cover one breach target after repositioning (`art move 1/3`); tune turns or defenders only after confirming the breach sequence survives enemy fire.
- Do not treat MG teams as breach tools. They are suppression support for the assault sequence.

## Workflow 5: AI Compatibility

After rule or stat changes, inspect whether AI scoring still understands the new roles.

Use `godot --headless --path . --script res://tools/ai_trace_report.gd` to
regenerate `docs/progress/ai_trace_report.md` when AI scoring, role shaping or
action selection changes. The trace report calls `AIController.plan_trace_for_unit()`
instead of mirroring the scoring formula in Python.

Current role-shaping pass:

- Light tanks get a scouting-position bonus when no enemy is currently visible.
- Light tanks can mark fire-support targets; AI scoring evaluates the active mark only when a same-faction follow-up attacker can use the suppression bonus.
- AT guns prefer armored targets over soft targets when damage is otherwise close.
- Artillery avoids close positions near known enemies.
- Engineers prefer entrenched urban/high-cover targets when their attack would remove dig-in.
- Engineers can also move toward visible entrenched/high-cover breach targets before they are already in attack range.
- Engineers can mark nearby entrenched targets for breach support when a same-faction follow-up attacker can use the extra dig-in loss.
- Attack value includes suppression and dig-in break, so AI can prefer pinning/siege hits over equal raw damage.
- Attack value includes light-tank spotter support for artillery, so scouting can break raw-damage ties.
- Capture factions bias movement toward their target hex.
- Unfinished secondary objectives add a smaller movement bias toward their target hex.
- Recon and destroy-unit secondary objectives bias movement toward their target hex or marked unit, and destroy targets get a direct attack-score bonus.
- Secondary objective movement pull includes deterministic reward value, so tactical rewards such as local suppression or breach rewards can matter before raw distance ties.
- Secondary objective movement pull includes immediately unlocked follow-up value, so prerequisite objectives can surface the next tactical or strategic payoff without scoring locked chains too early.
- Secondary objective movement pull stops scoring mutually exclusive branch alternatives once one objective in that branch completes.
- Suppressed units can choose Rally when recovery is worth more than other actions.
- Overwatch scoring uses unit-data reaction-fire percentages, so MG lane denial reflects its full-damage reaction profile.

## Workflow 6: AI Self-Play Probe

After AI scoring, action selection or balance changes, verify the AI in full
battles — not just synthetic trace situations.

Use `godot --headless --path . --script res://tools/ai_selfplay_report.gd` to
regenerate `docs/progress/ai_selfplay_report.md` (~10s). The generator drives
the real battle scene with every faction handed to `AIController` via
`tools/selfplay_runner.gd`, so combat, morale, overwatch, reinforcements and
victory all execute through game code. The engine is RNG-free, so reruns are
byte-identical until AI or data changes. Prefix with
`XDG_DATA_HOME="$(mktemp -d)"` to keep the game-over replay write out of your
real user directory (validate.sh already does this).

Run matrix and how to read it:

- One tutorial canary plus symmetric mirror matches (easy/easy, normal/normal,
  hard/hard) across theaters (gazala, guadalcanal, dnieper, stalingrad, kursk,
  sedan, bastogne) measure attacker/defender balance per difficulty.
- Ladder runs play the attacking seat hard-vs-easy in both orientations. The
  metric is the seat's HP exchange (enemy HP destroyed minus own HP destroyed);
  the hard seat must not do worse than the easy seat. `tools/check_ai_selfplay_report.py`
  recomputes the verdicts from the table and fails validation on a regression.
  Only scenarios whose AI-vs-AI mirror is a clean monotonic ladder are gated
  (gazala, guadalcanal, sedan); a heavily out-powered attacker (berlin, cbi,
  stalingrad, kursk, dnieper) makes the AI-vs-AI ladder unreliable, so those stay
  symmetric-coverage only — judge their winnability with a human/reference
  attacker, not this AI-vs-AI mirror.
- The Morale activity section tallies routs and reform events straight from live
  battle state; the checker requires at least one across the suite so a refactor
  cannot silently disable the rout/rally layer while runs still resolve.
- The Notes section flags pathologies straight from the data: stalled runs,
  turn-cap hits and zero-damage no-contact sides.

`tools/validate.sh` regenerates and checks this report on every full
validation, so committed AI changes cannot silently break the difficulty
ladder or stall a battle.
