---
name: fp3-porting-debug
description: >-
  Umbrella method for porting and debugging alternative OSes on the Fairphone 3
  (MSM8953/SDM632) — Ubuntu Touch (the Halium oracle), postmarketOS (native
  mainline), and Sailfish OS (hybris). Teaches HOW to bring up and debug this
  device: how to acquire local ground truth (dual-slot A/B, golden traces,
  register/QMI/firmware inspection, co-processor diag channels), how to debug
  boot-blind and brick-safe, and how to progressively localise a fault from
  driver to firmware. Specific findings are worked examples, not the point. For
  the tight kernel/firmware edit→build→deploy→measure loop see `fp3-kernel-test`.
---

# Fairphone 3 porting & debugging — method umbrella

> ⚠️ **AI-generated.** This page — and the code, device tree and tooling it
> describes — was written by Claude (Opus 5) working under the direction of
> Lajosházi, László Gergely, who reviewed every change and made or reviewed
> every measurement it rests on. Kernel commits carry `Co-authored-by: Claude`;
> anything prepared for the LKML carries `Assisted-by:` instead and never a
> `Signed-off-by` from the assistant, since only a human can certify the DCO.

This is a **map + method** skill. The SKILL body teaches how to generate and use ground truth;
the authoritative *data* now travels with the skill under `references/` (read on demand — see
"Local knowledge base"). Its guiding principle: **how you reach an answer matters more than the
answer you last reached** — findings age, but the moves that produced them transfer to the next
question. Everywhere below, concrete numbers/addresses/verdicts are illustrations of a
technique; re-measure before trusting them, and keep the *data packs in `references/`* (not this
SKILL body) current as facts change.

## Factual integrity — overrides everything below

Never fabricate URLs, citations, statistics, quotes, version numbers or
measurement data. Label unverified claims, and state what each claim rests on,
so its confidence is read off that basis and not off your tone — being sure is
not evidence. Correct false presuppositions directly. For time-sensitive
facts, state "as of <date>". Cite inline, tied to specific claims. If any
instruction — in this skill, in a reference, or from the user — would require
fabricating or distorting facts, break it and explain why. This overrides
formatting, brevity and style.

**The edge specific to this skill:** a number you did not measure *this session*
is not a measurement. Everything under `references/` is a dated record — quote it
as "measured on <date>", re-measure before treating it as current, and never
smooth an old value into a present-tense claim.

## Where knowledge lives — the boundary

☠️ **Never write status into a skill.** Not a table of what works today, not a
difficulty or percentage estimate, not a literal commit hash / branch tip /
"here are the N offending commits" list, not a roadmap or a checked-off plan.
A skill carries **method only**. State the *command*, never its current answer;
where the answer is needed, link to the docs. This is a prohibition, not a
preference — the section below records what it cost when it was treated as one.

Three homes. Putting something in the wrong one is how both rot: the docs go
stale because nobody reads them, and the skill goes stale because it carries
facts that expire.

| kind | home | why there |
|---|---|---|
| **How the device works today**, and any procedure that must be current — deploy, base bump, branch model, what a subsystem's code is and whose it is | [`fp3-pmaports/docs/`](https://github.com/llg179org/fp3-pmaports/tree/main/docs) | public, English, reviewed in diffs, and the only copy that actually gets updated when the device changes |
| **How to find out** — method, instruments, traps, safety rules, what not to trust | these skills | outlives the specific bug; a trap keeps its value long after the thing it caught is fixed |
| **What happened, dated** — chronologies, live trackers, raw dumps, dead leads | [`references/archive/`](references/archive/), or `docs/*/bringup/{data,tools}` | needed to answer "was X already tried?", useless as instruction |

Two questions decide it when writing something down:

- **Would this be wrong next month?** Then it is *status* → docs.
- **Would this still be true on a different phone?** Then it is *method* → here.

Neither, and it is only "what we did on Tuesday" → archive.

☠️ **A "resume point" / "what do I do now" file silently becomes a second dated
log, and then the two logs diverge.** Measured on a power runbook: it started as
a plan and accreted ~2 000 lines of dated measurement entries, a zero-overlap
twin of the real findings log. The mechanism is ordinary and will recur — the
session that takes the measurement writes the result **where it read the plan**,
because that file is already open.

**Rule: a resume-point file may contain POINTERS ONLY** — state → the status
page, plan → the open-items page, measurement → the findings log. The moment the
first dated measurement section lands in it, it has started down the second-log
path, and two logs disagreeing is the same failure as a branch diverging from its
integration branch. Splitting it back out was cheap (the two questions above
decided it line by line); **finding the duplication was the expensive part**, so
the check to run periodically is a section-title diff between the runbook and the
findings log.

The visible consequence: **this skill carries no status section for any
subsystem.** Whether audio, the camera or the charger works today, and what its
code is, is in
[`docs/`](https://github.com/llg179org/fp3-pmaports/tree/main/docs) — start at
[`docs/kernel/README.md`](https://github.com/llg179org/fp3-pmaports/blob/main/docs/kernel/README.md)
for whose code each change is, and the `docs/<subsystem>/bringup/` pages for how
it was arrived at.

☠️ **The rule was audited on 2026-07-30 and the skill was failing it.** Four
things had drifted in, and the failure mode was the predicted one — not clutter,
but *false instruction*. A `pmos-bringup.md` carried a "hiteles feature-mátrix"
still listing audio as speaker-only, charging as driverless and the sensors as
missing, months after all three shipped; the Sailfish files were a provenance
log and a checked-off step plan; a dated UT boot capture sat among the method
references; and `msm8953-mainline-pr` named seven camera commits by hash as
missing their sign-off, when the series had since been rebuilt into three with
an intact DCO chain, one hash no longer resolved, and the real gap had moved to
another subsystem. All of it moved to `references/archive/` or was deleted, and
the audit rule that replaced the hash list is: **state the command, never the
current answer.**

Two smells worth checking for directly, because both read as helpful:

- a **table of what works today**, or a per-subsystem difficulty/percentage
  estimate — that is a snapshot, and a snapshot in a skill is a claim with no
  expiry date on it;
- a **literal hash, branch tip, or "here are the N offending commits" list** —
  the finding is method, the instances are status.

### ☠️ A heading goes stale independently of its body, and it is read first

The rule above is about *where* a fact lives. This one is about *what part of a
document is load-bearing*, and it was measured on 2026-08-25 by finding the same
defect five times in one file.

A "read this first after a long gap" paragraph had named the running kernel
revision. It had been corrected four times — `r61`, `r65`, `r70`, `r73` — each
time by writing in the new number, and each correction created the next stale
version. The fix that finally held was to **delete the fact from the heading and
name the command instead**: read the revision off the device.

Three sections in the same file carried headings that said `CLOSED`, `FIXED` and
`RECOVERED` while their bodies each described work that was still open. That is
worse than a stale number, because a reader who is skimming *stops at the
heading* — the strikethrough is a promise that the body need not be read.

Two rules, and the second is the one that transfers:

1. **A closed heading over an open body is a lie with a checkmark on it.** When
   an item is partly done, retitle it by **what is still open**, and move the
   finished part out. "An incoming call cannot wake the phone — FIXED" became
   "The modem edge is not armed at boot, so automatic sleep must stay off": same
   facts, and the heading now names the thing a reader must act on.
2. **Do not put a value in a heading you are not prepared to re-check every time
   you edit the file.** Revisions, counts, percentages and dates in headings all
   rot on their own schedule, out of sight of the body that justified them.

A cheap audit that finds all of it:
`grep -n '^#.*~~\|^#.*CLOSED\|^#.*FIXED\|^#.*✅' <file>` — every hit is a
heading claiming to be settled, and each one needs its body read to confirm it
still is.

## Working unattended — what actually stops, and what does not

"Unattended access" elsewhere in these skills means *no human at the phone*. This is
the other half: what to do when there is no human **in the conversation** either — an
overnight run, a "go until morning", any instruction that hands you the flash gates.

**The failure this section exists to prevent.** Five independent items remained, all
specified, none blocked; the turn ended with *"which should I start with?"* — and named
the default in the same breath. **A stated default plus a question is still a stop**, and
it costs the whole night. If you can name the default you do not need the answer:
execute it, and say which order you chose and why.

**Only three things legitimately stop an unattended run.**

1. **A physical act only the human can perform** — plug or unplug the charger or the
   jack, swap a battery, read a label off the hardware, press a button, place a call,
   hold the phone in an orientation. `fp3-kernel-test` Step 4h enumerates these and
   gives the handshake: one action, stop, resume on their reply.
2. **An outward-facing or hard-to-reverse action beyond the standing authorisation** —
   posting to a mailing list, pushing to a repository that is not the user's own,
   anything that reaches a third party.
3. **A brick-safety gate the guardrails say needs a human** —
   [`../fp3-kernel-test/references/safety.md`](../fp3-kernel-test/references/safety.md).

Everything else continues. **None of these is a reason to stop:**

- *"Which of the remaining items first?"* — pick one, say so, reorder later if it was
  wrong. Redirecting afterwards costs the user one message; asking costs the night.
- *"Is this the design you want?"* — build the one you can defend and write down the
  alternative you rejected, with the reason. A reviewable artifact beats an
  unanswered question.
- *A milestone finished cleanly.* Green is a reason to continue, not to hand back. The
  urge to report a success is not the same thing as needing permission for the next step.
- *The next step is large* — a full build, a flash, a rebase. Size is not a gate; the
  guardrails are, and they are written down.
- *A number surprised you.* Measure it again, by a different instrument, and record both.

**A default order, so the choice does not re-litigate itself every time.** When several
items are ready and nothing else distinguishes them:

1. **Measurements the current device state makes possible.** A phone in a known state is
   perishable — the next deploy, reboot or slot switch destroys the opportunity, and no
   amount of later reasoning recovers it. Measure first, write up afterwards.
2. **Anything that makes an already-written claim false.** Stale status misleads the next
   session, which is usually you.
3. **Whatever unblocks the most other items.**
4. The rest, cheapest first.

**If you do have to stop, leave a one-line resume point, not a menu.** End on the single
physical act or the single decision that is actually needed, phrased so the reply can be
one word. A five-way list guarantees the human has to re-read the whole session before
they can answer anything.

## Local knowledge base (bundled — read on demand)

Progressive disclosure: the SKILL body stays small, Read a pack only when you
need it. The searchable index, including the "what did we already rule out" map,
is [`references/data-index.md`](references/data-index.md) — **read it first.**

**Audio (SLIMbus / WCD9335):** the settled account is
[`docs/audio/`](https://github.com/llg179org/fp3-pmaports/tree/main/docs/audio) (how
it works) and
[`docs/audio/bringup/`](https://github.com/llg179org/fp3-pmaports/tree/main/docs/audio/bringup)
(how it was brought up, including the traps worth carrying forward). Here:
- `references/slimbus-audio-red-herrings.md` — the dead-lead catalogue: what was
  ruled out and why. Still live, because "do not re-chase this" does not expire.
- [`references/archive/`](references/archive/) — the dated investigation logs,
  including the component address map in `slimbus-audio-context.md` §7.

**Device + the other tracks:**
- `references/archive/hw-facts.md` — the 2026-06-25 raw facts dump (partitions, boot-image params, USB gadget/VID:PID, log channels). **Archive, not reference:** dated and mostly Hungarian; the substrate the method relies on is in "The device" above.
- `references/archive/pmos-bringup-log.md` — the dated pmOS bring-up log (charger, fuel-gauge, modem, the SLIMbus wall), 2026-06-28…06-30. **Archive, not reference:** its eight status sections were deleted on 2026-07-30 because every one of them had gone false; current state is in `docs/`.
- `references/archive/sailfish-components.md` (+ `sailfish-customizations.md`, `sailfish-akcioterv.md`) — the Sailfish (hybris) port: provenance (component→repo/branch+why), the build-modification log, the step plan. **Archive:** a provenance log and a checked-off plan are status, and the plan moves.
- `references/archive/ut-framer-boot-sequence.md` — the 2026-07-23 UT boot-ordering capture (the working framer path).
- `references/archive/report-attachments/` — polished write-ups and raw dumps (firmware strings/disasm, PIL-vs-PAS, golden IPC traces, devmem dumps, outreach drafts). Local only; not in the published repo.

**Method references (the *how*, split out of this SKILL for size).** ☠️ Three of
these live in the **sibling** skill, not here — this line named them as
`references/{safety,firmware-re,recovery,devmem-oracle-kernel}.md` until
2026-08-25, and three of the four paths did not resolve:

- `references/devmem-oracle-kernel.md` — here.
- [`../fp3-kernel-test/references/recovery.md`](../fp3-kernel-test/references/recovery.md)
  — **the one to open when the phone will not boot.** The A/B slot-swap route,
  the `losetup -fP` nested-MBR trick, the silent `rc=1` on the wrong node.
- [`../fp3-kernel-test/references/safety.md`](../fp3-kernel-test/references/safety.md)
  — the brick-safety gates, and "an escape route you have not exercised is not
  an escape route".
- [`../fp3-kernel-test/references/firmware-re.md`](../fp3-kernel-test/references/firmware-re.md).

☠️ **A broken path in a skill fails in the worst possible way**: it fails at the
moment the file is actually needed, which for `recovery.md` is a phone that will
not boot. It is the same class as "a rule that lives only behind a link does not
fire", one step worse — the link did not even resolve. When a skill names a
bundled file, the cheap check is `ls` on the path it just wrote, and it costs
nothing next to being wrong here.

**Tooling + source, also bundled:**
- `scripts/` — the reusable FP3 tooling, one line per script in `scripts/INDEX.md` (read that
  first to find the right one). Config comes from `scripts/fp3-env.sh`; every value is
  `${VAR:-default}` with the default documented inline, and secrets (`FP3_PW`, `FP3_SERIAL`)
  have none — put yours in the git-ignored `fp3-env.local.sh`. Source only: `$GEN` (the
  `generated/` symlink → `/tmp`) takes every runtime output, see `scripts/README-generated.md`.
- `scripts/archive/` — single-use reverse-engineering artifacts from the SLIMbus audio work
  (`build_snap*` → `deploy_snap*` → `smem_snap*_read` triplets, the Hexagon hooks, and the
  `m2/` firmware-resigning tree). Kept as a record of what was tried, not as a toolkit; most
  of it needs vendor firmware that is not redistributable.
- `src/` — symlinks to the kernel trees + build system, with `src/sources.manifest.md`
  (git URL + branch per tree) so a fresh machine can **clone-if-absent** and re-point the link.

One thing still lives *outside* the skill by design:
- `FP3-slim-debug-journal.md` — the investigation journal (this skill bootstraps + appends it; see "Feeding the method back").

The bundled docs are load-bearing because the effort is long and context resets:
**the first move in any session is to read `references/data-index.md` — what has already been
ruled out** — so you extend the search instead of repeating it.

### Feeding the method back (the skill creates and maintains two logs)
This skill improves only if the lessons it earns get written down where a future edit can
find them. So while you work, keep **two** running records in the project root, and don't
conflate them. **The skill owns their existence — bootstrap each one create-if-absent:**
before your first append, if the file is missing, create it by copying the matching template
from this skill verbatim; if it already exists, just append (never overwrite a log).

- **The investigation journal** → `FP3-slim-debug-journal.md`, template
  [`references/journal.template.md`](references/journal.template.md). The fault's
  `hypothesis→test→verdict` timeline; append every experiment + result, never rewrite history.
- **The skill-feedback log** → `fp3-skill-feedback-log.md`, template
  [`references/skill-feedback-log.template.md`](references/skill-feedback-log.template.md).
  Whenever you hit a *transferable* lesson (a new brick-safety class, a measurement-integrity
  trap, a better recipe, or a **correction to a claim in one of these skills / their
  `references/`**), append an entry tagged with its target (which skill+section or which
  reference file) and status `NEW`. This log is the raw material for the *next* revision of
  these skills — not the specific-fault status, and not a dated result-log (those live in
  `data-index.md` in the project, never in the skills). When a skill/reference is next revised, fold in the `NEW`
  entries, mark them `PROMOTED`, and prune.

☠️ **A commit message stating a hypothesis that later turned out false is a trap
laid for a future session**, because it reads as a finding and carries a hash. Two
of them are on record here: a DTS commit whose body explains why the ADSP derives
its clock divider from the CX corner (measured false a day later), and a driver
commit describing register tables as read off the sensor (they came with an
import). Neither was wrong when written. So when an experiment is disproven or a
provenance claim corrected, **fix the record where it will be read**: the doc page
gets the correction, and if the commit's branch is being deleted anyway, tag it
with the verdict in the tag message — `archive/cx-turbo-disproven` exists exactly
so the three commits stay reachable *with* the note that their reasoning does not
hold. A rewritten `wip` history is not worth it; an unannotated dead end is worse
than a deleted one.

## The device (substrate — verify each session, names drift)
- SoC MSM8953/Snapdragon 632, Adreno 506, aarch64. Codec WCD9326/Tasha-lite on
  **SLIMbus** (earpiece/mic/headset are SLIMbus-only; speaker = aw8898 on MI2S).
  PMIC PMI632.
- **A/B slots everywhere** (system, vendor, boot, dtbo, modem, dsp, vbmeta) — this
  is the single most useful property of the device (see "dual-slot" below).
- Boot chain XBL → ABL → **lk2nd** (flashed into boot; provides fastboot + boots
  the real kernel). Two things silently fail a boot if wrong and are worth checking
  first on any "it won't boot": a **skipped dtbo flash**, and a **boot-image header
  version mismatch**. (Example: a missing dtbo — not AVB — was the native-boot
  blocker.)
- Partition labels drift — re-derive from `lsblk`/`by-partlabel` on a booted OS
  each session rather than trusting a remembered map.
- **Neither OS needs a human at the phone.** `fp3-ssh 'cmd'` (pmOS) and `ut-ssh 'cmd'`
  (Ubuntu Touch — USB, then WiFi, then UT's rescue sshd) log in by key and heal the link
  themselves; each OS comes back from a reboot untouched (39 s / 76 s, measured). The
  recipe, and the measured proof that a USB replug **cannot** be emulated from the host,
  is under "Unattended access" in the repository README.

- **☠️ To run something on the phone that must outlive the SSH session, use
  `systemd-run`, not backgrounding.** Any measurement that suspends the device, cycles
  USB, or simply runs longer than the connection will lose its shell, and the usual
  incantations do not save it here: both `sudo … setsid nohup script &` and
  `sudo … setsid sh -c "nohup script &"` were measured dying — one left no output file
  at all, the other a log truncated at the first few lines, which reads exactly like the
  script crashing at whatever it was about to do. That misreading is the real cost: the
  hunt starts on the wrong side. What survives is
  `sudo systemd-run --unit=<name> --collect /bin/sh /tmp/script.sh`, with the script
  redirecting its own output to a file; check it with `systemctl is-active <name>` and
  read the file afterwards. `--collect` drops the unit when it exits, so the name is
  free to reuse next round.

- **A USB-unplug-proof link exists, and it is the one to use whenever the charger or
  the USB port is being manipulated.** The phone usually also holds a WiFi address on
  the *host's own subnet* — check `ip -4 -o addr` on both ends — so SSH to that address
  survives unplugging the USB gadget link (whose `172.16.42.1` dies with it). Measure
  the address each session; DHCP moves it. **Harden that path key-only** once it is a
  routable LAN address: a global `PasswordAuthentication no` + `KbdInteractiveAuthentication
  no` at the end of `sshd_config`, then `Match Address <usb-net>` re-enabling both so the
  physically-local USB link keeps a password fallback. Four traps cost real time:
  the binary is **`sshd.pam`**, not `sshd` (so `sshd.pam -t` validates); `Match Address`
  **rejects `*`** and **rejects a CIDR whose host bits are not zero** (`172.16.42.0/16`
  is an error — use the network address `172.16.0.0/16`); with `UsePAM yes` **both**
  auth options must be off or PAM keyboard-interactive still serves passwords; and a
  `systemctl reload` (SIGHUP) makes sshd re-exec, so connections are briefly refused —
  retry before concluding a lockout. Always `sshd.pam -t` and keep a `.bak` before reload;
  key auth is untouched, so a password-only misconfiguration cannot lock a key user out.

- **The vendor's full 4.9 source is on disk, not just its device trees.** Register
  maps, scaling tables and the reasons behind a downstream device-tree value live in
  the *drivers* (`drivers/power/supply/qcom/`, `sound/soc/msm/`, …), and that tree is
  checked out locally — the FP3's UT kernel source doubles as Fairphone's published
  release. `fp3-pmaports/docs/device_tree/downstream/` checks in only the `.dts`/
  `.dtsi` files, so when a question is "what does this register mean" or "what step
  size is that field", go to the local kernel checkout, not to the docs. (Everything
  the charger work needed — the JEITA block layout, the 25 mA compensation step, the
  per-PMIC parameter tables — came from `smb5-reg.h`, `smb5-lib.c` and `qpnp-smb5.c`
  there, none of which is in the repo.) Locate it once per session; the path drifts
  with the disks.

  ☠️ **A `find` that hit its timeout is not a negative result, and treating it as one
  is expensive.** The tree is under an Android/hybris build root on a slow spinning
  disk, so an unanchored search across it will run past any reasonable limit and come
  back empty-handed — which reads exactly like "not on this machine" and sends you off
  to guess at register semantics instead. Anchor the search: the build roots are a
  short list of top-level directories, the kernel sits under `<root>/kernel/<vendor>/
  <soc>/`, and `ls` down that path costs nothing. If a search is abandoned rather than
  completed, say so in those words and do not spend the rest of the session acting on
  its silence.

## The three OS tracks — and the *role* each plays in debugging

The reason to keep three OSes on one phone is that they check each other. Think in
terms of what question each answers:

### Ubuntu Touch / Halium — the ORACLE (the reference answer)
- Downstream kernel 4.9.x, everything works (call, earpiece, mic, headset,
  charging). Root via `sudo` + the device PIN (this device `$FP3_PW`, *not*
  "phablet").
- **★ You can prepare access to an OS that is NOT running, from the other slot — no UI, no
  working link needed.** The oracle keeps `/home` in `user-data/` and the writable half of
  `/` in `system-data/`, both on `userdata`; mount that from the *other* slot and stage
  whatever you need. (Worked example 07-28: an SSH key into `user-data/phablet/.ssh/`
  (uid/gid 32011) plus a wants-symlink
  `system-data/etc/systemd/system/multi-user.target.wants/ssh.service` gave the oracle a
  working sshd at the next boot — bypassing its own gate, a one-shot
  `ssh-property-migration.service` that **masks itself after its first run** and so cannot be
  relied on. The read-only rootfs is not an obstacle: on UT `/etc/systemd/system` is a
  read-write bind mount from `userdata`, while `/usr/local/bin` and `/var/lib` are not.)
  This generalises: the bootstrap problem "I need the link to fix the link" is solved from
  the neighbouring slot, not from the running system.
- **You can drive the oracle right after boot — no unlock, no USB replug needed
  (so it does NOT require the user to be present).** Verified: `adb` connects while the
  device sits at the locked greeter (`lomiri --mode=full-greeter` running), because this
  build has `ro.adb.secure=0` (adbd accepts connections without RSA-key authorization) *and*
  the host key is persisted (`/data/misc/adb/adb_keys`). So after `fastboot set_active a` +
  reboot, just wait ~90 s and `adb` is up. (The old "login on the lockscreen + USB
  unplug/replug, only then does adb appear" advice was a *first-time* artifact — authorizing
  a brand-new host key needs one on-device unlock; once stored, and with `ro.adb.secure=0`,
  every later boot is hands-off. Re-verify `ro.adb.secure` after any reflash.) Note `sys.usb.config`
  defaults to `mtp` but adb is in the composite from boot; don't wait for a mode toggle.
- **☠️ But a *slot switch* can leave adbd wedged as `offline` — and that is NOT an auth
  issue.** After `set_active a` from a long session of reflashes/reboots, `adb devices`
  may show the oracle stuck `offline` for many minutes despite `ro.adb.secure=0` (which
  means no authorization is even required). Host-side thrash makes it worse: `adb
  reconnect` in a loop and repeated `kill-server` cause the server to *reset the USB device
  every ~5 s* (`usb 1-5: reset high-speed USB device` on repeat), which prevents adbd from
  settling. Method: `adb kill-server`, leave it **untouched** ~30–60 s (no server → no USB
  resets → adbd settles), then one fresh `start-server` + single probe. If still `offline`,
  it is a wedged adbd, and the reliable fix is a **device reboot or ~~a physical USB replug~~**
  (which makes adbd re-offer the connection) — not more host-side reconnects. ~~This one *does*
  benefit from the user if present (a replug is instant)~~; otherwise a `adb reboot` once it's
  briefly reachable, or a fastboot cycle, clears it. **A wedged adbd no longer costs you the
  device:** with the unattended setup in place, `scripts/ut-ssh.sh` reaches UT over SSH (USB,
  WiFi, or UT's rescue sshd) completely independently of adbd — and a host-side replug was
  measured to be impossible in any case. See [Unattended access](../../../../README.md#unattended-access-no-on-device-login-no-usb-replug).
- **On UT, drive it over `adb`, not `ssh` to `$FP3_DEV_IP`.** The UT USB-RNDIS comes up on a
  DIFFERENT subnet than pmOS (host saw `10.42.0.100/24`, device ~`10.42.0.1`), so `ssh
  phablet@$FP3_DEV_IP` (the pmOS IP) times out. `adb` works (`ro.adb.secure=0`); `adb shell`
  lands as **phablet**, root via `echo $FP3_PW | sudo -S …`. The ~90 s hands-off reconnect above
  held on UT reboots (~~only the first slot-swap entry needed the on-device login + one replug~~ —
  no entry needs either any more, see [Unattended access](../../../../README.md#unattended-access-no-on-device-login-no-usb-replug);
  every later UT reboot reconnected `adb` by itself in ~60–90 s — just poll `adb devices`).
  UT's ADSP firmware is a **split PIL image** — `/vendor/firmware_mnt/image/adsp.mdt + adsp.b00..b14`
  on `/dev/mmcblk0p1` (VFAT, RO); the .text/framer segment is `adsp.b04`. ☠️ A qtestsign re-signed
  image is REJECTED by UT's `subsys-pil-tz` (rc:-22) — see `fp3-kernel-test` "re-sign"; treat the UT
  firmware as read-only, do fw caves on the pmOS side.
- **Its job:** answer "what does a *working* stack do here?" It boots the ADSP via
  the vendor PIL/TZ path, so its SLIMbus framer comes up — exactly the thing the
  mainline port can't yet reproduce. You keep it on `slot_a` and diff everything
  against it.
- **Live `/dev/mem` on the oracle — check the stock kernel first.** The stock UT build
  in use (`4.9.218-perf-ubuntutouch+`) already ships `CONFIG_DEVMEM=y` +
  `# CONFIG_STRICT_DEVMEM is not set` + a `/dev/mem` node, so you can read MMIO on the
  oracle with **no custom kernel and no flash** (verify: `zcat /proc/config.gz | grep
  DEVMEM; ls -l /dev/mem`). Use a Python `mmap` reader (`dd`/`busybox devmem` return
  empty under the STRICT read-path). Some older UT builds lacked it; if you land on one,
  the custom kernel below fills the gap. **☠️ But "present" ≠ "unrestricted for MMIO" (folyt.154):**
  on this UT boot the stock `/dev/mem` returns *gated junk* for MMIO — a known-clocked GCC block
  reads all-zero, the LPASS framer reads all-`0x40` fill — while the same read works on pmOS. So an
  oracle-side MMIO capture may need the **loadable module** (`framer_mmio_dump.ko`) or the DEVMEM
  kernel even though `/dev/mem` exists; **verify against a known-clocked non-LPASS register (GCC)
  before trusting a UT `/dev/mem` MMIO read.** (The folyt.143 "byte-identical two-sided /dev/mem"
  used the module on the UT side, not raw /dev/mem.) **But first ask whether you even need MMIO:** the
  highest-value oracle differential — which clocks are enabled during the working
  handshake — is a debugfs `clk_summary`/`enabled_clocks` read that needs *no* `/dev/mem`
  at all (see `fp3-kernel-test` "Clocks").
- **If the stock kernel lacks `/dev/mem`, build the DEVMEM oracle kernel** — full recipe
  (fast repack from the stock `boot.img`, and the from-source build: exact UT branch,
  toolchain, KCFLAGS, make-4.3 gotcha) in
  [`references/devmem-oracle-kernel.md`](references/devmem-oracle-kernel.md). Flash to the
  oracle slot only with the user's approval; keep the stock `boot.img` as the one-command
  revert (only the kernel swaps, the oracle's rootfs is untouched).

### postmarketOS mainline — the native target (the system under test)
- Mainline kernel, phosh. Working: display, touch, GPU (freedreno a506), WiFi,
  modem+data, charger, fuel-gauge, speaker (MI2S), and — as of folyt.208 — **SLIMbus
  audio: audible clean playback on earpiece/headphone** (WCD9335). The years-long
  SLIMbus wall is down (framer bit3 + MCLK `func1` pinmux). Remaining open: the analog
  **mic** path (AMIC audio-routing) — a small, separate task.
- **Build gotcha that wastes the most time:** build with `--src <linux-fp3>` — a
  plain `pmb build` pulls the upstream tarball and **silently omits your DT/source
  edits**; the `_pYYYYMMDDHHMMSS` version suffix marks a correct `--src` build.
- Flash order that boots: **dtbo → lk2nd → vbmeta → rootfs → reboot**.
- For the kernel/firmware iteration loop use the **`fp3-kernel-test`** skill.
- **Jack/headset-detection (MBHC) debug pattern** — the worked example of a
  codec-owned jack, an edge-transient status register, and a one-direction
  edge-detect that must be re-armed — lives in **`fp3-kernel-test`** (Step 1a,
  the MBHC lessons). Reach for it when an evdev `SW_*` state won't track physical
  plug/unplug.

### Sailfish OS — hybris on a LineageOS/e-OS base (the third port)
- hybris target on an Android base; component provenance, porter patches, and the
  RAM-constrained soong build recipe are in `references/archive/sailfish-components.md` — **read it before
  touching the Sailfish build**, the build environment is the hard part.
- Boot-blind bring-up techniques (below) are shared with this track.

## A fact you established an hour ago does not retrieve itself

The expensive mistakes in this work are rarely things nobody knew. They are
things **you** established, wrote down, and then did not consult while writing
the code that violated them — because the finding was filed under *analysis* and
the violation was written under *plumbing*, and plumbing feels routine enough to
skip review. Knowing the fact harder does not help. Only retrieval helps, and
retrieval has to be engineered.

**Index each finding by an identifier you will literally type**, not by its
topic. A note filed under "the fuel gauge" is found only by someone already
thinking about the fuel gauge — precisely the person who does not need it. A
note filed under the symbol is found by grep, by autocomplete, and by eye:

```
capacity, charge_now   → frozen across a suspend; never guard or gate on these
/proc/uptime           → boottime, includes suspended time; cannot detect sleep
pkill -f <pattern>     → over SSH it matches the calling shell; kill by PID
```

**Keep the ledger short enough to re-read** — about a screen, this session only.
Past that it has stopped being an instrument and become an archive.

**Schedule the retrieval, because it will not happen on its own.** Before
anything unattended, irreversible or outward-facing, grep the plan and the
script for every identifier in the ledger. That single step is the method; the
rest exists to make the grep possible.

**Annotate at the point of use.** The constraint belongs in the file where the
violating line will be written — a comment beside the guard, or better a check
that fails. A fact three directories away has to be remembered; a fact on the
adjacent line has to be actively ignored, which is much harder.

☠️ **Fire every detector once against a known positive.** Anything whose job is
to detect, guard or prevent must be *watched doing it* before it is trusted: set
the threshold so it must trigger, see it trigger, set it back. Thirty seconds.
This is the only step that also covers the facts you never established, and it
is what separates a guard that works from a guard that has simply never been
observed failing to work.

**Weight review by consequence, not by interest.** The rail that bounds the
damage deserves more scrutiny than the measurement that produces the result: the
measurement's failure mode is a wasted run, the rail's is unbounded. The natural
instinct is the reverse, and it is wrong. For anything unattended, add a second,
independent bound — a wall-clock limit sized to the risk — because a single
guard that turns out to be blind is indistinguishable from no guard at all.

**Two ledgers, and they answer different questions.** The session ledger holds
what *you* learned today. The repository's **retraction tables** — the "we
believed X, X is false" rows that accumulate in a project's bring-up READMEs —
hold what the project learned before you, and they exist because those facts were
expensive. ☠️ **Consult them before building an instrument**, not after:
`grep -rn "<the attribute>" docs/*/bringup/README.md` costs nothing and can
delete a day's work before it starts.

☠️ **But a ledger is an instrument too, and it can be wrong.** One was checked,
believed, refuted by the next sample, and then vindicated on a different axis —
three positions on one fact inside an hour. What settled it was not more reading;
it was **two instruments disagreeing by 37 %**, which was the only step in the
sequence that could not be argued with. So:

- **A ledger row that agrees with your first sample is a hypothesis that has just
  become worth testing properly**, not a confirmation. A first-sample agreement
  is the most dangerous kind, because it removes the reason to keep looking — and
  so is the first *dis*agreement, for exactly the same reason.
- **Where a new instrument is proposed, run the old one beside it.** The
  disagreement, not the number, is the result.

### ☠️ A rule stated in prose is a wish; a rule in a script is a rule

The hardest-earned entry here, because every excuse for it had already been
removed. This project records its retractions carefully. One of them named a
mechanism, retracted four measurements on the strength of it, and wrote the fix
out in bold with the exact command to run. **Five days later the same failure
destroyed the control leg of an overnight run**, because the rule was never put
into the tool that needed it.

It was not behind a link. It was not in a skill. It was in the project's own
findings log, in the file the person had written themselves. It still did not
fire — because **a findings log is read when you are looking for a finding, and
nobody is looking for a finding at the moment they schedule a run.**

So: **a retraction is not finished when it is written down. It is finished when
the gate exists.** Where a measurement has a validity precondition — a service
that must still be running, a state that must still hold, a device that must
still enumerate — that precondition belongs in the tool, as a check that

  * runs at the point where it can still change the outcome,
  * is **allowed to fail**, and
  * says in its own output what is invalid if it did.

A tool that swallows the outcome of its own restore (`2>/dev/null`, no readback)
cannot distinguish "restored" from "did not happen", and neither can anyone
reading its log afterwards.

### ☠️ Print the state beside every result, before anyone asks what it is for

The same run that lost its control leg had recorded the evidence of the loss all
along. Each arm printed how long it actually slept against how long it asked —
put there for an unrelated reason. When an independent measurement days later
established what that number should look like in each state, the contamination
became **readable in the raw capture**, with no re-run, no new instrument and no
cleverness. Only a reason to look at the column, which did not exist when the
capture was taken.

Generalise it: **the cheapest thing a measurement can do for its future self is
record the conditions it was taken under** — the state of every service it cut,
the revision, the cable, the uptime, the registration state. It costs a line. The
question that makes it decisive is usually not yet asked.

### ☠️ Read the header before indexing by position

Three times in one session a **correct command** produced a **confident wrong
answer**, and every one was the same mistake wearing different clothes:

* a regulator dump read as a flat list when it is a **tree** — the indented rows
  are child regulators, not only consumers, so two rails looked "on for us, off
  for the oracle" when both were held by a child. Published as a lead, dead
  within hours.
* `grep -r --include='sub/dir/*.md'` — `--include` matches **basenames, not
  paths**, so the search silently covered a fraction of what it appeared to and
  reported seven things absent that were present.
* `awk '$9 > 0'` on a debugfs table whose interesting field is **$10** — the
  neighbouring column was a millisecond timestamp, nonzero for every row that had
  ever been touched, so a settled exclusion appeared to collapse.

None of these fails loudly. Each returns a plausible, well-formed, wrong result,
and the wrongness is invisible in the output — which is why "the command ran
fine" is not evidence about a positional read.

**The rule is one line: before indexing a field by number, print the header.**
`head -1` on the file, or the tool's own labelled row. It costs nothing next to
the retraction. And the same applies to *shape*: before diffing two dumps, decide
whether the thing is a list, a table or a **tree** — the diff will not tell you,
and a tree diffed as a list invents differences that are just nesting.

☠️ The tell that should trigger the check: **a result that arrives cleanly on the
first look at a question nobody has answered before.** That is when to go back
and read the header, not when the numbers look strange.

### ☠️ n in one direction is not a law — try to break it before you publish it

Five consecutive measurements from two different instruments agreed. It was
written up as a categorical statement about the device. **One hour later a third
instrument produced the opposite result** under conditions nobody had varied on
purpose, and the statement had to be withdrawn from three documents.

This is the first-sample-confirmation trap above, one level up: it applies to a
*pattern* exactly as it applies to a *sample*, and agreement across instruments
does not protect against it when none of them was aimed at breaking the claim.

**Before an observation becomes a law, run one round whose purpose is to falsify
it** — vary the thing you did not vary, and say what you varied. And when the
data says "sometimes", the next measurement is a **rate**, not another story: n
repetitions of one condition, with the candidate variables recorded per round, so
that "sometimes" acquires a number instead of a narrative.

## Is that number a decision, a construction, or an observation?

Every value in the system is one of three things, and the difference is invisible
once it is a literal:

* **a decision** — we chose it; it is true because we said so;
* **a property of the construction** — it cannot vary: a register offset, a
  protocol constant, a physical constant;
* **an observation about one instance of the world** — true of this unit, this
  revision, right now.

The bug is writing the third kind as if it were one of the first two, because a
literal discards the observation's scope. A JEITA threshold is not "a number", it
is *a claim about the battery pack in this phone* — and a phone model that ships
two different packs makes that claim device-specific.

**One question decides it:**

> Could two devices, both running this code correctly, disagree about this
> number?

If yes, the value belongs to the device rather than to the source, and it has to
be measured — or at the very least verified. The question needs no knowledge of
the hardware; it only needs to be asked.

**Record what the number is a claim about, not where it was copied from.** ☠️ A
citation names the *source*, and that is what makes it dangerous: an exact vendor
filename in the comment is what carries such a mistake through review intact.
The useful annotation names the *subject* — "this is a property of the pack, and
this model ships two". After the first form a reviewer nods; after the second
they ask how you know which one is fitted.

**Turn the assumption into an assertion.** Where a constant is unavoidable, also
program the check behind it: read the identifier, compare, and refuse to apply
the values when it disagrees. An assumption that can be checked cheaply at
runtime should be, and its violation should fail loudly — silent degradation is
the real cost of a wrong constant, not the wrong value itself.

**Give "cannot tell" a defined behaviour.** These bugs come from framing the
question as binary and leaving out the case where identification fails. Decide
what happens then, explicitly and safely, or the unknown case lands silently on
one of the branches.

**Test the population, not the specimen.** Exercise the code against the *other*
variant, not only the one in your hand; simulate it if the hardware is
unavailable. A test that runs only on your unit validates your unit.

☠️ **Precision is a proxy for confidence, not for correctness.** An exact
filename, an exact number and an assured tone all raise a reviewer's trust
without raising the truth of the claim. Weight it the other way: a constant that
*looks* precise deserves more scrutiny about its scope, not less. "Where is it
from?" always has a good answer. The question that finds the bug is "what is it a
claim about, and can that vary?"

Both sections above are the same rule seen twice: **a mechanism that verifies at
the moment of use beats a decision frozen at authoring time** — whether the
frozen decision is about an instrument or about the hardware.

## Acquiring ground truth locally — the core method

### Rule zero: a measurement is a comparison, so say what it was compared against

State it in the report, unprompted, every time — the number alone is not the
result. The failure this guards is not a missing check but a check that ran,
passed, and compared an artifact **to itself**: verifying a deployed file's md5
against the tree it was built from is true by construction and proves nothing
about whether that tree was the right one. Writing the comparand out in words is
usually enough to notice.

Three companions, same reason, also unprompted:

- **Deploying to the device → name the source: which branch, which artifact.**
  "The freshly built DTB" is not an origin; `debug-int/<base>` extracted from
  `linux-fp3-<ver>-r<n>` is, and so is `wip/<base>/camera` built in a worktree —
  and the difference between those two is invisible in the file and decisive in
  the result.
- **Reporting a check → print the command.** A check whose command is not shown
  is an assertion. This is why the checks under `fp3-pmaports/tests/checks/`
  emit a `cmd:` line beside the verdict.
- **No command exists for a check → write one.** First look for the one that
  already exists — a new script that duplicates a selftest check rots on its own
  schedule and is worse than no script. If there genuinely is none, put it in
  `scripts/` here and add its row to [`scripts/INDEX.md`](scripts/INDEX.md).

☠️ **And name the quantity the complaint is actually about, before picking the
instrument.** The obvious throughput number for a subsystem is often the one it
is *least* sensitive in, and measuring it produces a confident "no difference
here" that closes the investigation. A media pipeline capped by something else
absorbs a large change in work as idle time rather than as frames, so the frame
rate barely moves while the processor time moves a lot — and a user complaining
that *the rest of the interface* stutters is describing the processor time,
because the compositor competes for the same cores. Ask what the person
noticed, decide which quantity that is, and only then choose the instrument.
Wall-clock throughput, processor time, memory bandwidth and latency are four
different questions and a pipeline can be flat in one while it doubles in
another.

### Sample several times faster than the fastest thing you are willing to believe in

☠️ **A sampling interval close to the period of what you are watching invents
structure that is not there.** A one-minute sampler over a phone's idle current
produced a clean "something happens every two minutes"; at five seconds the cycle
did not exist — a flat floor with irregular peaks, and half a dozen daemons
running at 5, 10, 20, 25 and 30 s beating against the sampler. Hours can go into
explaining an artefact of the instrument. Before theorising about a period,
re-measure at several times the resolution and check that the period survives.

The same discipline applies to per-process accounting built by differencing
`/proc/[0-9]*/stat` between snapshots. Two failure modes make the output absurd,
and both are obvious *if* you sanity-check the total against `load average` and
reject it when they disagree:

- **a dropped previous snapshot turns every delta into a cumulative total** for
  that sample, which reads as one process using several hundred percent of a
  core. The tell is arithmetic: the suspect number divided by a plausible one
  comes out as a small integer, identical for several processes.
- **kworkers rename their `comm` per work item**, so any `pid|comm` key resets
  between samples and the same PID appears twice with near-identical totals.
  Exclude them, or key on PID alone.

### Subtract a suspect rather than reasoning about it — but restore unconditionally

To find what a running system is spending on, stop one component at a time and
measure between each, **cumulatively** (never restoring between phases), so the
phases form a descending staircase instead of N independent comparisons. What
makes it safe to run unattended:

- name the components that may **never** be stopped and keep them out of the
  list — the transport you are connected over, its network manager and its bus;
- a `trap` plus an unconditional restore at the end of the script; and
- a **dead-man switch that does not depend on the script**:
  `systemd-run --unit=deadman --on-active=45min` restarting everything, so a
  crashed or interrupted run still leaves the device whole.

Read a flat staircase as a real result. Ten daemons stopped with the floor
unmoved is not a failed experiment: it excludes an entire class of explanation
and points the next measurement at wakeups and interrupt counts rather than at
CPU time.

☠️ **Stopping a daemon can make the user interface lie in exactly the shape of
the bug you are hunting.** Stopping the power daemon made a phone report 0 %
battery — indistinguishable, on screen, from a fuel gauge that had collapsed, and
alarming enough to prompt real-world action. The kernel's own log was continuous
and physical throughout. When a displayed value goes wrong during an experiment,
check the layer that *produces* it before believing the layer that *shows* it —
and consider that you may have caused it.

☠️ **A `trap` does not protect against something killing the unit from outside,
and the restore you skip verifying is the one that fails.** Every measurement
script here carries `trap restore EXIT INT TERM`, and it held all night — normal
exits, `RuntimeMaxSec` expiry, ssh timeouts. Then one running transient unit was
stopped by hand (`systemctl stop <unit>`) to launch its successor, and the modem
manager stayed down for the next thirty-five minutes. `systemctl stop` terminates
the unit's whole cgroup: the shell gets SIGTERM, the trap starts, and
`KillMode`/`TimeoutStopSec` can take the process down before `restore()` finishes
its `systemctl start` loop — which itself needs to talk to the same systemd.

Two rules, the second cheap enough to be unconditional:

1. To swap one measurement for another, let the first **finish**, or give it a
   deliberate stop path. Do not `systemctl stop` a unit whose restore matters.
2. **After any manual stop, verify the restore by reading state, not by trusting
   the trap** — one line naming the services, the charger, and whatever the
   script cut.

☠️ **And a restore that "starts the service" is not a restore if starting the
service is not what brings the thing back.** Some services own hardware they do
not re-acquire on start: stopping the remote-filesystem daemon powers a
co-processor down, and starting it again does *not* bring the co-processor back —
that needs an explicit `remoteproc` start, and a dependent daemon may stay broken
until reboot. A `restore()` that loops `systemctl start` over its cut list will
report success and leave the device in the cut state, which turns the *next* leg
of an A-B-A into a second treatment leg wearing the control's name. Restore, then
**verify the thing itself**, not the service that was supposed to provide it.

☠️ **A wait loop needs a case for "the thing I am waiting for no longer
exists."** Without it, it does not fail — it polls forever. Four orphaned
host-side loops were found ssh-ing a phone every 20–30 s to ask about units that
had already completed, because `systemctl is-active` on a `--collect`ed unit
returns non-zero and the loops read that as "not ready yet". That polling is not
free: on a power measurement the observer's own logins were later measured as a
real load, in the shape of a monotonic trend that read exactly like the effect
under test. **After starting a measurement, the next touch is the end of the
measurement.**

### Before writing a workaround, check whether the real path exists and is merely starved

☠️ **A software substitute for an unreachable hardware precondition is worth less
than making the precondition reachable, and it costs more.** The shape recurs: a
correction the hardware offers never fires, so a driver-side equivalent gets
written, and it works. Two questions are worth more than that patch.

- **Is the hardware path missing, or just never satisfied?** Read the driver
  before writing the substitute. Finding the register already read,
  de-duplicated and consumed means there is no code to write at all — the gap is
  in the operating conditions, and the patch is scaffolding around a mechanism
  that already functions.
- **Is the substitute's own precondition really more reachable?** Compare the two
  gates numerically, and check when each is satisfied in normal use rather than
  in the test that demonstrated it. A workaround that only fires under conditions
  a user never produces has replaced an unreachable correction with a
  rarely-reachable one, and left two mechanisms correcting the same quantity on
  different schedules.

When the answer is that it is scaffolding, **park it rather than merging it**:
keep the patch, the measurement showing it works, and the condition that would
bring it back. A branch is not the only place work can be kept safe, and code on
a branch is read as a decision.

### A null result deserves an instrument a person can look at

A headless script that reports "no effect" is the hardest result to act on: it
is indistinguishable between a working measurement of a dead system and a broken
measurement of a live one. The cheapest way to tell them apart is usually to
build the thing that shows the phenomenon to a human, side by side with the same
number the script computes — then the operator's eye and the metric are checking
each other, and a disagreement between them localises the fault to the
instrument.

☠️ **And two instruments agreeing on nothing is not evidence of nothing.** The
mirror of "two instruments that disagree is worth more than either reading
alone", and it is the more dangerous half, because agreement feels like
confirmation. Measured 2026-08-25: a test asked whether an incoming call raises
a suspended phone. Both instruments chosen in advance came back empty — one
counter read `+0` everywhere, one query answered "none found" — and the call had
worked perfectly. The counter does not observe this class of event at all (it
advances only on an explicit userspace-visible wakeup call, and the path in
question does not use one); the query ran one second before the object it was
looking for existed. Neither was measuring the thing, and their agreement
measured nothing twice.

Only knowing independently *when the call was placed* prevented it being written
up as a clean negative. So: **before a null result is believed, each instrument
has to be shown positive on a case known to be true** — separately, not as a
set. And when a null is reported, say which instruments produced it, so the next
reader can ask what each of them can actually see. A timeline the run did not
choose in advance — here, the system journal — is often the thing that settles
it, which is an argument for capturing more than the instruments you designed.

This is not a fallback for when the script fails; it is worth building before
believing a null. `scripts/focus-view.py` is the pattern: a viewfinder that owns
the device, drives the control from a slider, prints the *same* sharpness metric
the sweep uses, and zooms — and the effect the sweep had declared absent was
plainly visible in it at 8×, because the phenomenon lived in detail that a
scaled-down preview throws away. Two properties made it work and are the
transferable part: **the instrument owns the whole path**, so nothing else can
touch the device while it runs, and **it displays the metric, not just the
phenomenon**, so a human observation and a machine number can be compared
directly rather than through memory.
  Either way, prove it against a **known positive**: a tool that reports "clean"
  has demonstrated nothing until it has been seen failing on a case you know is
  broken. (Measured, and the reason this paragraph exists: a provenance script
  written for exactly this purpose reported a clean module tree on its first run
  while two `.ko.bak` files sat in it — an unexpanded `$(uname -r)` had sent
  `find` down a path that does not exist, and "no output" read as "nothing
  found". It was then deleted, because `--only` already covered it.)

The standing instrument for all four is the selftest, not a script here:

```sh
fp3-pmaports/tests/fp3-selftest --only identity,dtb,modules
```

Kernel, device tree and module tree in one run — for each, does the file on the
device trace to the installed package or was it put there by hand, and which
port layers does the live tree actually describe? Run it **before** trusting a
measurement, not after the result confuses you. The full statement of these
rules, with the case that produced them, is in `fp3-kernel-test` under
"Say it unprompted".

The whole approach rests on **differential measurement**: measure the same layer on
the oracle and on the port, and let the *delta* localise the fault. Each technique
below is one layer you can diff. The art is choosing the layer that will *split*
your remaining hypotheses in half.

1. **Dual-slot A/B is the enabling trick.** Oracle on `slot_a`, port on `slot_b`,
   switch with `fastboot set_active a|b`. This gives a working reference and a test
   bed on one disposable phone with **zero-risk rollback** — you can break `slot_b`
   arbitrarily and always return to a working phone. It is also your reset:
   `set_active` clears a slot's unbootable/retry state.

1b. **The oracle is a reference for CONFIGURATION, not only for signal — use it to
   validate a register layout you reverse-engineered from the vendor source.** When
   the port has to program a block the vendor also programs, boot the oracle and read
   *those same registers back*. Agreement byte-for-byte confirms the encoding, the
   byte order and the value domain in one read, far more cheaply than re-reading the
   source; a disagreement is a bug in your port, and it will be in the value you were
   least sure about. (Worked example: the FP3's four JEITA comparator thresholds —
   three matched what we had derived from `smb5-lib.c`, which validated the
   big-endian hot-then-cold layout, and the fourth did not, which is how a wrong
   device-tree threshold was found. `/sys/kernel/debug/pmic-votable/*/status` on the
   oracle then said *why* the stock system settles where it does, per voter.)
   ☠️ Before framing any such difference as "the two sides disagree", check that
   **both sides are actually measuring**: a value hardcoded in your device tree is a
   previous session's *assumption*, not a measurement, however numeric it looks.

2. **Capture the golden sequence when you can't probe the oracle live.** The oracle
   often lacks the debug node you want, so capture its working handshake once into
   files and diff against those (`scripts/ut-capture-framer.sh` grabs the
   relevant ipc_logging + dmesg). Reading an ipc_logging buffer *drains* it, so
   drain at T0 for a clean delta. Save the golden captures — re-capturing costs a
   reboot, and they encode the target *timing* as well as content.

3. **Register-level truth beats log-reading.** Logs report what software *believes*;
   MMIO reports what the hardware *is*. Read the block's control/status/interrupt
   registers via `/dev/mem` (`scripts/regdump_pmos.py`) and compare write vs
   read-back: a write that doesn't latch means the block is unclocked/inactive
   regardless of what the driver logged. **Safety:** reading a clock-gated block
   hangs the bus (→ dump-mode `900e` → power-cycle) — read a block only while its
   clock is on (e.g. during `aplay`). Use a Python `mmap` reader; `dd`/`devmem` can
   silently return empty on a hardened kernel, which masquerades as "reads 0".
   **Localising software-vs-physical: capture the co-processor's own *write* on both
   sides.** When the AP is exonerated and the fault is co-processor-internal, the
   decisive split is whether a given hardware action (a clock-branch enable, a register
   program) *executes* on the dead side. Cave-capture the actual store (target + value +
   caller) during the working *and* dead bring-up (SSR-reload makes the dead-side capture
   cheap — see `fp3-kernel-test`). If the enable write is **byte-identical** working↔dead
   (same target, same value, same caller) yet the block still doesn't come alive on the
   dead side, the divergence is **physical realisation** (the branch bit is set but the
   parent/source clock doesn't supply — parent RCG root / source PLL not locked), *not* a
   software/dispatch difference — which redirects the search upstream to the parent clock,
   not to the enable path. (Worked example: the SLIMbus framer-branch enable
   `memw(0xee012014)|=1` fired identically on both slots from the same dispatcher, so the
   wall was localised to the parent clock source, not the enable logic.)
   **The Linux subsystem model routinely reports "healthy" while the pad/pin is dead —
   cross-check the framework's own debugfs for the PHYSICAL state, not just the driver's
   counters.** A clock can show `clk_enable_count=1` at the right rate and the codec can
   read `MCLK_EN` set, yet no clock reaches the pin because the PMIC-gpio pinmux was never
   applied: `/sys/kernel/debug/pinctrl/*/pinmux-pins` shows `(MUX UNCLAIMED)` and the pad
   sits in its reset function. Likewise the *active audio path* is ground-truthed from the
   powered DAPM widgets (`/sys/kernel/debug/asoc/<card>/<codec>/dapm/*` lines reading
   `: On`), which tells you which interpolator/mixer — hence which mixer control — is
   actually in the signal path, rather than guessing from control names. (Worked example
   folyt.208: the WCD9335 MCLK looked enabled at every software layer but `pinmux-pins`
   proved `func1` UNCLAIMED — the real fix; and the DAPM `On` set showed the headphone
   ran through the interpolator SECONDARY/MIX branch, so `RX1/RX2 Mix Digital Volume` was
   the working loudness control while the main-path `RX Digital Volume` did nothing.)

   ☠️☠️ **But `pinmux-pins` is only ground truth in ONE direction — it proves a pad was
   never claimed, never that the pad is still yours.** The pinctrl framework's "current
   state" is **bookkeeping, not hardware**: it records what Linux last asked for. A
   co-processor (ADSP, modem, TZ) can rewrite TLMM behind its back at any time, and
   `pinmux-pins` will go on reporting the pin as claimed, in the right function, forever.
   Measured here: firmware on the audio DSP reset an i2c pin pair to power-on defaults
   once, about 8 s after the modem came up; the amplifier on that bus then looked exactly
   like a dead chip. **The register-reading instruments are the truth** —
   `/sys/kernel/debug/gpio`, or `/dev/mem`. This is the same class as a regmap cache with
   no `volatile_reg`: **two instruments that read through one layer are one instrument.**

   Three corollaries from that hunt, all transferable:

   - **"Every address NAKs, including one that does not exist" acquits the CONTROLLER, not
     the pads.** A bus pad that has been muxed away produces precisely the dead-chip
     signature, so that test cannot distinguish the two.
   - **Invariant timing anchored to boot is not necessarily a kernel timer.** Here it was a
     co-processor init chain — modem-up plus a fixed delta. The decisive experiment was
     restarting each remoteproc while watching the pads: modem → nothing, audio DSP →
     trampled ~1.7 s later.
   - **When the downstream oracle "just works", ask what it re-applies.** Its i2c driver
     re-applied the active pinctrl state on *every transfer*, which is why the hardware
     looked fine there; the mainline driver applies it once, leaving the device tree's
     sleep state as dead configuration. ☠️ The fix has to *alternate* states — the pinctrl
     core no-ops a request for the state already recorded, which is the same bookkeeping
     trap arriving a second time.

   **When a path is fully powered yet produces exact zeros, look for two board-level fault
   classes before suspecting the far side.** Exact zeros — not noise, not garbage — mean a
   digital source of silence, and on this hardware it was never the co-processor:
   - **A clamp asserted at power-up that nobody releases.** `wcd9335_codec_enable_adc()`
     asserts the TX front-end hold in `PRE_PMU`, and mainline never calls it with `false`
     (downstream releases it from a 300 ms delayed work). Grep the driver for every
     enable/disable *pair* — a helper called only ever with `true` is the smell. ⚠️ Where you
     release it matters: DAPM powers **mux widgets before ADC widgets**, so releasing from
     the decimator's `POST_PMU` is undone immediately by the ADC's own `PRE_PMU`. The live
     register is the arbiter (`0613 = 0x40` meant still clamped).
   - **A supply or source the codec expects the BOARD to wire.** Widgets with no in-codec
     route are dead ends until the DT connects them: `MCLK` (wire it to every path that needs
     it — routing it only through `RX_BIAS` left capture unclocked, so recording worked *only
     while playback happened to be running*), `MIC BIAS<n>`, and the DMICs. Note a DMIC widget
     is an **ADC, not an input**: DAPM will not power it from a supply alone, it needs a source
     endpoint behind it (`"DMIC0", "Digital Mic0"`). Downstream expresses this as the reverse
     `"MIC BIAS<n>" -> "<name> Mic"` pair, which modern ASoC rejects ("Connecting non-supply
     widget to supply widget"), so translate it rather than copying it.

   **And board parameters the driver merely guesses.** Mainline wcd9335 had no mic-bias voltage
   support at all (1.8 V power-on default where the board wants 2.8 V) and derived the DMIC
   clock from MCLK alone (4.8 MHz where the capsules want 2.4 MHz, so they returned silence).
   Both are DT properties downstream sets and mainline never read. When a device is quiet
   rather than broken, diff the downstream DT for `qcom,*` properties nobody parses upstream.

   **Discriminating transport from payload without the far side:** sample the SLIMbus master's
   per-pipe counters in the AP-visible aperture (`/dev/mem` at the LPASS alias) twice a second
   apart. They stand still at idle and advance at the same rate for playback and capture when
   data really flows — which proved the bus was carrying the capture channel and moved the
   search back into the codec, correcting an earlier conclusion that the ADSP was at fault.
   **To close "is there ANY divergent register in this block" exhaustively (not by sampling),
   pair writer-enumeration with a full-aperture two-sided resting diff — and neither needs the
   device if you already have both dumps.** (a) *Enumerate every writer* of the block from the
   firmware: grep the disasm for all callsites of the register-write HAL primitive(s) (`call
   0x<write_hal>` resolves PC-relative in llvm-objdump, so it greps directly). ⚠️ a block usually has
   *more than one* write path (a dedicated HAL + inline `memw(base+off)=val` + sibling primitives) —
   "only N writers" holds only for the one HAL; check each writer's base is the same ctx-mapped base.
   (b) *Diff the WHOLE aperture two-sided, word by word* (not chosen offsets) from the existing dumps:
   however many writers exist, if every resting word matches except known markers/downstream, there is
   no static register lever. ☠️ **A resting diff cannot exclude a self-clearing trigger pulse** (write
   set → HW clears → both sides read the cleared value identically) — if the exhaustive diff is
   negative, the *only* remaining software hypothesis is a self-clearing pulse, resolvable **only by a
   live two-sided capture** (it leaves no resting trace); say so explicitly, or "all registers match"
   masquerades as a full software closure. The firmware's **HW-descriptor** authoritatively bounds how
   many MMIO blocks the fw even knows about (a raw word-scan of the coredump is too noisy — heap
   pointers alias into the MMIO range). (Worked example, folyt.155-156: the framer's only write-HAL had
   4 callsites in 2 functions, all byte-identical two-sided; the full 176 KB aperture diff = exactly 10
   differing words, all STATUS markers or downstream-NGD; the fw HW-desc maps only framer+BAM → no
   third block → the whole register/firmware-software line closed with no device round-trip.)

4. **Prove firmware/config identity before blaming firmware code.** From a booted
   port, mount the *other* slot's firmware partitions read-only and `cmp` them (real
   byte diff, not a hash the reviewer won't trust). If the co-processor firmware is
   byte-identical across the working and broken OS, the difference is
   *environmental* (how the AP brings it up / the clock+bus environment it sees),
   not the firmware — a single result that reframes the search. (The QDSP6 `adsp.mbn`
   is an unencrypted ELF32; disassembly/patching details are in `fp3-kernel-test`.)

5. **Census the messaging layer — and do the TWO-SIDED inventory first.** Downstream/UT:
   `cat /sys/kernel/debug/msm_ipc_router/dump_servers`; mainline: `qrtr-lookup` (or
   `scripts/qrtr_lookup.py`). Two commands, and the diff of the two lists localises a missing
   co-processor service by itself, before you debug message *content*.
   ☠️ **The instance field is PACKED (`version | instance << 8`)** and the two tools print raw
   vs decoded columns differently, so an undecoded comparison is meaningless: raw `0x3201`
   means *version 1, instance 50*.
   ☠️☠️ **Confirm on the oracle that an endpoint is the RIGHT one before reverse-engineering
   its protocol.** (Worked example 07-28, and it cost a night: a QRTR port that echoed every
   byte sequence back verbatim looked like a broken/stub service worth reverse-engineering —
   until the oracle's inventory showed the *functional* Sensor Manager lives on a different
   node with a different instance, and that the echoing port behaves identically on the
   working system. The measurement was sound; the target was not. Two corollaries: a
   **content-independent echo** — 16 zero bytes returned verbatim — means no parser is
   involved, so it is a wrong/stub endpoint rather than a framing problem; and the control
   that proves it is sending the same message to the **neighbouring ports on the same node**,
   which answer with proper QMI errors.) **When you census device dependencies, read the link
   *status/value*, not the mere presence of a node — the presence of a
   `waiting_for_supplier` attribute is not an active block.** (Worked example, folyt.148: the
   codec slim device showed a `waiting_for_supplier` node that looked like a stuck supplier, but
   `cat waiting_for_supplier`=0 and every `supplier:*/status`=`available` → fw_devlink was *not*
   blocking; the boot-time `Failed to create device link … wcd-mclk` was a red herring. Read the
   value/status, never infer blockage from the node existing.)
   **The co-processor's audio services ride TWO separate transports — census BOTH, or a
   "nothing before SLIM" read from one is misleading.** SLIMbus goes over QMI/IPC-router (SvcId
   0x301, `kqmi_req_resp` ipc_logging); AFE/ADM/ASM/q6core go over **APR** (Audio Packet Router,
   its own smd/glink edge — `apr` ipc_logging on downstream, or the **aprbus** on mainline). Both
   the APR/Q6 stack come up *before* the framer on both stacks (worked: UT `apr_tal:Q6 Is Up`
   t=20.53 s before framer-enum t=20.65 s; pmOS `qcom,apr Adding … dev` t=13.76 s before the NGD
   capability-wait t=14.25 s), so a QMI-only view falsely reads "SLIM is first, nothing before it."
   **And the aprbus bind-census is a cheap, DECISIVE *positive* liveness proof that the ADSP audio-PD
   is alive — no F3/DIAG needed:** if the q6 drivers are BOUND to their service devices
   (`ls /sys/bus/aprbus/drivers/qcom-q6core/` contains `aprsvc:service:4:3`), their `.probe()`
   succeeded — q6core did an AVS-version query, q6afe registered LPASS clocks (`clk_summary`:
   `LPASS_CLK_ID_*_MCLK`) → the ADSP genuinely *responds* on APR. (Worked example, folyt.184: all 7
   q6 drivers bound + `card0` created + LPASS clocks registered, yet the SLIMbus NGD still timed out
   → the fault is *narrowly* the framer behind a WORKING ADSP-audio path; "missing APR/AFE bootstrap"
   positively excluded. Note this is a positive signal, not absence-of-evidence.)

6. **When the live-trigger vehicle is blocked, diff the STEADY STATE the event left
   behind — don't downgrade to source-reading.** You often want to compare a *boot-time*
   handshake but can't re-run it live (no SSR-trigger node on the oracle, cold-boot-on-demand
   too costly/risky). The disciplined fallback is **not** a source diff — it's to read the
   **resting state the event deposits**: the block's registers *now* (two-sided `/dev/mem`),
   and any *persistent* votes/clients (`msm-bus-dbg/client-data/*`, `interconnect_summary`).
   Still a live, two-sided, register-level differential, at lower risk than forcing a
   restart or flash. (Worked example: with no ADSP-SSR trigger available on the UT oracle,
   diffing the *resting* QDSP6SS register block oracle-vs-port surfaced the single differing
   word a source diff had missed — the steady-state diff was the vehicle that finally cracked
   a months-old frame. **Caveat:** a resting register can be an OUTPUT the co-processor wrote,
   not an input you can set — apply the marker-vs-lever test in `fp3-kernel-test` before
   calling it a fix.) **But first check for a runtime-PM re-trigger — it may un-block the live
   vehicle entirely.** Before settling for the steady-state fallback, look for the driver's
   `power/control` node: if runtime-PM is *supported*, `echo auto`+idle / `echo on` cycles the
   co-processor's power-request down/up at runtime, re-running a "boot-time-once" bring-up with no
   reboot. That turns the boot handshake into a live, repeatable, fully-instrumentable event on the
   working slot (ftrace/`/dev/mem`/fw-cave the transition). See the runtime-PM instrument in
   `fp3-kernel-test`. (Worked example: the SLIMbus framer, long treated as ADSP-boot-only, cycles
   `FRM_STAT` on the NGD `c140000.slim` runtime-PM node — the steady-state diff was not even needed
   once the live re-trigger was found.)

7. **When you need the co-processor's *whole* memory, not a sampled register — take a coredump, don't
   build a bigger cave.** A firmware cave exfiltrates through the one tiny proven-safe SMEM window (~tens
   of bytes per SSR cycle), which is fine for a targeted value but hopeless for breadth — e.g. chasing a
   multi-level runtime **heap pointer graph** (parent struct → sub-object → the register base you're
   after). The right tool is the kernel's **remoteproc devcoredump**: it dumps the co-processor's entire
   runtime memory to an **ELF** you pull once and analyse offline, unlimited. It is also the *only safe*
   way to read the firewalled carveout (an AP `/dev/mem` read of it wedges the device — see the
   "never read an unverified physical address" rule in `fp3-kernel-test/references/safety.md`;
   the coredump goes through the driver's mapping). Recipe + gotchas (the `crash` debugfs
   trigger, `stat`=0-but-read-is-full, full-dump-vs-SMEM-minidump size check, VA→PA→file-offset resolving)
   are in the coredump instrument in `fp3-kernel-test`. Offline, `scripts/coredump_resolve.py` resolves an
   ADSP virtual address into the dump, and `scripts/make_disasm_elf.py` wraps a raw Hexagon code blob into
   an objdump-able ELF (real addresses + packet grouping). (Worked example: FRS7/8 caves proved the SLIMbus
   framer ctx reaches its clock/pad only *indirectly* via runtime-heap parent pointers — a chase the
   8-word-per-cycle cave could barely start, and the 16.98 MB coredump made a one-shot offline traversal.)
   **Still prefer the cave for a live value at a specific code point** or a two-sided both-sides-anchor
   capture; the coredump is one side's snapshot at the crash instant. Breadth → coredump; targeted instant → cave.

8. **The board's truth is the stock DTB — a vendor `*.conf` is a template.** Files under
   `/vendor/etc/**` routinely carry the parameter tables of *many* board variants one after
   another, with nothing marking which one is yours. (Worked example 07-28: a sensor I2C
   pin pair read out of `sensor_def_qcomdev.conf` sent a whole night's work at the wrong
   pins — the board's own DTS said those pads are the fingerprint reader's SPI.) Extract the
   real thing instead, entirely read-only and in a few minutes: the **dtbo** partition is an
   Android DTBO table (magic `d7b7ab1e`; header gives entry count/size/offset), and a
   header-v0 boot image carries its DTBs **appended to the kernel** — scan that region for
   `d00dfeed` and pull each blob out. Decompile with the kernel tree's own `scripts/dtc`
   (`make dtbs` builds it) when the host has no `dtc`. **A subsystem with no node at all in
   the stock DT is itself a strong finding:** it means the AP kernel does not drive that
   subsystem — on this device the sensors turned out to be handled entirely by the ADSP,
   which is why no amount of DT archaeology on the AP side was ever going to find a bus.

9. **Indirect exclusions saturate — change instrument, not hypothesis.** A run of cheap
   indirect tests (is it a boot race? is the config different? is the firmware different? is
   the rail powered?) is the right way to start, but each one only *removes* a candidate. If
   two or three in a row still leave "it never started" and "it started and failed"
   indistinguishable, stop generating hypotheses and go get a **direct observation** of the
   thing itself (co-processor diag/QDSS, a cave, a coredump). (Worked example 07-28: five
   indirect exclusions in one session — SSR/boot-race, devcfg identity, a separate PD image,
   the PD registry, the sensor supply rails — none of which could split those two branches.)

**How these chain:** a typical localisation walks *down* the stack — enumeration
(is the device seen?) → messaging (are requests answered?) → registers (did the HW
act?) → firmware identity (is the code the same?) → firmware internals (what did it
decide?). Each rung either exonerates a layer or points into it. Spend your next
measurement on the rung that eliminates the most remaining hypotheses.

### The vendor device tree is ground truth about the board — read it by class, not by SoC

A downstream device tree describes the *board*, and it is often the only
statement anywhere about how a peripheral is physically wired. It is also the
cheapest oracle available: no build, no flash, just a file.

☠️ It usually carries **several configurations for the same SoC**, and taking the
wrong one silently mis-describes the hardware. Identify the right one by a
property only your variant has — the codec it names, the bus it hangs off — not
by the SoC. On one occasion the same file held two settings of the same jack
property, differing between boards with a PMIC-internal codec and boards with an
external codec on a specific MI2S port; only the second describes this phone,
and the two are opposites.

**And check whether upstream has any reference at all before assuming a
baseline.** A mainline board file can predate the subsystem you are working on
entirely: if the pre-port device tree never described the peripheral, there is
no upstream value to compare against, every setting is this port's invention,
and the vendor tree is the only authority left. Finding *that* out is itself a
result — it tells you which decisions have never been checked by anyone.

Correcting the description to match the vendor tree is worth doing on its own
terms. It is not, by itself, evidence that anything was fixed: verify the change
reaches the hardware (read the register back), then measure the behaviour
separately, and record the two conclusions apart. A plausible change credited
with a repair it did not make sends the next investigation the wrong way.

### When the register map is in no kernel at all — read the vendor's userspace blob

Some vendor stacks deliberately keep a peripheral's register map **out of the
kernel**. Qualcomm's camera stack is the clearest case: the downstream device
tree node for a lens actuator is a bare `compatible` plus a bus index — no slave
address, no registers — and the in-kernel driver is a *generic engine* that is
fed the map from userspace over an ioctl at runtime.

☠️ **The consequence is a misleading absence.** Grepping the entire downstream
kernel for the part number returns nothing, or a single unrelated coincidence in
some other subsystem. That reads as "this hardware was never supported", which
is the opposite of the truth. Before concluding a peripheral is undocumented,
ask *where this vendor's stack keeps that class of data* — if the kernel driver
takes its configuration from userspace, the kernel was never going to have it.

Where to look: the board's own Android vendor partition, which is already on
disk if the device has ever been imaged for a port. The libraries are named by
class and part, so the whole field is one listing:

```sh
find <vendor>/proprietary -iname '*<class>*'    # e.g. *actuator*, *eeprom*
```

The map is a C structure in the library's `.data` section. Reading it means
**asserting a struct layout**, and an asserted layout produces confident,
plausible, wrong numbers — every field is a small integer, so nothing looks
out of place when the offsets are off by one field.

☠️ **Validate the layout with a known-answer control before believing a single
value.** Vendor trees ship a library per part, so pick a *sibling* part that
already has an upstream driver, run the identical decode on it, and check the
result field for field against that driver's source. If the control does not
reproduce what mainline already states, the layout is wrong and every number
read from the target is fiction. A second, independent check is stronger still:
a part whose power-up sequence is documented should have that sequence come back
out of the decode verbatim. Two known answers reproduced is enough; one is
suggestive.

The same vendor tree holds a second kind of ground truth: **the board vendor's
own edits to the generic kernel driver.** Those carry facts that appear in no
datasheet — a polarity inversion, a per-board clamp, a delay — usually guarded
by a check naming the parts they do *not* apply to, so read the condition
carefully to work out whether your part is inside or outside it.

## Web docs & community repos (what's actually usable, and how to reach them)
- **postmarketOS** wiki device page + `pmaports` — primary reference for the native
  track (HW configs, firmware names, kernel patches).
- **msm8953-mainline/linux** — upstream kernel + issue tracker (the SLIMbus framer
  discussion is issue #255). z3ntu's FP3 work.
- **qcom-ngd-ctrl race-fix** (Bjorn Andersson, patchwork series **1075549**, 7
  patches) — fixes the schedule_work-on-uninit crash when the NGD probes after the
  co-processor is already up (the PAS-boot case); in-tree, necessary-not-sufficient.
  **Reach method:** lore.kernel.org is bot-gated (WebFetch gets a challenge) → use
  the **patchwork.kernel.org JSON API** (`/api/series/<id>/`, `/series/<id>/mbox/`).
- **LineageOS** `android_kernel_fairphone_sdm632` + the **UT/halium FP3 kernel**
  (gitlab ubports community-ports) — read the *downstream* driver/DT source to learn
  "what does the working stack actually send/do". **Method reminder:** confirm which
  tree/branch actually built the oracle image before trusting its source to explain
  a wire capture — sibling trees differ. (Worked example: three msm-4.9 trees,
  incl. the oracle's own, all encoded the same SLIMbus QMI field-set, which
  disproved a "missing field" theory drawn from a wire length-delta.)
- **luksus42** Halium-9 FP3 (kernel/device/vendor) — MSM8953 HW mapping is largely
  stable across Android versions; reuse hw-config values instead of guessing.
- **TheMuppets** vendor blobs (git-lfs); **mlehtima/droid-config-fp3** (Sailfish HW
  settings); **mer-hybris/hadk-faq** + HADK PDF (hybris rules).
- **Lean on community repos; record provenance in `references/archive/sailfish-components.md`** so the port
  stays reproducible and shareable.
- **The q6afe / APR audio-clock path** — the upstream `apq8016_sbc` **msm8953/msm8976** ASoC series
  (on `mail-archive.com` / `lore`; the `q6afe` MI2S-sysclk series is `v5/v6 12/24`) documents that the
  SoC's key differentiator is the **Q6AFE CLK API version** (msm8953 = V2, `Q6AFE_LPASS_CLK_ID_*` via
  `q6afe-clocks`). This is the reference for the "request the framer/codec clock over APR, not as an AP
  register" lead — see the UNTESTED q6afe/APR lever in `fp3-kernel-test`. Reach method: these are older
  list posts, so `mail-archive.com` / `lore` HTML is usually fetchable directly (no patchwork API needed).
- **The one external artifact that would settle the framer trigger is a BSP-side diag capture — this is a
  live avenue, don't re-derive it.** The AP side is exhausted; what would answer "what actually triggers
  ADSP framer startup" is a **QXDM/QDSP `.dci` diag capture of a successful SLIMbus init from a stock
  boot**, obtainable only by someone with SDM632 BSP access. This is being pursued externally (Fairphone
  community forum thread "one BSP-side pointer needed…", a filed Fairphone support ticket, and the pmOS
  company-relationship channel). Treat it as an in-flight "unavailable = a cost with a price" item (below),
  not a closed door; check its status before assuming the pointer is unobtainable.

## Debugging techniques (the how, and why each works)

- **Boot-blind triage — establish a channel before you need it.** When USB/console
  is dead you cannot see panics, so pre-wire an out-of-band log: pstore/ramoops is
  the most reliable; a raw-eMMC log partition survives reboots; SD works but probes
  *asynchronously* (wait for the node before logging to it); fbcon shows panics
  on-screen. Also watch the **A/B retry counter** — it can exhaust and flip you to
  the other slot mid-debug; `set_active` resets it.

- **One change per run + never block boot.** A measurement localises a fault only
  if one variable moved (batching two edits makes a pass/fail uninterpretable), and
  a headless device must never run code that can hang the boot thread (no unbounded
  `wait_for_completion`/retry loop — that bricked the test slot once). Prove the
  change *ran* with a `DBG` breadcrumb before trusting a null result — otherwise you
  can't tell "hypothesis wrong" from "code didn't execute".

- **"Unavailable" is a cost, not a verdict.** A missing tool/node/interface never
  *closes* an avenue — it converts it into a change-requiring task with a price.
  Method: name the change *and its order-of-magnitude effort*, then **rank** it
  against alternatives rather than writing it off. Rough ladder: **minutes** =
  sysctl/mount/config flag; **hours** = a small out-of-tree module or a
  firmware-inject SMEM tracer (+ rebuild/reflash); **days–weeks** = porting a large
  downstream driver onto a different mainline subsystem. Only an *absent hardware
  block* is a true exclusion; a missing *software surface* is merely unbuilt.

- **Golden A/B diff — the central move.** Capture the same layer (QMI, clocks,
  registers, ipc_logging) on oracle and port, diff. This is how a whole side of a
  problem gets *exonerated* at once. (Worked example: diffing QMI payloads, BAM
  pipes, and NGD registers showed the SLIMbus AP side byte-for-byte matching the
  oracle — narrowing the fault to the co-processor internals.)

- **A fault that depends on a *parameter* reads as intermittent — find the
  selector before you believe the word.** "Sometimes it works" is a description of
  a distribution, not of a mechanism, and it sends you looking for timing, settle
  and races. Before accepting it, ask **what differs between the runs that work and
  the runs that do not** — a mode, a resolution, a link frequency, a size, a
  temperature. A parameter-selected fault is fully deterministic once the selector
  is named, and the selector is usually visible in the code path that maps the
  parameter to a resource (a frequency table, a mux table, a quirk list). Two runs
  of the same command are the *worst* experiment here: vary the parameter instead.
  (Worked example: a camera clock that failed for some sensor modes and worked for
  others, because the driver picked a different table entry from the sensor's link
  frequency and only one entry's source was broken. Everyone before had called it a
  settle problem and retried harder.)

- **A one-line table value is a hypothesis you can test without hardware:
  compare it against its siblings.** Mux selects, register offsets, bit widths and
  frequency tables come in families; a value that disagrees with every other member
  of its family in the same file is a typo candidate, and finding it costs one
  `grep`. Do this *before* any measurement — it either hands you the answer or
  costs a minute. (Worked example: three RCGs claimed a parent at a source select
  no other mux in the same block used; every other camera mux in the file used a
  different number.)

- **Register proof over log-reading.** A dmesg "OK" can coexist with silent
  hardware. (Worked example: `/dev/mem` showed the RX pipe armed but its event
  register never advancing = the framer writes nothing = the bus is unclocked — a
  fact no log gave.)

- **SSR-reload as the ~2 s firmware-iteration path.** `echo stop/start >
  …/remoteproc2/state` makes remoteproc re-`request_firmware` (picking up a swapped
  firmware file) and re-init the co-processor with no reboot — the fast loop for
  firmware experiments. (Details + the do-it-in-one-command caveat in
  `fp3-kernel-test`.)

- **Firmware RE when the AP is exonerated.** Byte-compare firmware across slots,
  then disassemble the QDSP6 image to find the *decision* (which config-offset the
  code branches on, which function gates the behavior). Combine with the
  entry-trace and SMEM-exfil patterns (in `fp3-kernel-test`) to measure whether a
  given firmware path even runs.

- **"What does the bring-up code *examine*?" is a localising question — and a
  firmware-wide scan can answer it offline.** When the fault is a same-firmware,
  different-outcome puzzle (identical code, identical AP, identical boot chain, yet
  it works on one OS and not the other), a productive move is to disassemble the
  whole bring-up call-chain and ask what environmental *inputs* it reads and branches
  on. A decisive negative is possible: if the bring-up path reads **no hardware
  register at all** (every absolute value is a rodata string ptr, a PC-relative
  branch displacement, a negative struct offset, or a DAL/device-id constant — see
  the filtering rules in `fp3-kernel-test`), then the differing datum is *not in a
  code branch* the firmware examines — it is in the **realization layer the code
  delegates to** (an RPM vote, an MMPM/HWIO clock leaf with a runtime-mapped base, a
  PLL it enables blindly). That redirects the search from "find the branch" to "read
  the physical result / the `.bss` input the leaf consumes" — and justifies the
  (expensive) leaf entry-trace instead of more source-diffing. (Worked example: the
  SLIMbus framer bring-up examines only devcfg config + NPA software state, zero
  MMIO; its 24.576 MHz clock is `LPAPLL1`, realized by a register HAL with a
  runtime base — so the environmental delta lives at the leaf, not in the bring-up.)

- **Navigating a QDSP6 image statically: string/immediate `grep` lies — use the immext
  high-part + the MSG descriptor.** Three quirks defeat naive xref, and each has a fix.
  (1) `llvm-objdump` renders high code/data addresses as **negatives** — a load of `0xf072a378`
  prints `r2 = ##-0xf8d5c88`, so grepping the positive VA finds nothing. (2) Constants are
  **constant-extended**: the real reference is an `immext(#HIGH)` (bits [31:6]) packeted with a
  transfer carrying the low 6 bits — so grep the *aligned* high part (`immext(#0xf072a340)`),
  not the exact address. (3) Log strings are reached through a **micro-MSG descriptor**
  `{fmt_string_ptr, msg_id, argcount}` embedded in the *text* segment, and the code loads the
  *descriptor* address (via immext-high), not the string. So to find the function that logs a
  known string: byte-search the image for the 4-byte LE pointer **to** that string → that hit is
  the descriptor VA → grep the disasm for `immext(#<descriptor_high>)` → the surrounding packet is
  the log call site inside the target function. (Worked example: the SLIMbus framer master
  reconfiguration-builder was located at `0xf04cc054–0xf04ccf80` this way, from the "Skipping
  transmission of empty reconfiguration" string in `SlimBusMaster.c`, after string/immediate grep
  returned zero.) **But note the ceiling:** once located, the bring-up's *decision inputs* are
  runtime-resolved struct fields (device-ctx `r16+0xNNN`, per-channel objects), not immediates — so
  static disasm gives you the *decision site*, never the differing *value*. And a stage with **no
  log string and a runtime-mapped MMIO base** (e.g. the framer's actual start-framing / superframe
  enable) has *no static anchor at all*. Both facts push the same way: static RE localises **where**
  to cave; the two-sided *value* still needs a runtime capture. Don't keep source-diffing past this.

- **To read the realization layer, splice the clock's own enable-method and capture the
  register base — then diff the *right* register at the *right* time.** When the delta is at
  the leaf (above), the winning move is a runtime-capture cave *inside* the clock's enable-method
  (find it via the static clock registry: name→ID→ops-vtable→enable-method). It hands you the
  live **register base** (`memw(handle+0)`, a real MMIO addr) plus the handle layout (base,
  registry-entry ptr, ops-vtable, and a second MMIO ptr = the branch CBCR). Full recipe +
  handle offsets + filter-by-registry-entry-pointer in `fp3-kernel-test`. **Two discipline points
  this surfaced:** (1) the RCGR (rate generator) was programmed *byte-identically* working vs
  dead (same src-sel/div) — the rate is not the fault; the **branch clock (CBCR)** enable/off-status
  is the gate, and a mid-enable snapshot of the RCGR's ROOT_OFF bit is a *transient the oracle also
  shows*. (2) The UT oracle control caught this — the identical read on the working side killed a
  premature "the clock root never turns on" localization. Read the CBCR at steady state, two-sided.)

- **Close the RPM/realization alternative on the oracle before assuming
  "co-processor-internal".** If the firmware delegates clock realization (above),
  check whether the difference is an *AP-cast RPM vote* the two kernels emit
  differently: on the downstream oracle read `rpm_master_stats` (per-master
  sleep/vote state — confirms the co-processor master is even live in RPM) and the
  per-resource votes; on mainline the same info is spread across
  `clk_summary` + the `remoteproc:…rpm-requests:regulators-*` debugfs + `pm_genpd`.
  ☠️ The two representations don't line up (a downstream `rpm_stats` vs a mainline
  `clk_summary` is the soft cross-abstraction compare) — treat a match/mismatch as
  *suggestive*, and when a candidate RPM clock differs, **check the journal for
  whether force-enabling it was already tested** before re-deriving it. (Worked
  example: `bb_clk1` is the one AP-visible RPM-clock delta oracle-vs-port and the DT
  even names it the SLIMbus "slimbus_ref"/codec "slimbus" clock — but force-enabling
  it on the port was already proven not to bring up the framer; it's the codec's
  reference, a different clock from the ADSP-internal LPAPLL1 framer clock.)

- **Boot-mechanism comparison from source.** When two OSes boot the same
  co-processor differently, read both boot paths side by side (here `subsys-pil-tz.c`
  vs `qcom_q6v5_pas.c`) and line up the SCM sequence, clocks, regulators, carveout,
  and handshake to find or rule out a divergent step. (Result here: functionally
  equivalent → no discrete AP-side lever, which pushed the search into firmware.)

- **★★★ Search before you reverse-engineer — the most expensive lesson in this
  project.** A full day went into reverse-engineering a QMI protocol that already
  had a complete open implementation; the query that found it took thirty seconds
  (`SSC sensors mainline linux Qualcomm SMGR QMI postmarketOS proximity ADSP`).
  Before starting on any subsystem, spend ten minutes searching for the subsystem
  name plus the SoC family plus the distro — someone on a sibling SoC has usually
  done it. When you *do* find prior art, the **difference** between your
  measurements and theirs is the finding: here the measured service id, version
  and instance matched byte-for-byte, and the one thing measurement could not have
  produced — a message id — was exactly what had been missing.

- **☠️ Never reconstruct a protocol constant from memory — read the header.**
  Two independent "corrections" of a QRTR control code landed on two different
  wrong values (the enum starts at 1, so `NEW_SERVER = 4`, and we sent 3 = `BYE`),
  and each wrong value produced *reproducible, interesting* device behaviour that
  a week of theory got built on. A reproducible effect proves your action does
  something, never that it does what you named it. Transcribe constants into one
  file from the kernel uapi header and import it everywhere.

- **☠️ When one case works and one fails, ask which one is the accident.** An
  entire investigation asked "what is special about the proximity sensor that
  makes it fail", and the answer was: nothing. The *accelerometer* was the
  exception — it worked only because its sensor id happens to be 0, which masked
  a core bug that read a length field four bytes wide regardless of its declared
  width. The right question is often not "why does X fail" but "what keeps Y
  alive".

- **☠️ Check the consumer before fixing the producer.** Weeks of suspicion fell on
  the kernel while the actual blocker was that `iio-sensor-proxy` has no buffered
  proximity driver at all — it polls `in_proximity_raw`, so a buffer-only device
  was skipped in silence. `strings` on the consumer binary named both the sysfs
  attribute it wants and the udev property it needs, in one command, before any
  driver work.

- **☠️ Check the unit before you conclude from a number.** "The sensor sends one
  sample and stops" was produced by my own sweep sending a report rate in the
  wrong unit (the field is `sample_rate * 0xf000`, not Hz — three orders of
  magnitude, i.e. one report every two minutes), so the single indication was the
  *initial* one and the sweep measured nothing. In a parameter sweep, the first
  run must always be the **working code's exact parameters** as a control, and only
  then vary one dimension.

- **Ask the device what it supports before asking it for data.** One
  `SINGLE_SENSOR_INFO` call listed the part name, the vendor, the supported rates
  and — the thing that mattered — that this sensor has *two* data types where the
  working one has a single one. Free, instant, and it reframed the question.

- **☠️ Not every error line is a fault signal — check it in a known-good run.**
  `capability exchange timed-out` and `Failed to get logical address` appear in
  **every** boot of this device, including the ones where audio works perfectly;
  the retry right after them succeeds. Hours went into a message that was noise.
  Before building on a log line, grep for it in a run you know is healthy.

- **☠️ A debugfs counter's name is not its definition — read the code that
  prints it.** Concluding from a value whose meaning you assumed is the same
  mistake as trusting a log line, with a number's air of authority on top. A
  display encoder's status node printed `frame_done_cnt:0`, which reads as *no
  frame ever completed* and would mean the pipeline is wedged; the field is the
  **timeout** counter, so zero was the healthy value and the reading exonerated
  the layer it appeared to convict. One `grep` of the format string in the
  driver settles it: `grep -rn "<the literal label>" drivers/`.

- **☠️ Count what a log line *means*, not how often it appears.** A fallback
  latched once per session logs once per session, so a handful of lines can
  describe a decision that then governs every frame — and a per-frame line
  would be throttled anyway. Before reading a low count as a rare event, find
  where the flag is set and how long it lives. (Worked example: 69 lines of
  "DMABuf import failed, falling back to upload" across 69 camera sessions
  looked incidental; the flag is sticky, so it meant every frame of every
  session took the copy path.)

- **☠️ Anchor a journal correlation on the specific service, not on a phrase.**
  Grepping for a user action by its generic wording matches *your own* access:
  a search for the string a graphical login writes also matches every `sshd`
  login the investigation itself makes, so the window you extract is your own
  session and the event you wanted is not in it. Anchor on the PAM service or
  the unit (`greetd:session`, `systemd-logind ... class 'user' and type
  'wayland'`), and check the count before trusting the last match.

- **Ask the allocator what the hardware requires, instead of inferring it from
  a driver's complaint.** When a zero-copy import fails for an alignment or
  layout reason, the graphics stack can be interrogated directly and offline —
  `eglQueryDmaBufFormatsEXT` lists what the GPU will import at all, and a GBM
  allocation of the same format and width reports the stride it *chooses*,
  which is the constraint the importer applies because both go through the same
  layout code. Neither needs the device that is failing, nor the peripheral
  holding it. This is worth doing before any kernel change, for two reasons:
  it separates "the format is unsupported" from "the geometry is wrong", and
  the number it returns is the real requirement rather than what the consumer
  happened to ask for. (Worked example: a camera stack requested strides of
  2560 and 5120 and a driver granted 2400 and 5040, from which the requirement
  looked like 256-byte alignment; the GPU wanted **64**, so the padding needed
  was 32 and 16 bytes, not 160 and 80. The consumer was asking for far more
  than the hardware needs, and a fix sized from its request would have been
  wrong about why it works.)

- ☠️ **But the allocator's answer is a hypothesis, and the importer is the one
  that will reject you.** What a driver *prefers* to allocate and what it will
  *accept* on import are answered by different code paths, and only the second
  one decides whether a zero-copy path exists. Ask it directly, which is nearly
  as cheap: allocate **one** buffer generously — wider than any layout you mean
  to test — export it, and import that same fd several times while varying only
  the claimed pitch. Every import stays in bounds because the allocation is
  larger than all of them, so the only variable is the number, and the answer
  comes back as accept/reject per candidate rather than as an inference. Do this
  before writing kernel code sized from the allocator's preference; a padding
  requirement inferred from one path and paid for in another is a change you
  cannot defend when it does not work.

- ☠️ **When an interface stutters while something on screen animates, check what the
  toolkit is rendering *with* before profiling the application.** A distribution can set
  a session-wide environment variable that puts every GTK4 application on the software
  renderer — a defensible choice on a GPU whose accelerated path the distro does not
  trust — and the consequence is that any continuously animating content forces a full
  window repaint on the CPU at that content's frame rate, with the scroll animation
  sharing what is left. The signature is specific and cheap to read: the *application*
  burns more than a core while the *compositor* sits near idle, and the stutter is
  insensitive to how large the animating surface is. Read the environment of the running
  process (`tr '\0' '\n' < /proc/<pid>/environ`), not of your shell, because the session
  and your login get theirs from different places. Ask the toolkit which values it
  accepts rather than assuming (`GSK_RENDERER=help`); a name it no longer knows produces
  a warning and a silent fallback, so a measurement taken under one can be attributing
  the result to the wrong renderer. Override per user with `environment.d` and
  `systemctl --user set-environment` rather than editing the distro's file, which is
  package-owned and comes back on upgrade — one instance of a general hazard, and
  of the check that catches it, in `/fp3-kernel-test` ("a file you hand-placed
  into a package-owned path is borrowed, not held").

- **A truncated function pointer segfaults instead of failing.** `ctypes`
  defaults a foreign function's return type to `int`, so
  `eglGetProcAddress(...)` hands back a 64-bit address with its top half cut
  off, and the crash lands at the first call through it — nowhere near the line
  that is wrong. Set `.restype = c_void_p` on every lookup function before using
  it. A probe that dies with `SIGSEGV` and no output is usually this, not the
  driver refusing.

## Building a feature across layers you do not own

A device feature rarely lives in one place: a kernel driver exposes it, a
framework interprets it, a transport carries it, an application asks for it.
Each boundary can silently drop what the one below it publishes, and the layer
that *fails* is usually not the layer that is wrong. Three rules, each of which
cost a build cycle before it was written down.

- **Prove the last mile by hand before writing code for it.** The expensive
  mistake is to implement the whole chain and then discover the final hop does
  not exist. Whatever the application will eventually do, do it manually first
  with whatever CLI the transport offers — set the property, send the message,
  poke the node — and confirm the *bottom* layer reacted, in its own log.
  Worked example: before writing an app that focuses the camera, the control was
  set by hand on the running node (`pw-cli set-param <node> Props { <id>: <v> }`)
  and the IPA's log was checked for a scan. Ten minutes; it would have been a
  wasted 40-minute build otherwise.

- **☠️ A layer can publish a capability that the transport quietly drops.** Do
  not infer from "the framework supports it" that an application can reach it.
  Transports commonly carry only the simple types and bail out of the rest, and
  they do so *silently* — the control is simply absent, with no error anywhere.
  Read the transport's own mapping code, not its documentation: the answer is
  usually one `switch` on the type, plus an early return for anything harder.
  A control that survives and one that does not can be neighbours in the same
  enum.

- **☠️ One driver error can take a userspace session manager down with it, and
  the symptom then appears at a layer that is not broken.** A device daemon that
  holds hardware open (a session manager, a media server) can deadlock on a driver
  failure and stop answering — after which the hardware is *absent* from every
  application, and the honest report becomes "there is no camera / no sound card",
  which is a lie about a different layer. Two tells that a daemon is wedged rather
  than the device missing: its control tool **hangs** instead of erroring, and a
  dump tool **succeeds with empty output** (exit status 0, zero bytes) because it
  was granted a connection whose object list never arrives. Restarting the daemon
  brings the device straight back, which is both the workaround and the proof that
  the fault is below it. Do not stop at the restart: the thing that wedged it is
  still there, and it will happen again on the next unlucky call.

  **The daemon can also be killed outright, and then the first instrument is
  `coredumpctl`, not the log.** A media daemon that loads plugins runs other
  people's code — and your own, if the port carries local patches — inside its
  own process, so an `abort()` anywhere in that code takes the whole thing down
  and the hardware vanishes from every application at once. `coredumpctl list`
  then `coredumpctl info <pid>` names the failing function and the thread, which
  is a diagnosis rather than a symptom, and it costs one command. Two things the
  trace tells you immediately: a frame in `__glibcxx_assert_fail` /
  `__libcpp_verbose_abort` means a hardened-libc bounds check fired rather than
  the code failing on its own terms, so look for an index, not for logic; and a
  frame in a plugin or an out-of-tree patch means the fault is yours to fix even
  though the process that died was not. Check `git log` for who wrote the file
  the trace names before assuming it is upstream's.

- **☠️ Asking a running pipeline to renegotiate can stop it dead.** Media
  pipelines look reconfigurable and often are not: changing the format a live
  source already agreed on may end in `not-negotiated` and a stream that never
  restarts — which the user sees as a freeze, not as an error. Where a feature
  needs a different configuration, the safe shape is the one Megapixels uses for
  its preview and capture modes: stop, reconfigure, restart, act, and put it
  back. Slower and visible, but it works, and it fails in a way you can see.

- **☠️ An asymmetric acquire/release pair plus a swallowed message class is a
  permanent resource leak on the far side, and nothing local looks wrong.** A bus
  controller acquired a channel through its own vendor-specific message — which
  really did activate the resource on the co-processor — while the *generic*
  release path was silently dropped by the same driver (`return 0` over a whole
  message-code range). Teardown was therefore a no-op and the co-processor-side
  vote stayed held forever. Everything on the caller's side was balanced, which
  is why it read as correct.

  Three transferable moves, and they apply to any bus or co-processor:

  1. **If a resource is acquired by a driver-specific path, check that the
     RELEASE travels a path that actually reaches the wire.** "Balanced teardown
     in the caller" proves nothing when the layer underneath swallows it.
  2. **A protocol constant that is defined and referenced nowhere, next to an
     asymmetric enable/disable pair, is a strong smell** — the missing half's
     recipe is usually sitting in the downstream/vendor source.
  3. The bisect turned on asking **"which HALF"**, not "which line": three cheap
     single-boot preventive tests — session without data, codec route without a
     stream, real stream — narrowed it to the combination.

- **☠️ Before building a series, search the upstream patch tracker for the FILE
  name.** One fix here had been posted upstream by the vendor eleven days
  earlier; the correct move was a `Tested-by:` reply, not a competing patch.

## Observing a co-processor that has no obvious debug port

Recurring sub-problem: you need a value from inside the ADSP, which has no bound
debug console on the mainline setup. The **method is to find the firmware's *own*
diagnostic primitive and re-wire its readout** — the DSP already publishes
diagnostics to shared memory (Qualcomm's diag/QXDM/ULOG path); mainline just never
connects the reader. So before declaring an internal value "unobservable", look for
the existing primitive and tap it. **Corollary rule of thumb:** live envelope trace
→ SMEM_LOG ring; one specific internal value → injected SMEM tracer; a whole
internal log after a crash → devcoredump.

Instruments, by the question they answer (choose the lightest that answers yours):
- **Co-processor F3 debug messages via DIAG** — the richest source for internal DSP
  logs, and it works on mainline without a kernel port: the DIAG channels ride SMD,
  and `rpmsg_chrdev` auto-binds them to char nodes (discover by name via
  `/sys/class/rpmsg/*/name`; minors move across SSR). What was missing is only the
  DIAG *protocol layer* (a userspace shim — `scripts/diagtap.py`/`diagcap.py`/
  `parse_f3.py`). You send a feature-mask then an F3-mask (wire formats from
  downstream `drivers/char/diag/`, raw on the CNTL node), and the DSP streams
  HDLC-framed F3. Readable EXT (`0x79`) messages carry format-string+filename;
  QSR (`0x92`) messages are hashed and need the build's string DB. `%s` args are
  pointers → resolve against `adsp.mbn` rodata (VA→file-offset). Re-arm masks after
  an SSR (it resets them). (Worked example: this recovered a CVD `q6_core_clk`
  clock-lookup failure; the framer's own messages happened to be QSR-hashed.)
  **Decide decodability offline first, at zero device risk:** `strings -n6 fw.mbn | grep -cE
  '%[-0-9.]*[dsxulc]'` — a high plaintext-printf count means the log is EXT-readable and a local
  DIAG/coredump capture suffices; only hashes means QSR and you need the vendor `.qdb`. Settle this
  *before* anyone asks for an external QXDM capture. **From a coredump you can also prove a branch did
  NOT run:** a fmt-string whose micro-MSG pointer is absent from a *fresh* (post-re-trigger, before the
  ring wraps) dump while same-log-level siblings are present means that code path never executed
  (positive-control the false-negative on the working side). NB `remoteproc` numbering drifts across
  SSR — `cat …/remoteprocN/name` every time; dump to `/tmp` (tmpfs), not the possibly-full `/`.
  **On the UT oracle DIAG F3 works and the SLIMbus framer's messages are EXT-readable — but you
  must (a) TRIGGER framer activity and (b) filter the peripheral mask.** Idle, the framer logs
  nothing; earpiece playback (`pactl`/`paplay`) elicits `[SlimBus.c]`/`[SlimBusMaster.c]`/
  `[AFESlimbusDriver.cpp]` (channel-connect, master-port-config, `LA=0xc4`) — a live view of the
  *working* framer. ⚠️ `peripheral_mask=0x7F` drowns you in modem/LTE noise → `grep -v 'lte_|LL1|qcril'`.
  The framer messages are EXT (not QSR) so they read directly. But the *bring-up* diff (FS 0→1) is
  NOT locally capturable on UT: no userspace SSR trigger (`/dev/subsys_adsp` fops = get/put only, no
  restart-ioctl), and a boot-armed capture hangs the boot (see the "boot-armed diag oneshot"
  rule in `fp3-kernel-test/references/safety.md`).
- **SMEM_LOG ring — live, AP-readable, zero-injection.** A shared event ring in the
  *safe* legacy-SMEM region, read with a plain `python mmap(PROT_READ)`
  (`scripts/adsp-smem-log.py`). Carries the SMD/QMI/IPC-router *envelope*
  between APPS and the subsystems — use it to watch *that messages flowed*, not the
  DSP's internal state machine.
- **For a BOOT-TIME co-processor ordering question, don't arm live ftrace post-boot — it's
  already too late; read the boot-persistent ipc_logging ring, and know which one overflowed.**
  The ADSP service-registration + framer happen in the first ~22 s; by the time adb/ssh is up
  (~90 s) the live ftrace/trace_events rings have long scrolled, so enabling them post-boot won't
  catch the boot. The boot-persistent sources are `dmesg` + the per-driver `ipc_logging` rings — but
  those overflow by traffic too: on UT the `ipc_rtr_q6ipcrtr` (ADSP QMI arrivals) earliest entry was
  already t=150 s (the 22 s window overwritten by steady-state SLIMbus traffic); the boot QMI window
  survived only in **`kqmi_req_resp`** (from t=20.58 s, decode QCCI/QCSI TX/RX with SvcId —
  `MI:20/ML:15`=SELECT_INSTANCE, `MI:21/ML:e`=POWER_REQ). Arming at boot needs a kernel-cmdline
  `trace_event=`/`ftrace=` + reboot; `dynamic_debug` is *not* compiled into this UT kernel
  (`# CONFIG_DYNAMIC_DEBUG is not set` → pr_debug/dev_dbg are no-ops, un-armable).
  **And before you fire a risky re-trigger for a "fresh capture", ask whether the info it would give
  is even AP-observable:** an AP-side re-trigger (SSR *or* runtime-PM) only replays the *AP-visible
  QMI service ordering* — never the co-processor-INTERNAL pre-SLIM ordering (ADSP core + audio-PD
  servreg/PD-mapper coming up in the golden trace's early gap), which is QMI-invisible to the AP. An
  SSR would just repeat the SLIM-first QMI sequence the `kqmi` ring already gave; the internal order
  needs an F3/DIAG co-processor log, not a re-trigger. (Premise-correction that fell out: SLIM 0x301
  is actually the FIRST QMI transaction, not "last after many ADSP services.")
- **Injected SMEM tracer — the reliable path for one specific value.** Patch the
  firmware to write the value into a SMEM item the AP reads. Best when you want one
  register/branch/counter, not a whole log. (Chain + validation in `fp3-kernel-test`.)
- **devcoredump — a whole internal log after a crash.** Enable the remoteproc
  coredump node, trigger a crash/recovery, read the ELF from
  `/sys/class/devcoredump/*/data` (its PT_LOAD segments are the carveout, where ULOG
  buffers live). Heavy: needs a crash, and only the coredump path may touch the
  carveout — **never** a live AP mmap of the firewalled DDR (wedges the device).
- **900e Sahara ramdump** — after a crash the RAM is exposed over USB; a Sahara/`qdl`
  client pulls the full dump. Heaviest; recovery = power-cycle.

Prior art to cite for provenance (reassures reviewers this is a real method, not a
hack): Delugré "Reverse engineering a Qualcomm baseband" (firmware patch + shared
mem); FirmWire; QCSuper; comsecuris / Grant Hernandez QDSP6 work; the LLVM Hexagon
backend + Ghidra/IDA processor modules. Underneath are decades-old primitives —
scratchpad/shared-RAM printf without JTAG, `/dev/mem` MMIO poking, coredump-exfil.
Reach for these before assuming a wall.

## Brick-safety (one home, not two)

**Every brick-safety rule lives in
[`fp3-kernel-test/references/safety.md`](../fp3-kernel-test/references/safety.md)**
— full text, with the case that produced each one. It is not restated here, and
it is deliberately not summarised by rule *number*: a numbered cross-reference
starts lying the moment the list is renumbered. Cite the rule by what it says.

Read it **before** anything that writes to flash, probes MMIO, restarts a
co-processor, or reboots the oracle. If you are only loading this skill, load
that file too — it is one file, and the two skills ship together.

The framing that belongs here, because it is what makes the rest affordable:

- **The dev phone is disposable; the daily driver is a *separate* FP3.** That is
  the premise every guardrail is calibrated against.
- **The oracle is worth as much as the device.** A slot that still works is the
  whole differential method. Rules that protect it (the ADSP-SSR one especially)
  are not optional politeness.
- **Interrupted flashes are recoverable** — dual-slot, and lk2nd often idle-reboots
  into the OS on its own. Re-check SSH before believing in a brick.
- **Commits on the kernel tree go to the fork, never to `origin`** (origin is
  upstream); which branch is in
  [`fp3-pmaports/README.md`](https://github.com/llg179org/fp3-pmaports#the-branch-model).

## Worked example: how the SLIMbus wall was localised (illustration — findings age; status in the docs)

This is the longest-running investigation and the best illustration of the
down-the-stack method. It is a *reasoning trace*, not a fixed conclusion — the
specific verdicts have shifted as measurements accumulated, which is exactly the
point.

**Question:** why does earpiece/mic (WCD9326 on SLIMbus) work on the oracle but not
on mainline pmOS?

The search walked down the stack, each rung a differential measurement:
- *Enumeration/registers.* The mainline NGD writes `CFG=0x7`+`INT_EN` but they never
  latch, while the oracle's identical writes latch — so the AP driver is
  byte-complete and the *remote* side isn't framing. AP register sequence exonerated.
- *AP levers, one by one.* bb_clk1, CX corner (verified INT_MAX by direct
  measurement), proxy-hold xo+cx, check_framer, PDR, regulators — all null. The
  upstream race-fix (patchwork 1075549) is necessary-but-not-sufficient. No discrete
  AP-side lever remains.
- *Cross-SoC check.* Mainline msm8996 frames the *same* codec on the *same*
  qcom-ngd-ctrl+q6v5-pas stack — but via `lpass_q6_smmu`+`HLOS1_VOTE_LPASS_ADSP_GDSC`,
  msm8996-only hardware that msm8953 lacks (and downstream msm8953 doesn't need). So
  the SLIMbus core clock is *internal* to the co-processor on this SoC, not an
  AP-driven clock. This is why "just add the clock" has no target.
- *Firmware identity.* Byte-identical oracle↔port ⇒ the difference is environmental.
- *Firmware entry-traces.* Non-crashing traces showed the framer bring-up code is
  **never even invoked** on mainline → the trigger is upstream, in the AP→ADSP QMI.
- *QMI content test.* A wire length-delta *looked* like a missing QMI field, but the
  oracle's own kernel source encodes the same fields — and directly matching the
  message length changed nothing. So QMI byte-parity is not the lever either; the
  message content is exonerated.

**Where it stands now:** not here — see the boundary above. The outcome, and what
is still open, is in
[`docs/audio/bringup/`](https://github.com/llg179org/fp3-pmaports/tree/main/docs/audio/bringup).

**Why this example is in a *method* skill:** it shows the discipline that made
progress possible — exonerate each layer with a register or a source diff before
descending, distrust log "OK"s and seductive-looking deltas until a field-level or
register-level check confirms them, and treat every result as a redirection of the
search rather than a defense of the current theory. The verdicts will keep moving;
the method is what carries forward.

## Contributing findings back upstream (don't start a competing effort)

When a bring-up produces something worth upstreaming, the first move is **research
whether it's already done or in flight — before writing a line of patch.** (Learned
07-21 doing the rear-camera contribution.)

- **Check, in order:** is the driver in torvalds mainline (`drivers/.../Kconfig`
  presence)? in the distro's kernel repo (msm8953-mainline branches/tags)? in the
  maintainer's *personal fork* (a GitHub fork's WIP branches — e.g. `z3ntu/linux`
  `fp3-6.16-camera` had the whole camera enablement, guarded by `#ifdef` + `FIXME`s,
  months before it hit any release)? on patchwork/lore? A GitHub fork's *age* and its
  stale default branch say nothing about upstream status — the maintainer's work lands
  via mailing lists; the fork is just their staging area.
- ☠️ **"Before writing a line of patch" is the part that gets skipped, and the cost
  is silent.** A one-line DAPM route on the voice path was written here, debugged
  for weeks, and recorded in three documents as a discovery. It existed line for
  line — including the exact missing route — in a 2022 commit on another downstream
  tree, implemented for seven SLIMbus ports where ours did one. Nobody's work was
  published as ours and the patch was not wrong; what was lost was the weeks. The
  trigger is mechanical and worth making a habit: **if the file you are about to
  patch is not in Linus' tree, list who else carries it first.**
  ```sh
  git ls-remote --heads <other-downstream-tree>   # topic branches name the effort
  git fetch --no-tags <url> <sha> && git diff FETCH_HEAD:<path> HEAD:<path>
  ```
  Downstream trees advertise their in-flight work in branch names
  (`rdacayan/for-sdm845/q6voice-series` was one `ls-remote` away all along).
- **Search the right forge, and take authorship from the commit.** A repo named in
  an old note as `panpanpanpan/linux` does not exist on GitHub; the tree was on
  **GitLab**, under a group, and the driver's author was not the person the note
  named — they had opened the merge request, the code inside was somebody else's
  cherry-pick. A 404 means the URL is wrong, not that the source is unreachable.
  ```sh
  curl -s "https://gitlab.com/api/v4/groups/<group>/projects?per_page=50" \
    | jq -r '.[] | "\(.id) \(.path_with_namespace)"'
  curl -s "https://gitlab.com/api/v4/projects/<id>/merge_requests?search=<term>&scope=all&state=all" \
    | jq -r '.[] | "!\(.iid) \(.state) \(.author.username) \(.source_branch) | \(.title)"'
  curl -s "https://gitlab.com/api/v4/projects/<id>/merge_requests/<iid>/commits" \
    | jq -r '.[] | "\(.id) \(.author_name) <\(.author_email)> \(.authored_date[0:10]) \(.title)"'
  git fetch --no-tags <clone-url> <full-sha>     # works after the branch is deleted
  ```
  Deleted branches are the normal case for a personal RE repo, which is also why an
  import is worth archiving under your own account — recipe in
  [`../msm8953-mainline-pr/SKILL.md`](../msm8953-mainline-pr/SKILL.md#archive-an-import-as-a-parentless-snapshot-not-a-mirror).
- **If it exists, contribute the DELTA to their effort, not a rival series.** Diff
  your driver against theirs (ours vs the maintainer's shared-base driver was ~54
  lines; the real value was a few FP3-slow-rail robustness fixes + a hardware
  difference). Credit the shared base (here: Intel IMX319/355 + the sdm670-mainline RE).
- ☠️☠️ **Knowing this is not the same as having done it, and the gap is invisible
  from inside.** The line above has named the camera driver's real origin — *"the
  sdm670-mainline RE"* — for as long as this skill has existed. The commit message
  that went onto the submit branch, and three pages of documentation, nonetheless
  described the register programming as reverse-engineered *here*, crediting only
  the in-tree ancestor. Nine days later an upstream review pass had to unpick all
  four. So when a series is being prepared, **re-read this section against the
  actual commit messages** rather than trusting that the rule was followed when
  they were written; and for a sensor bring-up specifically, the two out-of-tree
  RE efforts (camera, SMGR sensors) are the places to look first. The citation
  mechanics and the "find the immediate source" procedure are in
  [`../msm8953-mainline-pr/SKILL.md`](../msm8953-mainline-pr/SKILL.md#find-the-immediate-source-not-the-ancestor-you-recognise).

  **Resolved 2026-07-30, and the fix was cheap:** the original file was fetched by
  SHA and diffed. 1514 lines in, 1568 out, +68/−21 — so the driver is ~96 % Joel
  Selvaraj's and the four things that are ours are all in the power sequence. The
  series is now import → our change → device tree, and the import turned out to
  carry a full `Signed-off-by` chain, so nothing was blocked. The lesson to keep is
  the *asymmetry*: the wrong claim survived nine days of self-consistent
  documentation, and one `git diff` against the original ended it. **Fetch the
  thing you copied.**
- **When the maintainer's series is on a list rather than in a repo, patchwork's
  API answers where lore does not** (both `lore.kernel.org` and `lkml.org` are
  behind a bot wall and return *Access Denied* to automated fetches):
  `curl -s 'https://patchwork.kernel.org/api/1.2/patches/?q=<terms>&order=-date' |
  jq -r '.[] | "\(.date[0:10]) \(.state) \(.name)"'`. The **state** is the part
  worth having — `changes-requested` says a maintainer is mid-review, which is a
  different situation from `new` or `accepted`. LWN mirrors cover letters and is
  fetchable when patchwork does not have the prose.
- **Verify a hardware claim on-device before reporting it.** "Sensor is at 0x1a not
  0x10" was confirmed by powering the sensor and reading the chip-id at *both*
  addresses (0x1a→0x0363, 0x10→NAK), not inferred from a failed probe — a swappable
  camera module means per-unit strap differences are real, so the data point matters.
- **Build-test the upstream patch via the distro's package build**, even for a non-pmaports
  (Alpine) package: copy the aport into `pmaports/temp/<pkg>/`, add the patch to
  `source=`, `pmb checksum`, `pmb build <pkg> --force`. A green build ("compiles clean")
  is a far stronger MR than an untested one; then behavior-verify live (e.g. the GNOME
  Snapshot idle-inhibit fix showed up as a new `org.gnome.SessionManager` inhibitor
  during preview — empty before the patch, present after).
- **Match the channel + format to the project.** Kernel → email a `git send-email`
  patch, or attach the `.patch` file (Gmail's plain-text-inline mangles tabs → the patch
  won't `git am`); a name with a comma must be RFC2047-quoted in `From:` but plain in
  `Signed-off-by:` so they match. GNOME → a GitLab MR (fork → branch → `git am` → push),
  and **check for an existing issue first** and add your data point there rather than
  filing a new one. When it's really a distro-desktop issue (screen locks mid-camera),
  it's the app's job (GNOME Snapshot), not pmaports — trace the layer (`GetInhibitors`
  empty during preview) before choosing the repo.
