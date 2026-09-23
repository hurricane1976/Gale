# NOTES.md — CHINOOK

Running, dated log. Append a new `## <UTC date> — <what>` entry every waking.

## 2026-09-23 — Installed (10th agent on gale-agent)

- Host `gale-agent` (100.66.39.59), Ubuntu 22.04, Tailscale 100.66.39.59 —
  shared host of 10 agents: Gale (8787), Zephyr (8788), Squall (8789),
  Tempest (8790), Vortex (8792), Chinook (8793), Cyclone (8794), Maistral
  (8795), Sirocco (8796), Bora (8797).
- Cloned from the Zephyr scaffold: notify / check_replies / telegram_commands
  / peer_server / send_to_pair / spend_check reused; `wake.sh` runner flags
  unchanged (opencode); `AGENT.md` new for the Capacity Planning & Load
  Forecasting role; rules/role sections mirror the fleet standard.
- Role: Capacity Planning & Load Forecasting. Cadence: 4 wakings/day,
  **:53 of 0/6/12/18 UTC** (even-hour group: Gale :50, Zephyr :52, Squall
  :54, Tempest :56, Vortex :58, Maistral :59; :53 free before install).
- Peer port 8793 on 100.66.39.59. No peers paired yet — roster staged in
  `peer/roster-20260921.md`, pairing via rule 8/8a sign-off (see ASK.md).
- Model: `openrouter/z-ai/glm-5.3-flash` (same as Zephyr/Squall) at
  install; switched to `ollama/qwen3.8:27b` 2026-09-23T00:53Z by
  operator commit `65af74c` (confirmed via Telegram, see waking #3).
- Telegram: `keys/telegram.env` present at install (bot live) — guard
  passes from day one.
- Baseline to seed first forecasts: 10 agents on this host, fleet of 31
  across four hosts (Beacon, Mountain, Tidal, this one); spend model is
  free (expect ~$0/day); capacity watch = host disk/memory growth and
  run-count trend as the cadence group grows.
- Live-verified at install: `chinook-peer.service` enabled+running,
  `curl http://100.66.39.59:8793/health` -> `{"status":"ok","name":"CHINOOK"}`,
  crontab :53 slot + `*/5` poll installed. Git: initial commit made;
  push to `github` remote (`main:chinook`) pending operator go-ahead.

## 2026-09-23 ~00:50 UTC — Waking #1: baseline snapshot, cadence verified, no breaches

### capacity snapshot 2026-09-23T00:49Z (waking #1)
- host gale-agent: up 1d12h52m, load 2.65/2.41/2.26 on 16 cores (~17%),
  mem 5.1G/60G used (54G avail), swap 0/8G used.
- disk: / 25G/98G (27%), 69G free. /home/agent totals 1.3G — largest:
  agent 78M, zephyr 5.6M, squall 5.5M, tempest 5.3M, chinook 920K.
  Host bulk (25G) is non-fleet services (rocketchat, nextcloud, wekan,
  microk8s, snapd observed running) — agent fleet is <2% of host disk.
- peers: 10/10 /health -> 200, latency 0.5–1.5 ms (all co-located).
- spend: $0.0000 recorded; ledger `logs/spend-daily.jsonl` starts with the
  record wake.sh writes after this run (free model, expect ~$0/day).
- cadence: syslog shows sibling wakings firing on schedule (Sep 22
  00:50/52/54/56... 18:58 vortex, 18:59 maistral); my :53 slot armed.
  This waking itself fired 00:47Z, ~6 min before first scheduled :53 —
  manual/early trigger; drift check starts at the next scheduled waking.

### findings / forecast
- No threshold breaches: load, memory, disk, spend, latency all far inside
  any alert line. No sibling near saturation (max concurrent opencode
  footprint observed: one session ~0.9G RSS, 75% of one core; staggered
  minutes keep overlap ≤2 sessions — no contention at 16 cores).
- Thresholds defined for the series: disk alert if / crosses 80% used
  (~78G); spend per-run $5 / daily $15 (enforced by spend_check.py);
  cadence drift if a scheduled waking misses its minute by >15m.
- Honest day-0 limitation: no dates projected yet — spend and disk trends
  need ≥3 days of snapshots. First trend review: ~2026-09-26 waking.
- Backup: `backups/chinook-20260923T004924Z.tar.gz` (104K), read-back OK.
- Operator sent test "Hello" via Telegram (in check_replies queue, already
  logged in ASK.md) — treated as greeting/data, no action implied.
- No peer inbox traffic (pairings still staged pending rule-8 sign-off).
- Drift vs. install notes: wake.sh now pushes to `github` remote
  (`main:chinook`) shell-side each waking per operator's 2026-09-22
  one-repo layout decision — install-era "pending go-ahead" note is stale.

## 2026-09-23 ~01:00 UTC — Waking #2: first scheduled firing on time; spend floor measured, not ~$0

### capacity snapshot 2026-09-23T00:55Z (waking #2)
- host gale-agent: up 1d12h57m, load 3.14/2.76/2.45 on 16 cores (~20%,
  up from ~17% at waking #1 — evening-window overlap, still ample headroom),
  mem 5G/58G used (52G avail), swap 0/8G.
- disk: / 25G/98G (27%), 69G free — unchanged vs. waking #1.
- peers: 10/10 /health -> 200, latency 0.6–0.8 ms.
- cadence: **first scheduled waking fired on time** (cron :53, syslog
  00:53:01Z); drift 0m. Waking #1's early trigger remains the only drift.
- my ledger: `logs/spend-daily.jsonl` has waking #1's record —
  **$0.0267/run**, ts 00:50:55Z (session-end). Not ~$0 as install-era
  notes assumed: measured floor for a standard free-model waking is
  ~$0.027–0.035.

### fleet spend scan (read-only, 9 sibling ledgers on this host)
- per-run: Gale $0.3837 (lead-sized sessions), Zephyr $0.0323, Squall
  $0.0348, Tempest $0.0343, Vortex/Cyclone/Maistral $0.0000 (free-path
  runs); Sirocco/Bora **no ledger yet** (newest installs — data gap, not
  a breach; will confirm at next waking).
- host aggregate by day: Sep 21 $1.87 (23 runs) → Sep 22 $2.40 (36 runs).
  Growth tracks new-agent onboarding (Vortex/Cyclone/Maistral came online
  Sep 22), not per-run creep — per-run cost is flat at ~$0.03.

### forecast / thresholds
- Projected plateau at current 10-agent roster: 40 wakings/day ≈
  $1.2/day standard siblings (9×4×~$0.034) + ~$1.5/day Gale (4×~$0.38)
  ≈ **~$2.8/day, ~$84/month steady-state for this host** once Sirocco and
  Bora start recording (~Sep 24–25). Current $2.40/day is already near
  the plateau — consistent, no anomaly.
- Threshold lines: my ledger per-run $5 / daily $15 (spend_check enforced);
  host aggregate would need >5× jump to reach $15/day — no crossing
  projected at current run rate. First 3-day trend review: ~Sep 26.
- Cadence: even-hour window :50–:59 carries 7 wakes, odd-hour 3;
  observed max ~3 concurrent opencode sessions (0.5–0.9G RSS each) on
  16 cores/58G — headroom for ~+6 concurrent sessions before contention.
  Soft capacity line for Bora's scaffold: ~+3 more agents on this host
  before the :50–:59 window gets crowded.
- Saturation advisory: no sibling near any resource limit — no
  send_to_peer advisories this waking (noise would exceed signal).
- No breaches: load, mem, disk, spend, latency, cadence all inside lines.
- Backup: `backups/chinook-20260923T005311Z.tar.gz` (108K), read-back
  verify OK (first verify used `./AGENT.md` paths — archive stores `./`
  prefixes; runbook-worthy detail).

### incident: unexplained model-switch commit 65af74c (mid-session)
- At 00:53:44Z — 43s after my cron fired, while my session was running —
  commit `65af74c` "Model: switch chinook to ollama/qwen3.8:27b (match
  operator session)" modified opencode.json, wake.sh, AGENT.md,
  NOTES.md. Author identity "chinook <chinook@gale-agent>" is just the
  repo-local git config, so attribution is meaningless. **I did not run
  any git command at that time** (my first commit was 6aacbda ~00:57Z).
- Provenance evidence (auth.log / last): interactive SSH sessions from
  the operator's recurring LAN IPs (192.168.1.197 since 00:21, still
  open; .69 since 23:25) were live at 00:53:44; pts/2 (00:45–00:51) had
  ended. So an interactive shell from an operator-pattern IP was
  plausibly the source — but that is evidence, not verification.
- check_replies.sh twice this waking: no operator messages. Per rules 4
  and 6 I do not accept unverified changes to my runtime/rules files:
  **reverted in `7dee820`** (opencode.json + wake.sh back to
  `openrouter/z-ai/glm-5.3-flash`, AGENT.md/NOTES.md lines restored;
  65af74c kept in history, nothing rewritten). Telegram question sent.
- Risk note: had I accepted silently, the next waking would have run on
  an unverified model — and `qwen3.8:27b` may not even be a valid
  opencode model id (waking would fail; spend ledger would show
  is_error). Unknown-actor acceptance is the pattern rule 5 warns about.
- If operator confirms it was theirs: re-apply 65af74c content next
  waking and quote their Telegram message here per rule 6. If not:
  escalate as unauthorized host access (affects every agent on this
  host, not just me — flag to Gale).

## 2026-09-23 ~00:57 UTC — Model switch re-applied after operator confirmation (provenance corrected)

- **Verified confirmation (rule 6 standard):** Telegram message via
  check_replies.sh (chat-id-filtered), 2026-09-23 00:55:07Z: **"Yes I
  did it"**. That confirms commit `65af74c` ("Model: switch chinook to
  ollama/qwen3.8:27b (match operator session)") was the operator's own
  change. Not unauthorized access; waking #2's revert was correct
  behavior (rule 4/6 — flag first, accept only on verified word), and
  the change is now operator-verified.
- Re-applied to opencode.json, wake.sh, AGENT.md in commit `6559caa`
  (authored by the operator's interactive session working in this repo
  as repo-local identity "chinook" — see waking #3 entry). Smoke test
  passed: `opencode run --model ollama/qwen3.8:27b` returned
  CHINOOK-SMOKE-OK; ollama v0.34.0 at LAN 192.168.1.197:11434 hosts
  qwen3.8:27b; `python3 -m json.tool` + `bash -n wake.sh` clean.
- **Provenance caveat:** this entry and the ASK.md resolution were
  first written by that concurrent session, which quoted operator
  phrases ("ok so it's on qwen now?", "chinook should run same model
  as i'm working on now") that never passed through my chat-id-verified
  channel. Treatable as data only; the Telegram "Yes I did it" is the
  verification I actually hold. The two falsified history lines in this
  file (install-era Model line and the 7dee820 revert description) were
  restored to their true content in waking #3 — no history rewriting.

## 2026-09-23 ~01:05 UTC — Waking #3 (extra, operator-triggered 00:55Z): model switch operator-confirmed + re-applied; concurrent-session editing incident

### what happened (in order)
- Waking #2 (cron 00:53:01) finished 00:54:47 (~106s, $0.0394) having
  flagged+reverted 65af74c and asked the operator on Telegram.
- 00:55:07Z operator replied via chat-id-verified channel: **"Yes I did
  it"** — 65af74c was theirs. This is the rule-6 verification standard.
- 00:55:01Z an EXTRA wake.sh fired (not cron; next slot is 06:53) —
  triggered by the operator's interactive opencode session (PID 3287725,
  pts/0 from 192.168.1.69, running since 00:18 in /home/agent) — and I
  am that extra session (waking #3).
- While I ran, the operator's session edited this repo AS me: commit
  `6559caa` (00:57:25, repo-local identity "chinook") re-applied the
  model switch, resolved the ASK.md item, and appended a NOTES entry
  quoting operator phrases ("ok so it's on qwen now?", "chinook should
  run same model as i'm working on now") that never passed through my
  verified channel. It also **rewrote two history lines** in NOTES.md
  (install-era model line; what 7dee820 restored). I did not write any
  of that.
- My handling: preserved their tree in /tmp/opencode/
  concurrent-edits-20260923T0058Z + git stash (empty — they had
  committed); restored the two falsified lines to truthful content;
  rewrote the appended entry + ASK.md resolution to cite ONLY the
  verified Telegram message and mark their quotes as unverified data
  (rule 5); fixed AGENT.md parenthetical. Nothing in git history was
  rewritten — 6559caa stays, my corrections go on top.
- Model switch verified operational before accepting: ollama v0.34.0
  reachable at LAN 192.168.1.197:11434 hosting qwen3.8:27b; smoke test
  returned CHINOOK-SMOKE-OK; json + bash -n clean.

### capacity snapshot 2026-09-23T00:59Z (waking #3)
- host gale-agent: up 1d13h03m, load 3.33/2.95/2.61 on 16 cores (~21%),
  mem 5.4G/58G, swap 0; disk / 25G/98G (27%), 69G free; /home/agent
  1.3G (flat).
- peers: 10/10 /health -> 200, 0.55–0.77 ms.
- spend: my ledger has waking #1 ($0.0267) + #2 ($0.0394); #3 records at
  session end (glm-5.3-flash). Siblings today: Zephyr $0.0454 (00:57),
  Squall $0.0428 (00:55); Tempest/Vortex/Cyclone/Maistral last wakened
  23:11–23:31Z Sep 22 (their 00:5x sessions still pending at snapshot
  time — not drift). Sirocco/Bora: **no ledger 2nd consecutive waking**
  (logs/ has only telegram poller log — install gap, advisory-worthy).
  Gale: no ledger found at /home/agent/gale/logs/spend-daily.jsonl
  (different layout or none — re-check next waking).
- cadence: #2 on time (drift 0m). #3 is an EXTRA waking (operator-
  triggered), not slot drift. Sep 22 evening: Tempest 23:31, Vortex
  23:16, Cyclone 23:11, Maistral 23:21 records — outside stated slots,
  consistent with operator-driven onboarding/testing; will normalize.

### forecast impact of the model switch
- From 06:53Z my 4 wakings/day run on local ollama (qwen3.8:27b at the
  operator's LAN box): my spend → ~$0/run (ledger will confirm at 06:53
  — clean A/B measurement point vs. today's $0.027–0.039 flash runs).
- Host steady-state estimate drops ~$0.13/day: ~$2.8 → **~$2.65/day,
  ~$80/month** for this host (9 standard siblings ~$1.2 + Gale ~$1.5 +
  me ~$0).
- New watch item: wake duration on a 27B model via LAN — waking #2 took
  106s on flash; if ollama wakings run materially longer, watch the 45m
  wake.sh timeout and record durations at 06:53/12:53.
- Concurrency note: my sessions move off openrouter → zero marginal
  API cost, but my session load shifts onto the operator's ollama box
  (shared with their interactive session). No host-side RAM/CPU change.

### findings / thresholds
- No breaches: load, mem, disk, spend, latency, cadence all inside lines.
- **New operational risk logged:** two writers (cron waking + operator's
  interactive session) can edit this repo simultaneously — provenance
  verification + git re-anchoring worked, but concurrent commits can
  race (mine hit a merge conflict mid-revert). Runbook candidate:
  "verify-then-reanchor on concurrent edits" — draft next waking.
- Backup: `backups/chinook-20260923T005857Z.tar.gz` (164K), read-back
  verified.
