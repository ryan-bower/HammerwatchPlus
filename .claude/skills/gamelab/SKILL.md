---
name: gamelab
description: Run, write and debug GameLab scenarios - the only sanctioned way to auto boot Heroes of Hammerwatch II. Use to smoke-test a mod in the live game, measure an engine fact on the pinned build, drive the player with a Pilot bot, or read a run's run.json and exit code. Also use to set up a fresh clone or new machine (missing gamecode/, decompiled scripts, tools/bin, save backups) via `python -m gamelab doctor`. For a one-off screenshot, use game-screenshot instead.
---

# gamelab

GameLab boots HoH2 on a hidden desktop, muted, with its own profile and saves, builds a
known character (a fixture), runs a JSON scenario against the live game and writes a
verdict. Purpose: claims about the game are measured on the pinned build and cited by
run dir, never assumed.

This is a committed workflow for any agent, not a Claude-only API. First read the
[canonical agent rules](../../../AGENTS.md), [GameLab quickstart](../../../gamelab/README.md),
and [regression guide](../../../docs/qa/REGRESSIONS.md). They provide the portable
entry point, current evidence index, test selection, and known prerequisite failures.
Use this skill for the detailed scenario and engine-command reference.

## First: is this machine ready? (`doctor`)

A fresh clone lacks everything gitignored: `.venv`, `gamecode/` (the game's scripts and
datatables), `tools/bin/` (patched PACKAGER, capture shim), the GameLab game dir and any
save backup. Run this before anything else in a session, and before every run on a
clone you haven't checked:

```
python -m gamelab doctor         # report only; exit 0 green, 2 not ready
python -m gamelab doctor --fix   # uv sync, confirm saves (when unambiguous), bootstrap.py, env_link.py,
                                 # class_units.py, the HoH1 imports once HoH1 is known,
                                 # make_pet_dyes.py, then one smoke boot
python -m gamelab doctor --hoh1 "<dir>" --fix   # the user told you where HoH1 is
python -m gamelab doctor --no-hoh1               # the user does not own HoH1
python -m gamelab doctor --smoke                 # boot null-payload again now, whatever the stamp says
```

After setup creates `.venv`, use `uv run python` or `.\.venv\Scripts\python.exe`
instead of bare `python`, as explained in the quickstart, so the project dependencies
are available.

**HoH1: ask, never guess.** doctor finds Heroes of Hammerwatch (1) through Steam (any
library), a path the user gave earlier (`tools/paths.local.json`, gitignored), or a search
next to the HoH2 install and in every library's `steamapps/common/`. When none of that
works and nobody has answered yet, the `HoH1 install (optional)` row is `[NO]` and
says `ASK THE USER`. doctor stays NOT green until they answer, so ask them:

> Where is Heroes of Hammerwatch (1) installed (the folder with HWR.exe)? Or don't you own it?

- They give a folder: `python -m gamelab doctor --hoh1 "<folder>" --fix`. The folder must
  have `HWR.exe` and `res/assets.bin`, or nothing is recorded and doctor exits 2; ask again.
  HoH2's folder (HWR2.exe) is not it. Never pass a path they did not give you.
- They don't own it: `python -m gamelab doctor --no-hoh1`. HoH1 content is then reported
  as skipped, not failed. A later `--hoh1` undoes it.

Once HoH1 is known, `--fix` also runs bootstrap for `gamecode/sdk/hoh1/`, then
`tools/import_hoh1.py pets|levels|campaign|classes`. It runs each importer only when its
output is missing and never with `--force`, so a second `--fix` writes nothing. If
`mods/campaign/hoh1/` exists without the importer's `.hwp-generated` marker, doctor
reports it and leaves it alone. Ask the user before moving it.

- `--fix` only writes inside the repo. bootstrap copies the install's `PACKAGER.exe` to
  `tools/bin/`, patches out its Steam check, and unpacks `res/assets.bin` into
  `gamecode/sdk/hoh2/` on a hidden desktop (~1 GB, a few minutes), then exports
  `gamecode/datatables/`. Nothing is written to the install.
- That unpack is the "decompiled source". Every HoH2 binary is native C++, so ILSpy
  does not apply. The game's logic is the AngelScript in `gamecode/sdk/hoh2/scripts/`.
  The native engine API is only the strings in `gamecode/assets/hwr2_api_strings.txt`.
- No auto-fix for these; tell the user what to do:
  - **Steam not running**: start Steam.
  - **Build not pinned**: Steam updated the game. Re-pinning is a team decision
    (exit 3 row below), never a quick fix.
  - **No gcc mingw-w64 x86_64**: needed to build the capture shim. Example:
    `choco install mingw`, then a new shell.
  - **Repo on a different drive from the install**: `res/assets.bin` is hard-linked,
    so clone onto the Steam library's drive.
  - **Low disk space.**
- `--fix` also runs `tools/class_units.py` when its gitignored unit copies in
  `mods/keys/` and `mods/pets/` are missing or stale (made from `gamecode/sdk/hoh2/`).
- `--fix` runs `tools/make_pet_dyes.py` (the dye-ready pet copies in
  `mods/pets/players/pets/hwp/dye/`) after the HoH1 content steps, because it needs the
  HoH1 pet import too. Its stamp (`.hwp-generated.json`) holds the generator's and every
  source's hash, so a new HoH1 import, an edited pet unit or a changed generator marks it
  stale and the next `--fix` remakes it (`python tools/make_pet_dyes.py --verify` checks).

**Smoke boot.** Once every row it needs is green (HoH1 and content rows don't count),
`--fix` boots `null-payload` in lab mode once. It proves this machine's GPU, antivirus
and core count let GameLab work at all. A pass is stamped in `gamelab/smoke.local.json`
(gitignored) with the build, shim source, core count and GPUs; change any of those and
it boots again. A failure is reported as its plain cause, and recorded, so plain
`doctor` keeps repeating it. A failed boot often leaves the lock dirty (exit 4). The next
`--fix`/`--smoke` clears that with `python -m gamelab reset` only when the dirty
teardown is doctor's own failed smoke run; any other dirty teardown still needs you to
find out why. Pass the cause on to the user, because the fix is on their machine:

| cause doctor prints | what it means / what the user does |
|---|---|
| Windows refused to load the capture shim | antivirus/EDR blocks DLL injection: allow-list `tools/bin/hwr2_capture.dll` and the GameLab `HWR2.exe` |
| renderer did not start on the hidden desktop | no OpenGL 3.2 context: update the GPU driver, pick the dedicated GPU, avoid remote desktop |
| captured frames were blank or missing | the driver doesn't render on a non-interactive desktop (remote desktop, hybrid GPUs) |
| too slow: the deadline passed (N of M cores) | GameLab gets all cores but two at idle priority: close heavy programs; ≤4 cores is marginal |
| game window reached the real desktop | remote desktop or overlay/recording software: close it |
| game exited before writing its log | Steam not running / not the owning account, or antivirus killed it |
| changed the user's config, saves or install | stop and report: must never happen |
- The Discord mirror is out of scope.

**Saves gate.** The launcher (exit 2) and `deploy.py modded-prod` refuse until
`saves-backup/confirmed.json` exists and its backup still re-hashes. bootstrap's
datatables step boots the game through GameLab, so `--fix` confirms saves before it
bootstraps.

- **Unambiguous: `--fix` confirms by itself.** Unambiguous means all of these hold:
  - save files exist;
  - the dir the player's config writes (cloud or local) has files;
  - no other Steam account on the PC has HoH2 saves;
  - no unknown `save*` dir in the install holds files.

  In that case `--fix` does the following, then prints the restore command:
  - runs `tools/saves_selftest.py` (backup, verify and restore, on a sandbox);
  - copies the real saves to `saves-backup/<ts>/`;
  - re-hashes the copy and checks it against the real saves;
  - writes the stamp.

  Pass that restore command on to the user.
- **Anything else prints `AMBIGUOUS:` lines and stops. Ask the user.** Only they know
  whether another account's saves matter, or whether they have never saved. If they
  still want the backup as listed, run `python -m gamelab doctor --confirm-saves`
  (plus `--no-saves-yet` if they never saved). The stamp records what they overrode.

Never write the stamp by hand. Never run `saves.py restore` without the user asking:
it overwrites their real saves (it backs up the current state first).

The first scenario run on a new machine also builds the fixtures (cache is per build
and recipe), so it does two extra boots. A slow first run is normal.

Doctor also generates Forgemaster risen/body units through
`tools/make_forgemaster_risen.py`. These generated game-derived prerequisites are
local setup outputs; use doctor to refresh them. `mod-all` covers the 31 normal-release
modules; the optional `holylocal` module is local-only and outside that stack.

## Hard rules

- `--mode lab`, always. The default is `watch`, which puts the game window on the
  user's desktop.
- Never start `HWR2.exe` directly unless the user specifically asks. Never touch the
  user's `HWR2.exe.cfg`, Steam or local saves, `%LOCALAPPDATA%/HeroesofHammerwatch2` or
  install `res/`; the launcher checks these and a change makes the run INVALID.
- No real input (`SendInput`, `keybd_event`, `mouse_event`, `SetCursorPos`,
  `SetForegroundWindow`, `bring_to_front`). Input is the `key` step (PostMessage) or
  `gl input`. Never PrintWindow: it is blank on the hidden desktop.
- One run at a time, machine-wide (one shared game dir, `gamelab/lock.py`).
- Designate one runtime owner for a serial queue. The machine lock does not prevent
  source edits: freeze installed gameplay, harness, bots, scenarios, and tools until
  the queue reaches a clean boundary. Stage independent drafts under ignored
  `gamelab/results/`; review and install them between runs, then compile/load before
  dependent effect tests. The deliberate scenario-owned `write_*_file` steps below
  are restored measurement tests, not permission for concurrent ad hoc edits.
- Gate dependent cases on successful setup/controller/observer contracts. After a
  transport error, inspect what completed before retrying; after dirty teardown,
  stop launches until the cause is known and the refused state is safely resolved.

## Running and exit codes

```
python -m gamelab list [it]
python -m gamelab run <scenario> --mode lab [--wait 1800]   # --wait: queue behind another agent's live run
python -m gamelab suite it/<mod> --mode lab                  # every integration scenario of a module, in order
```

Integration tests (full happy/error paths, run on purpose, not on every change) live in
`gamelab/scenarios/it/<mod>/`; run one as `python -m gamelab run it/<mod>/<name> --mode lab`.
The launcher takes the lock before preflight (preflight re-links the mods dir, which must not
happen under another live run).

| exit | verdict | do |
|---|---|---|
| 0 | PASS | |
| 1 | FAIL | a result, not a refusal: read `run.json` assertions and `error` |
| 2 | preflight | read the failed preflight assertion. `saves: ... not confirmed` means run the doctor and the saves gate above |
| 3 | build changed | `python tools/pin_build.py --show`, then `python tools/pin_build.py --reason "<why>"`, then `python tools/bootstrap.py --force` (the dumps are stale). `--accept-build-drift` overrides for one run and stamps it `build_drift` |
| 4 | lock / dirty teardown | read the `REFUSED` line. "another GameLab run holds the lock": another agent is running, wait. Stale lock or dirty teardown: find the cause in the last run's `run.json` `teardown`, then `python -m gamelab reset` |
| 5 | INVALID | the run can't be trusted: user config, saves or `res/` changed, focus left the user's window, or only `shot ...` assertions failed (the frame disagrees with probes that passed) |
| 6 | TIMEOUT | what was collected is kept |

Results in `gamelab/results/<YYYYmmdd-HHMMSS>-<scenario>-lab/`:
- `run.json`: outer launcher verdict, assertions, `error`, `teardown`, build, and
  isolation evidence. This is the final run verdict, not just the bot's aggregate.
- `inner.json`: runner observations/assertions, pass/live verification state, and
  references to completed bot results. It is rewritten after assertions; `partial`
  indicates that it is not a final runner result.
- `bot-results.jsonl`: full returned observations from completed bot steps, appended
  before their expectations are scored. Assertion summaries are intentionally short;
  read these records to inspect individual trials. A bot that raises before returning
  may leave no completed record, so use the error, telemetry, and logs too.
- `runner.out.txt`: runner stdout and traceback.
- `gl.jsonl`: telemetry.
- `logs/pass<N>.HWR2.exe.log`: game log; the scenario is the last pass.
- `shots/*.png`: Read them; never describe one unread.
- `boundaries.md`: when the scenario has `boundaries`.

Cite a result as `<scenario> <YYYYmmdd-HHMMSS>`.

A clean native PASS requires exit 0, outer `run.json` verdict `PASS`, no error,
`teardown.clean: true`, `build_drift: false`, and final `inner.json` with
`partial: false`. A successful bot aggregate alone is insufficient.

Record the tested source revision/fingerprint alongside the pinned build and run ID.
Neither `run.json` nor `inner.json` contains a global source fingerprint; the launcher
records build/mod and isolation facts. A serial workflow must separately record and
compare its source epoch. Do not assume the machine lock proves source
stability, or that an earlier pass covers later source changes. Keep before/after
failures, fixed trial counts, expected-source anchors, and actual effects. Source-only
review, controlled setup, and ordinary play are separate scopes. Bindings, counters,
or successful debug setters alone do not prove gameplay effects.

Raw run directories are ignored/local. Use the regression guide's committed checkpoint,
inventories, and compact evidence records for a portable handoff. A manifest for an
ignored/unapplied draft is not the draft itself and is not a native PASS; revalidate
its baseline/pins after a commit, rebase, or other source change before applying it.

## Scenario file (`gamelab/scenarios/<name>.json`)

```json
{"name": "mod-x", "about": "what this proves", "fixture": "town-paladin",
 "mods": ["x"], "timeout": 120,
 "steps": [
  {"do": "log_has", "pattern": "\\[HWP:x\\] self-check done", "timeout": 20},
  {"do": "gl", "verb": "state", "expect": {"phase": "town", "player.level": {"between": [1, 5]}}},
  {"do": "shot", "name": "town"},
  {"do": "log_clean"}]}
```

- Top-level keys:
  - `name`, `about`, `fixture`, `steps`.
  - `mods`: `mods/` folder ids, enabled on top of the fixture's; the enabled set is asserted exactly.
  - `timeout` (default 300): the step budget; the whole run gets 3x, to cover fixture builds.
  - `boundaries`, `probe_menu` (below).
  - `explore: true`: the only way an `exit` writes new edges to `gamelab/travel/learned.json`.
- `forget_edges: [[from, to], ...]`: this run treats those edges as unknown, so an `explore`
  scenario re-proves learning every run; the fresh crossing replaces the stored entry.
- `expect` is `{dotted.path: value}` against the reply, or `{"between": [lo, hi]}`.
- `save_as` names a reply for `assert_more`, `assert_dist`, `loot_check` and `boundaries`.
- Templates: `mod-fishing.json` (mod smoke test), `pilot-floor.json` (bot, shots, `shot_changed`).

## Step kinds (`do`)

| step | fields | what |
|---|---|---|
| `gl` | `verb`, `args`, `expect`, `save_as` | one in-engine command |
| `wait_phase` | `phase`, `timeout` | wait for `town` / `mission` / ... |
| `pilot` | `call`, `args`, `until`, `timeout`, `expect` | one Pilot intent |
| `bot` | `bot`, `kwargs`, `expect` | run `gamelab/bots/<bot>.py` |
| `shot` | `name` | a real frame at the profile resolution; an `end` shot is automatic |
| `shot_changed` / `shot_diff` / `shot_tint` | `before`, `after`, ... | pixels must agree with what the probes say |
| `log_has` / `log_lacks` | `pattern`, `timeout` | regex in this pass's game log |
| `log_capture` | `pattern`, `save_as`, `timeout` | the named groups of the regex's last match, saved as `{match: {...}}` (numbers where they parse); `assert_dist` with `path: "match"` compares logged positions |
| `log_clean` | `allow` | no script errors in our mods' files; `allow` regexes drop expected error lines (with the `From "<file>" line N` line after each) |
| `overlays` | `allow` | nothing unexpected drawn over the world |
| `assert_more` | `than`, `now`, `path` | the values under `path` grew |
| `assert_dist` | `a`, `b`, `path`, `min`, `max` | distance between two saved `{x, y}` |
| `loot_check` | `than`, `now`, `file`, `entry` | the gain is one the loot table can produce |
| `restart` | | quit (the game saves) and re-enter the fixture |
| `write_mod_file` / `write_bot_file` | `mod`/`path`, `replace`, `with` | edit a file mid-run, restored at the end |
| `same_process` | `mark` / `since` | assert no restart in between |
| `retry` | `times`, `until`, `timeout`, `steps` | rerun `steps` until `until` (regex) shows in new log lines, up to `times`; fails after the last try. For a random level feature (a room that may not roll), not to hide a bug |
| `sval` | `file`, `dest` | export a datatable as the game parsed it |
| `key`, `console`, `sleep`, `minimize` | | posted key, raw console line, wait, minimize |
| `type` | `text`, `gap` | posted WM_CHARs into whatever has the keyboard (a textinput pressed with `gl menu <tab> - <widget> !click`). Each `gl` command opens the console, whose key char (`) reaches a focused field unless the field forbids it; identical consecutive chars arrive once ("qqq" -> "q") |
| `console` + `expect` / `lacks` | `line`, `expect`, `lacks`, `timeout`, `settle`, `save_as` | a console line (`hwp ...`) whose reply is matched in the log written **after** it (typed-line echoes left out) |
| `click` / `hover` | `widget` (+`n`, `root`, `any_window`) or `x`,`y`; `verify`, `after`, `click_anyway` | a human click / pointer move with the emulated mouse (`gl pointer`, `gamelab/ui.py`) at the widget's centre; by default fails unless the game kept the position, the window hovers the widget and took the press and release |
| `mark` | `name` | a point in the log; `log_has` / `log_lacks` take `"since": name` |
| `assert_delta` | `than`, `now`, `path`, `equals` / `between` / `in` | `now - than` at a numeric path (gold spent: `equals: -40000`; a bet: `in: [-100, 0, 100]`) |
| `compare` | `a`, `b`, `same`, `differ` | paths equal / not equal between two saved replies (a refused action changed nothing) |

`{$name.dotted.path}` inside a `gl` or `pilot` step's `args`, or a `console` line, is replaced by that saved
value (a missing one fails the run). It hands a unit id from `near` to `pilot use`, or a logged position from
`log_capture` to `pilot path_to`, so the player walks to it. `gl cull mine` credits the local player with the
kills (XP, `PlayerKilledActor` hooks), which plain `cull` does not.
Don't press Escape after a `gl use` that may have failed: with no window open it opens the pause menu, and
module timers stop until it closes.

`expect` values may also be `{"match": regex}`, `{"not": v}` or `{"in": [v, ...]}`.

### Using the UI like a human

- A town session starts with an arrival cinematic: the game walks the player itself and drops
  input until `gl cinema` reports `active: false` (Player.as:1388-1395; diag-teleport
  20261018-053946). Act after it.
- Open an NPC's window: the `use_unit` bot (`gamelab/bots/use_unit.py`), kwargs `name` (unit
  name or behaviour, as `near` filters), `window`, `teleport: true` for town NPCs the Pilot
  cannot route to (a labelled setup cheat). It presses the Use key when the unit is the top
  usable.
- Find what to click: `gl clickables [top|all] [id]` (what the top window's hit-test can
  reach: id, func, enabled, shown, text, `px`/`py`); `gl widget <id> [n] [top|all]` (one
  widget's text/state/position, `count: 0` when absent); `gl widgets` (whole tree, positions).
- Click it: `{"do": "click", "widget": "bet-btn-2"}` (the emulated mouse, as a player; posted
  WM_MOUSE* never reach the game) or
  `{"do": "gl", "verb": "press", "args": ["bet-btn-2"]}` (the top window's widget's own
  ClickDown/ClickUp, no mouse; it does not check that the widget is shown or enabled). Prefer
  `click`; `press` when the mouse path is not what is under test.
- Only the top window gets input (WindowManager::Update); a widget sits at
  `window.m_origin + widget.m_origin` GUI units, times `m_wndScale` in pixels.
- Script paths must be unique across mods: two mods with the same `scripts/...` path shadow
  each other (ProbeUi.as / HandsUi.as, 2026-10-18).

## Fixtures (`gamelab/fixtures/`)

- `town-paladin`: level 1, in town.
- `town-tavern`: town-paladin plus a built tavern. The lab town is minimal: `farm_0`
  with no fields (4 soil patches from -560,1040, the well at -648,980 beside the pet bowl
  at -600,980), no farmer or Pet Shop NPC (a bot spawns them beside the player with
  `spawn`), no Hunter's Lodge (`build hunters_cabin` + `townrefresh`).
- `mission-ranger`: level 20 full build, for combat floors.

Recipe keys: `slot` (0), `binary_edits.enable_mods`, `character`, `setup` (gl verbs),
`save_town`, `readback`, `readback_probes`. Only `readback` and `readback_probes` are
checked, so give every `setup` effect a probe. A fixture is cached per build and recipe
hash; the first run after a change does two extra boots.

## gl verbs

The current registered verbs and doc comments are in the
[generated catalog](../../../docs/generated/verbs.md), or `gl help` at runtime.
Use `python tools/list_verbs.py --check` to verify that the catalog matches source;
do not rely on a fixed verb count in this skill.

- Read: `state`, `scan`, `near`, `usables`, `ui`, `overlays`, `widgets [depth] [root] [type]`
  (one root: a window class, `PlayerMenu:<tab class>` or the HUD; `type` keeps one script class),
  `widget`, `clickables`, `cinema`, `inv`, `buildings`, `cvars`, `mods`, `clock`, `terrain`,
  `pathfind`, `reachmap`.
  `widgets` gives `text` for TextWidgets, `enabled` for buttons and `item` for item slots,
  and the open tab of a tabbed window as its own root (`PlayerMenu:PlayerMenuCharacterTab`).
  A button's caption is a BitmapString it can't read, so check a window's result line
  instead. `near <r> [filter]` only returns units within r and is capped: a big radius in a
  run truncates (radius 600 saw 3406 units), so pass a path filter (`near 800 pets/`).
  `shop` entries carry `id`, `title`, `gold`, `available`, `icon` and `sub` (texts cut at 60).
  `press <id>` clicks a widget of the top window (real ClickDown/ClickUp), so give rows ids.
  `func <name...>` runs the top window's `OnFunc` as a key-bound action would (the loadout's
  Play is `func play`, bound to MenuAdditional). `state` carries `ngp` (`g_ngp`) too.
  `subclass <id>` (ChangeClass, e.g. priest_crusader) and `skill <id> [n]` (SkillUp; give points
  with `hwp skillpoints`) build a spec; `kill <r> <filter> [hp]` kills actors (or sets their
  health fraction); `abort [failed]` leaves a run the pause menu's way (Aborted) or the death
  screen's (Failed). `near` entries of actors carry `hp` (fraction) and `dead`.
  `kill` takes `tag:<tag>` as the filter (tag:elite, tag:boss, tag:enemy) and `me` as the third
  argument to credit the local player (kill hooks and drops run; vanilla `cht_killall` / `hwp
  killall` kill with no killer, so no drops). `combo` is Player.GiveCombo (needs a combo skill:
  `skill combo_kills 1 combo`); `state.player` has `combo` and `buffs` (name keys).
  A reply over 15,000 chars comes back as an error (a longer log line looked fatal).
- Read the game's own data:
  - `inspect player|town <dotted.path>`: the save record.
  - `sval <file>`: a datatable as parsed; `sval <file>:<entry>` only one dictionary key, or the
    array element whose `id` matches.
  - `members <Type>`: script reflection.
- Act through the game's own code path: `mission`, `build`, `equip`, `xp`, `material`,
  `upgrade`, `assign`, `charflag`, `spawn`, `save`, `pick`, `char`, `input`, `pointer`,
  `skillup`, `mastery`.
  `spawn` of a material unit gives an amount-0 pickup; `drop <type> <amount> <dx> <dy>`
  makes a real one (Material::DropMaterial).
- `areatriggers [radius]` (read-only): AreaTrigger / AllPlayersAreaTrigger scripts near the
  player (enabled, inside). Boss levels spawn the boss through one; walk into it first.
- `multi a + b + c` runs many verbs in one frame.

## Measurement-only verbs

`teleport`, `cull` and `timescale` measure engine facts (`cull` is cht_kill_all, targetable actors only;
`cull all` kills the untargetable ones too and reports `untargetable`; `cull mine` credits the local
player). A scenario that uses them is not evidence of play. `timescale` speeds up timers but not
per-frame movement. A teleport takes the pet along, so check following with a walk (`input <ms> <x> <y>`).

## Pilot intents and bots

- Intents run in-engine until done or interrupted:
  - `move`, `path_to`, `attack`, `kite`, `use`, `potion`, `wait`, `exit`.
  - `travel <place>`, through the travel graph; an edge the graph doesn't know gives `no_route`.
- Results: `done`, `failed`, `timeout`, `interrupted`, `no_route`.
- `until=` is a closed vocabulary; anything else raises ValueError:
  `hp_below:N`, `under_attack`, `target_dead`, `level_changed`, `menu_open`, `dead`.
- `reflex(potion=<hp%>, fire=<radius>)` sets standing orders the engine runs itself.
  A Python round trip is too slow to survive a swarm.
- A bot is `gamelab/bots/<name>.py` defining `run(pilot, **kwargs) -> dict`; the step's
  `kwargs` are passed in. Client API: `gamelab/pilot.py`.

## Editing files mid-run

- `write_bot_file` edits a bot, and the next `bot` step runs the new code: bots are
  reloaded from disk on every call. `same_process` asserts no restart happened in between.
- `write_mod_file` (gamelab-* mods only) edits a script, but a level load does not
  recompile it. Only `restart` does (reload-mark 20261017-144040).

## Boundary assertions

Top-level `boundaries: [{"name", "before", "after", "survives": [...], "changes": [...]}]`.
- `before` and `after` are `save_as` names, or `menu` (needs `"probe_menu": true`).
- `"p|q"` reads path p before and path q after.
- The rows are checked after the steps run and written to `boundaries.md`.
- Pair with `{"do": "restart"}` for save to load, or a `mission` step for a level load.

## Adding a verb

1. Register it:
   - A read-only verb goes in `mods/gamelab-probe/scripts/GameLab/Probe.as`. It must be
     capped and report truncation.
   - A verb that acts goes in `mods/gamelab-hands/scripts/GameLab/Hands.as`, and its doc
     comment cites the game function it mirrors.
   - Pilot verbs go in `mods/gamelab-pilot/scripts/GameLab/Pilot.as`.
2. Then run `python tools/list_verbs.py`; `--check` fails while `docs/generated/verbs.md` is stale.
