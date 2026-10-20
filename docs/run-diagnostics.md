# Recording and diagnosing a run

> **Who this is for:** anyone trying to work out why a run went wrong, after the fact.
> **Read first:** [operations.md](operations.md) — record the run first, diagnose it second.
> **You'll be able to:** record a run so it can actually be diagnosed, then analyze pipeline health, pose lag and watchdog stops.

How to capture everything needed to work out what a run did — and how to
hand that to a person or an AI agent so they can act on it.

This exists because of a debugging session on **2026-07-27** in which four
separate faults stacked on top of each other, each one hiding the next.
Every recommendation below is here because its absence cost real time or a
real collision that night. The postmortem is at the end.

---

## TL;DR

Three terminals. Start them in this order.

```bash
# --- Terminal 1: the recorder. Start FIRST, so nothing is missed. ---
source /opt/ros/jazzy/setup.bash && source ~/racerbot-ws/install/setup.bash
ros2 launch race_diagnostics record_run.py
# It prints the run directory it created, and the exact tee command to use.

# --- Terminal 2: the driving stack. Note the `| tee` (optional, see below). ---
source /opt/ros/jazzy/setup.bash && source ~/racerbot-ws/install/setup.bash
ros2 launch racerbot_launch auto_map_race_launch.py \
  2>&1 | tee ~/.ros/racerbot_runs/<the-dir-it-printed>/launch.log

# --- Terminal 3 (optional): live high-signal view of terminal 2 ---
ros2 run race_diagnostics filter_log ~/.ros/racerbot_runs/<dir>/launch.log
```

> **`auto_map_race_launch.py` already starts this for you.** It runs the probe by default (`diagnostics:=true`), so a one-command map-and-race run leaves a machine-readable record without a second terminal. The rosbag stays off there unless you pass `record_bag:=true`. Everything below still applies to any other workflow.

Afterwards:

```bash
ros2 run race_diagnostics summarize_run ~/.ros/racerbot_runs/<dir>
```

For questions `summarize_run` doesn't answer ("when did the battery sag?",
"what happened at 1:05?"), see
[Asking questions about a recording](#asking-questions-about-a-recording).

**`| tee` is no longer strictly required, but is still the simplest option.**
`summarize_run` can reconstruct an equivalent merged log on its own: ROS 2
launch already writes every node's complete stdout to a loose
`~/.ros/log/python3_<PID>_<epoch_ms>.log` file per node process, whether or
not anyone tees anything. When `launch.log` is missing, `summarize_run`
locates the per-node files that fall inside the run's own time window and
merges them back into one chronological stream automatically — see
`race_diagnostics/node_logs.py`.

This is a **different** file from ROS's own aggregated
`~/.ros/log/<run>/launch.log`, which is still close to useless and this
reconstruction does not rely on: during the 2026-07-27 session that
aggregated file held 48 lines of a run that printed several thousand.
`| tee` remains the most direct way to get one complete, already-ordered
log without depending on after-the-fact file-hunting, so keep using it
when you remember to — the fallback exists for when you didn't.

*(Housekeeping, not an action item: `~/.ros/log/` currently holds around
19,000 of these loose per-process log files on this machine, going back
months, and nothing prunes them.)*

---

## What gets captured, and why each piece earns its place

One timestamped directory per run under `~/.ros/racerbot_runs/`:

| Artifact | Produced by | Answers |
|---|---|---|
| `launch.log` | your `tee` | What every node decided, tick by tick |
| `events.jsonl` | `race_diag_node` | Machine-readable pipeline state, **pose lag**, watchdog fires |
| `probe.log` | `race_diag_node` stdout | Same, human-readable |
| `bag/` | `ros2 bag record` | Everything, replayable offline |
| `map.pgm` / `map.yaml` | `slam_toolbox` save | The map as SLAM saw it |
| `raceline_*.csv` | `auto_map_race_node` | The line that was generated and driven. `raceline_raw.csv` is the unmodified recording and is written even when the cleanup *refuses* the run, so a refusal can be plotted against the map |

### Why the probe exists at all

Each node's own log says what *it* is doing. None of them can say why the
node upstream is silent. When SLAM was dead on 2026-07-27, every
downstream node logged a perfectly reasonable "waiting…" — which reads
identically to "healthy but idle". The probe watches the whole chain at
once:

```
/scan → slam_toolbox → /map + map→base_link TF → /slam_pose
      → auto_map_race_node → /drive
```

### Why pose lag is the single most valuable number

Localization staleness is **invisible in a topic's message rate**.
`auto_map_race_node` republishes SLAM's transform at a fixed 40 Hz
regardless of its age, so a frozen transform arrives exactly as punctually
as a live one. Only the header stamp reveals it.

This is not theoretical: it is what drove the car into a wall. Pure
pursuit spent a full second steering from a position the car had already
left, while its staleness watchdog — which measured *message arrival* —
saw nothing wrong.

The same number explains the dashboard's scan-not-lining-up-with-the-map
complaint. Overlay error ≈ **speed × pose lag**. Measured that night:
0.01 s parked, 0.31 s under load, **3.38 s peak** — 3 m of error at
1 m/s.

Rules of thumb:

| Worst pose lag | Meaning |
|---|---|
| < 0.15 s | healthy |
| 0.15–0.5 s | marginal; visible dashboard misalignment |
| > 0.5 s | `pure_pursuit` will hard-stop through the stall (`pose_timeout_sec`) |

### Why a rosbag

Because "what did the car actually see at the moment it hit the wall" is
not answerable from log text. The bag makes a run replayable:

```bash
ros2 bag play ~/.ros/racerbot_runs/<dir>/bag --clock
```

`/scan` is ~90% of the size. Drop it for a 10× smaller bag if you only
need pose/TF/command timing:

```bash
ros2 launch race_diagnostics record_run.py \
  topics:="/odom /slam_pose /drive /ackermann_cmd /tf /tf_static /map /joy /parameter_events"
```

**Parameter changes are in the bag too.** `/parameter_events` is recorded by default. Every node announces each change to one of its settings on that topic, so the bag holds every change made during the run: from the [web dashboard's tuning panel](../src/web_dashboards/car/docs/web-dashboard.md#live-parameter-tuning), from Lichtblick through [foxglove_bridge](foxglove-bridge.md), or from `ros2 param set` in a terminal. Without it, a bag can show the car driving differently halfway through a run with no record of why.

To read them back:

```bash
ros2 bag play ~/.ros/racerbot_runs/<dir>/bag --clock &
ros2 topic echo /parameter_events
```

Keep `/parameter_events` in the list if you pass your own `topics:=`, as above.

---

## Reading the results

```bash
ros2 run race_diagnostics summarize_run ~/.ros/racerbot_runs/<dir>
ros2 run race_diagnostics summarize_run ~/.ros/racerbot_runs/<dir> --json   # for an agent
```

It reports, in the order that matters:

1. **How far the run got** — SLAM active → lap closed → profile generated
   → profile loaded → pure pursuit driving. The first `[ NOT ]` is where
   to look.
2. **Localization health** — worst pose lag, frozen-pose samples, TF losses.
3. **Watchdog stops by reason** — which safety net fired, how often. Every
   hard-stop state either driving node can log is named here now, not just
   the six that were originally listed — see `run_events.py`'s
   `CRITICAL_PATTERNS`.
4. **Unclassified stops** — how many `STOP [...]` lines matched no known
   watchdog state. 0 is the expected value; a nonzero count means
   `CRITICAL_PATTERNS` has drifted out of sync with what the driving nodes
   actually log (exactly what happened to the lap-progress regex below,
   before 2026-08-25) and is itself a finding worth fixing. (This
   deliberately excludes `auto_map_race_node`'s own routine bookkeeping
   stops — `loading_profile`, `transition_hold`, and the rest of
   `supervisor_stop` — which fire on every ordinary run and would
   otherwise make this count permanently, uninformatively nonzero.)
5. **Which lap-closure gate is holding a lap open** — see below.
6. **Errors and node deaths**, de-duplicated.
7. **Missing artifacts** — itself a finding. No `map.pgm` means the
   occupancy save failed, which happened when slam_toolbox's executor was
   too busy to serve its own map subscription. `launch.log` itself is no
   longer fatal if missing — see the `| tee` note above.

Escape/recovery maneuvers (`emergency_escape`, and — once landed —
`ttc_escape`/`body_contact_escape`/`off_racing_line_recovery`) get their
own `escape_maneuver` count too: these publish a nonzero crawl speed and
log with the `DRIVE` prefix rather than `STOP`, so before 2026-08-25 they
were invisible to this whole classification scheme, not merely
miscategorized.

### The lap-closure gates

The supervisor declares a lap only when *all* of these pass at once, and
the log line reports every one as `value/limit`:

| Gate | Config key | Failure looks like |
|---|---|---|
| departed the start | `departure_distance` | never leaves the start area |
| distance travelled | `minimum_lap_distance` | loop shorter than the minimum can never close |
| turning done | `minimum_lap_turn_deg` | repeated reactive stops keep resetting progress before a full 300° accumulates — the actual blocker on every run in the 2026-08-25 session, and silently unreported by `summarize_run` before that day's regex fix |
| elapsed time | `minimum_lap_duration_sec` | rarely the blocker |
| back near the start | `closure_distance` | passes the start but too wide |
| heading matches start | `closure_heading_deg` | comes back the "wrong way round" |

`summarize_run` names the single blocking gate. On 2026-07-27 the car
drove **114 m without closing a lap** because heading error was 30.2°
against a 30.0° limit while every other gate had passed long before —
invisible unless you read that one field.

---

## Asking questions about a recording

`summarize_run` answers a fixed list of questions. For anything else, such as
"when did the battery sag?" or "what was the car doing at 1:05?", there are
four small commands that read the run's rosbag (the recording of every
topic, see [glossary](glossary.md#rosbag--bag)) and print **a short answer, never the
data itself**.

**Highlights**

- **The answer stays small however big the recording is.** An hour of
  driving is about 140,000 [LiDAR](glossary.md#lidar) scans (sweeps of the
  laser rangefinder). `bag_find` turns that into a handful of lines saying
  when something happened.
- **Built for AI agents as much as people.** Claude Code can run these and
  read their output without ever loading the recording into its context,
  so a long run doesn't overflow it. Most commands have `--json`.
- **Noise-aware.** `--min-duration` drops single-sample glitches, and
  `min()`/`max()`/`mean()` skip the NaN and inf readings a LiDAR reports
  for missing beams.
- **Needs no sourced ROS.** Copy a run folder to a laptop and run them
  there. Message types are decoded from definitions stored inside the
  recording, so `vesc_msgs` decodes even where it was never built.
- **Read-only, not a ROS node.** It opens files and nothing else, so it
  cannot affect the car.
- **Limits:** it reads MCAP recordings only (the Jazzy default, which
  `record_run.py` produces). It does not join two topics in one question:
  find the moment on one topic, then look at everything around it with
  `bag_window`.

### One-time setup

The commands need two Python libraries that are not part of ROS. Install
them once per machine, then rebuild so the four commands exist.

**Terminal: any, from `~/racerbot-ws`:**

```bash
pip install --user --break-system-packages mcap==1.6.0 mcap-ros2-support==0.6.0
colcon build --symlink-install --packages-select race_diagnostics
source install/setup.bash
```

`--break-system-packages` is how Ubuntu 24.04 lets pip install anything
outside a virtual environment. With `--user` it only writes under
`~/.local`, never into the system's own files.

**Working when:** `ros2 run race_diagnostics bag_stats --help` prints a usage
message.

**If it doesn't:** "No executable found" means the rebuild or the
`source install/setup.bash` step was skipped. If it says "reading
recordings needs the mcap libraries", the pip install went to a different
Python.

### The four commands

Every command takes the run directory first. It also accepts the run's
`bag/` directory, or a single `.mcap` file. Times are seconds from the start of the recording
(`65`) or minutes:seconds (`1:05`), on the command line and in the output.

**Terminal: any, after `source install/setup.bash`.** None of these need
the car or the driver stack running.

```bash
RUN=~/.ros/racerbot_runs/20261019-140211        # your run directory

# 1. What is in it? Each topic's rate, its gaps, and how old its data was.
ros2 run race_diagnostics bag_stats $RUN

# 2. When did something happen? Prints one line per episode.
ros2 run race_diagnostics bag_find $RUN /scan "min(ranges) < 0.4" --min-duration 0.05
ros2 run race_diagnostics bag_find $RUN /joy "buttons[4] == 0"          # LB released

# 3. What was going on around then? Every topic, long arrays summarised.
ros2 run race_diagnostics bag_window $RUN --at 1:05 --span 2

# 4. One value over time, as CSV, bucketed to 5 rows a second.
ros2 run race_diagnostics bag_extract $RUN /odom twist.twist.linear.x --hz 5
```

**Working when:** `bag_stats` starts with a `Worth a look:` list. That list
names every topic gap and every topic whose data arrived more than 0.15 s
old (the "marginal" line in the pose-lag table above). If nothing is
wrong, it says so.

**If it doesn't:** every error is one line starting with `error:` that says
what to do. A run recorded with `record_bag:=false` has no `bag/` at all,
and the error says no recording was found.

**Battery and motor questions need `/sensors/core` in the recording, and
`record_run.py` does not record it by default.** Add it when you start the
recorder if you will want it.

**Terminal 1, the recorder, in place of the plain `record_run.py` command in
the TL;DR:**

```bash
ros2 launch race_diagnostics record_run.py \
  topics:="/scan /odom /slam_pose /drive /ackermann_cmd /teleop /tf /tf_static /map /joy /auto_map/drive /auto_race/drive /parameter_events /sensors/core"
```

**Working when:** it prints the run directory, exactly as the plain
command does.

**Terminal: any, after the run.** Battery questions then work:

```bash
ros2 run race_diagnostics bag_find $RUN /sensors/core "state.voltage_input < 10.5" --min-duration 0.1
```

**Working when:** it lists the episodes, or prints `Never true.` If it
says `not in this recording: /sensors/core`, the run was recorded without
that topic and the answer cannot be recovered.

### Writing a question

A condition or value is a small expression over one message's fields. The
field names are the ones in the message definition, which `bag_window`
shows you:

| You want | Write |
|---|---|
| a field | `state.voltage_input`, `twist.twist.linear.x` |
| one element of a list | `buttons[4]` (LB on the F710), `axes[-1]` |
| the closest LiDAR return | `min(ranges)` (NaN and inf beams ignored) |
| how many beams were missing | `nonfinite(ranges)` |
| a combination | `drive.speed > 1 and min(ranges) < 1.0` |

Allowed: `+ - * /`, `< <= > >= == !=`, `and or not`, and the functions
`min max mean abs len nonfinite`. Anything else is refused before it runs.
That matters because these commands are meant to be run by AI agents, and
an expression must not be able to run code.

### Noise: why a question can report events that didn't happen

Real sensors produce single-sample glitches, like one voltage reading that
dips for 20 ms or one LiDAR beam that bounces off dust. A plain threshold
reports every one of them as an event. Two options fix that:

- `--min-duration 0.1` ignores anything that lasted less than 0.1 s.
- `--merge-gap 0.2` joins episodes less than 0.2 s apart, for a signal
  hovering right at its threshold.

`bag_extract` has the same problem in reverse. Its default `--agg mean`
averages a short spike away. Use `--agg min` or `--agg max` when spikes are
what you are looking for.

<details>
<summary>How it works, and how it's tested (safe to skip)</summary>

- `bag_io.py` opens the recording with the pure-Python `mcap` library, merges
  split files (`bag_0.mcap`, `bag_1.mcap`, …) by arrival time, and turns a
  damaged or half-written file into a clear error.
- `bag_query.py` does the arithmetic: timing statistics, episodes,
  bucketing, and summarising long arrays. It has no ROS and no `mcap` in it.
- `field_expr.py` is the expression language. It parses with Python's `ast`
  and walks a whitelist; it never calls `eval()`.
- `bag_tools.py` is the command line.
- **Lag** is arrival time minus the message's own header stamp. `bag_stats`
  reads the stamp straight from the first 12 bytes of each message rather
  than decoding it, so a big message costs no more than a small one.

There is no real recording in the repo, so the tests generate one.
`test/fake_recording.py` writes a 60 s, two-file recording of the car
circling. It adds bounded timing jitter, sensor noise, NaN/inf beams and
one-sample glitches.

It also contains five known events: an `/odom` dropout, a
battery dip, a near-wall moment, a lag spike and an LB release. The tests
check each command finds exactly those, with tolerances derived from the
jitter bounds.

**Terminal: any, from `~/racerbot-ws`,** to try the commands on it yourself:

```bash
python3 src/race_diagnostics/test/fake_recording.py /tmp/fake_run
ros2 run race_diagnostics bag_stats /tmp/fake_run
```

**Working when:** `Worth a look:` names an `/odom` gap near 12 s and stale
`/odom` data near 40 s, the two problems the generator planted there.

</details>

---

## Safety notes for anyone (or anything) changing this code

Read [architecture.md](architecture.md) and
[writing-your-own-node.md](writing-your-own-node.md) first. The
non-negotiables:

- **Every node that can move the car requires the LB deadman held.** Never
  set `enable_deadman: false` — that is a policy change, not a tuning knob.
- **`race_diagnostics` only subscribes.** It publishes nothing and is
  therefore not driving code. Keep it that way; if it ever needs to
  publish, it becomes driving code and inherits the whole safety policy.
- **Test order for driving changes, never skipped:** static topic check →
  wheels off the ground → floor, low speed, open space.
- Integration tests construct real nodes with the deadman disabled. They
  remap `drive_topic` to `/test_only/drive` for that reason. **Never
  remove that remap** — without it, `pytest` sends live commands to the
  VESC if the driver stack happens to be up.

---

## Prompt structure for an AI agent

For a fresh Claude Code session in this workspace. Fill the brackets. The
ordering is deliberate: constraints before task, evidence before
hypothesis, and an explicit statement of what is *not* yet known.

```markdown
## Context
ROS2 Jazzy F1TENTH car (Jetson Orin Nano, 8GB). This is a PHYSICAL robot
that can hurt itself or people. Read CLAUDE.md and docs/architecture.md
before proposing any change to code that publishes to /drive.

## What I ran
[e.g. ros2 launch racerbot_launch auto_map_race_launch.py, 2 mapping laps
then automatic handover to pure pursuit]

## What I expected
[e.g. car maps 2 laps, generates a raceline, then races it faster than the
1.0 m/s mapping cap]

## What actually happened
[e.g. handover completed, car accelerated, then hit a wall on the left]

## Recorded evidence
Run directory: ~/.ros/racerbot_runs/<dir>
- launch.log       full terminal output of every node
- events.jsonl     probe stream: pipeline state + pose lag
- bag/             replayable with `ros2 bag play <dir>/bag --clock`.
                   Do not read it directly: query it with bag_stats,
                   bag_find, bag_window and bag_extract
                   (docs/run-diagnostics.md#asking-questions-about-a-recording)
- summarize_run output pasted below:

<paste `ros2 run race_diagnostics summarize_run <dir>` here>

## Your task
1. Read the artifacts above BEFORE forming a hypothesis. Quote the
   specific log lines or events.jsonl records that support your
   conclusion — do not infer from code alone.
2. Distinguish clearly between what the evidence PROVES and what it merely
   suggests. Say which is which.
3. Identify root cause. If several faults stacked, order them by which one
   masked the others.
4. Propose fixes. For each: what breaks if it's wrong, and how it would be
   verified.
5. Do NOT change safety watchdog behaviour, the deadman gate, or speed
   limits without flagging it explicitly and waiting for my confirmation.
6. Add a regression test for every behavioural fix. Tests that need no
   rclpy go in the pure-logic modules (racing_math.py, run_events.py,
   protocol.py); node tests must remap drive_topic to /test_only/drive.
7. Run the full suite and report the real result:
   `python3 -m pytest src/<pkg>/test/ -q`

## Constraints
- --symlink-install: edits to .py/launch/config take effect on next launch
  with no rebuild. Rebuild only after touching package.xml/setup.py/C++.
- Full rebuild on this Jetson needs --parallel-workers 1 (8GB RAM).
- Do not commit unless I ask.
```

### What makes this work

- **Evidence before hypothesis.** Asking for quoted log lines is what
  separates "the pose was frozen — here are two identical poses 1.0 s
  apart while odometry read 1.25 m/s" from a plausible-sounding guess.
- **Proved vs. suggested.** On 2026-07-27 the pose freeze was *proved* by
  the logs; the blocking map-save being its *cause* was only inferred. Both
  were worth acting on, but conflating them would have been wrong.
- **Ordering stacked faults.** Four faults were present at once. Reporting
  them flat would have been useless — what mattered was that the SLAM
  lifecycle bug made the other three unreachable.
- **Explicit safety veto.** An agent asked to "fix the car hitting things"
  will otherwise cheerfully relax a threshold that exists for a reason.

### Also worth telling the agent

- Which fix attempts already failed, and why. Nothing wastes an agent's
  time faster than re-deriving a dead end.
- Whether the car is physically undamaged. A bent steering linkage
  presents exactly like a control bug and no log will ever show it.
- That a monitor's *silence* is ambiguous: it can mean healthy, or that
  the monitor's filter never matched. Ask it to confirm the pipeline is
  alive rather than infer it from an absence of complaints.

---

## Postmortem: 2026-07-27

Four faults, each hiding the next. In the order they had to be peeled:

**1. `slam_toolbox` never started.** As of 2.x it is a lifecycle node that
does not configure itself; `slam_launch.py` started it as a plain `Node`,
so it sat in `unconfigured` forever — no `/map`, no `map` frame, no
`/slam_toolbox/save_map`. The tell was a *missing* log line: the
constructor's "Node using stack size" appeared, `on_configure`'s "Using
solver plugin" never did. Everything downstream waited forever and
reported it as normal idling.

**2. `AttributeError` at the handover.** `AsyncParameterClient` exposes
`services_are_ready()`, not `service_is_ready()`. The call sat in the code
path that only runs after the final mapping lap closes — unreachable while
fault 1 kept any lap from ever closing. It killed the supervisor at the
exact moment mapping succeeded.

**3. The collision.** Three things at once: the map/pose-graph save
blocked slam_toolbox's executor and froze the pose; pure pursuit's
staleness watchdog measured message *arrival*, so a faithfully
republished stale transform looked perfectly fresh; and its safety net was
a 60° forward-cone minimum, structurally blind to the wall the car was
already touching *beside* it. It logged `LIDAR clear` while in contact.

**4. A fix that made things worse.** The footprint check added for fault 3
was applied across the Hokuyo's full 270° sweep. The rearmost beams see
the car's own chassis, which is inside the footprint by construction, so
clearance read a permanent −0.110 m and the car could not move at all.
Negative clearance is physically impossible for a real obstacle — that is
what gave it away. `gap_follow` had always windowed to 180° before the
same computation; the maths was copied, the windowing was not.

### What the tooling in this document would have changed

- Faults 1 and 4 were both diagnosed from a **number that could not be
  real** (a missing log line; a negative distance). The probe surfaces
  both classes directly.
- Fault 3 needed pose lag, which nothing was measuring at the time. It had
  to be reconstructed by hand from two log lines that happened to be one
  second apart.
- No rosbag existed, so "what did the LiDAR see at the moment of impact"
  was permanently unanswerable.
- The 114 m of laps that never closed was one unread field in a line that
  scrolled past once a second.
