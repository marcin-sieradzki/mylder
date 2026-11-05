---
name: verify-mylder
description: "Launch Mylder's production build on the weekday recording and drive it in Chromium as a rider would, keeping screenshots and ARIA snapshots as evidence. Use to prove a change works in the real app, and for the factory's verdict."
---

# Verify Mylder

Mylder's surface is one web page, the map at `/en` and `/da`, with its panels and side sheet, served by a Next.js production build. This skill starts that build on a recording (`docs/testing-seams.md`), drives it with Playwright as a rider would, and keeps what it saw. Every command runs from the root of the checkout under test; each run has a **run id** you choose (`ticket-92`, `main-92`), and everything it makes lives in `.verify/<run-id>/`, which git ignores.

The feature map in [`features/README.md`](features/README.md) says what to drive for each feature and what proves it. Read it before driving.

## Launch

```sh
.claude/skills/verify-mylder/scripts/launch.sh <run-id> [port] [recording|timetable|timetable:<folder>|updates:<folder>[/<moment>]]
```

It runs `npm run build`, starts `next start` on the port (4300 by default) with `MYLDER_SOURCE` set to `recording:<recording>` (`weekday` by default) and `MYLDER_AIRCRAFT_SOURCE` to `recording:weekday`, and waits until `/api/snapshot` answers with vehicles: ready is printed as `Ready: http://localhost:<port>/en`. It refuses a port that already answers. `node_modules` must match the lockfile (`npm ci` in a fresh worktree). `VERIFY_SKIP_BUILD=1` reuses the build when it was made from the same clean commit, which a relaunch on an unchanged checkout wants.

The `weekday` recording holds ten minutes from 07:20 on 16 June 2026, and the server's clock starts there at launch and runs on in real time; the page takes its time from the server, so nothing in the browser is faked. After ten minutes the recording repeats its last answer and every vehicle ages towards No signal, so drive within nine minutes of launch, or relaunch. A recipe that names another recording, such as `crowded` (five minutes from the same moment, on a timetable of its own), runs on its own launch with that name as the third argument, on a port and run id of its own.

**The timetable source.** `timetable` as the third argument starts the build with `MYLDER_SOURCE` unset in place of a recording, the default, which is the timetable source, as production runs until the key arrives (the simulation is only ever `MYLDER_SOURCE=simulated`, which no launch here sets): the deployed timetable in `public/timetable/` at the real time, with no call of any kind, so every vehicle is Timetable only and nothing runs out (the doctor skips the recording's minutes). What it shows is the real network's plan at that moment: fewer vehicles at night, and none if the deployed timetable's window has ended. It runs on its own launch, port and run id, as another recording does. To check it: `/en` draws vehicles (`[data-vehicles]` above 0) and every trip in `/api/snapshot` has `"state":"timetable-only"`, with the snapshot's `source` `{"kind":"timetable"}`. `timetable:<folder>` runs the same source on a saved folder in `recordings/` (`MYLDER_TIMETABLE_FROM`): its `timetable/` and a clock that starts at its `clock.json`'s moment, so a moment can be driven again. `timetable:timetable-ending` starts at 07:20 on Tuesday 25 August 2026, two days before the fixture timetable's window ends on 26 August, so `/api/snapshot` has `"timetableRunningOut":true` and the page shows the timetable notice; `timetable:timetable-source` starts at 07:20 on 16 June 2026, the screen tests' minute. The doctor skips the minutes for both.

**SIRI-ET's delays.** `updates:<folder>` starts the timetable source, `MYLDER_SOURCE` unset, with `MYLDER_UPDATES=recording:<folder>`: the SIRI-ET reader runs inside the tracker over the folder's recorded messages, on its `timetable/`, from its `clock.json`'s moment. `updates:siri-et` starts at 09:00:03 on Saturday 31 October 2026 and its messages run 56 minutes, so drive within 55 minutes of launch (the doctor counts them). The table fills as messages come: about 300 journeys after the first minute, 650 by the tenth. To check it: `/api/snapshot`'s `updates` reads `"kind":"recording"` and `"fresh":true`, and its trips are `estimated` (with `updated` and a `delay`) or `timetable-only`, every Metro and Light rail trip among the latter. Never pass `siri-et` alone as a recording: it has no Rejseplanen answers. `updates:<folder>/<moment>` replays the same messages from a saved moment's own clock, `recordings/<folder>/<moment>/clock.json`. `updates:siri-et/quiet` starts at 09:55:00, 67 s before the last message, at 09:56:07 (so screens say "since 09:56"), and the feed is fresh at launch and goes quiet at 10:01:07 on the server's clock, about 6 minutes in, so wait up to 8 minutes for it: from then on `/api/snapshot`'s `updates` reads `"fresh":false` with that `lastMessage`, every trip with an `updated` time is `no-signal`, the rest stay `timetable-only`, and Disruptions shows the quiet feed's card. It never runs out (the doctor sets it no limit).

**Main against the branch.** To see how main behaves, launch main from its own worktree on another port: `git worktree add ../mylder-verify-main origin/main`, then `npm ci` and `launch.sh main-<n> 4301` there. Two runs never share a port, a build folder or a run id; the ports every server takes are in `scripts/ports.ts` and the table in `docs/testing-seams.md`.

## Doctor

```sh
.claude/skills/verify-mylder/scripts/doctor.sh <run-id>
```

Read-only. Prints `healthy` with the URL, the commit, the recording and its minute, or names the fault: the server stopped, the checkout moved since launch, the port isn't held by this run's server, the snapshot has no trips, or the recording has run out. Run it before the first drive, after any failed or surprising drive, and when anything looks off; a fault means clean up and launch again.

## Drive

Write each journey as a small module in `.verify/<run-id>/journeys/<journey>.ts` and run it:

```sh
node .claude/skills/verify-mylder/scripts/drive.ts <run-id> .verify/<run-id>/journeys/<journey>.ts [--phone]
```

```ts
import type { Journey } from '../../../.claude/skills/verify-mylder/scripts/drive.ts'

export default async ({ page, step, expect }: Journey) => {
  await page.goto('/en')
  await expect(page.getByRole('banner').getByText(/^Updated /)).toBeVisible()
  await step('map loaded')
  // ...the feature's recipe, a step() after each action that changes what the rider sees
}
```

`page` is a Playwright page on the run's server (a Desktop Chrome viewport, or a Pixel 7 with `--phone`), `expect` is Playwright's, and `step(name)` saves the next screenshot and ARIA snapshot. The script exits 0 when the journey passes and 1 with the error when it fails, after saving a `failure` step. In a sandbox whose Chromium differs from the pinned Playwright's, set `PLAYWRIGHT_CHROMIUM_EXECUTABLE` to its binary (`/opt/pw-browsers/chromium` in Claude's cloud containers).

Handles, most stable first: ARIA roles and names (`getByRole('dialog', { name: 'Overview' })`), the address (`?trip=`, `?stop=`, `?aircraft=`, `?latest=now`, `?tab=`, `?map=<zoom>/<lat>/<lon>`, `?hide=`, `?line=`), and the map's own attributes `[data-vehicles]` and `[data-aircraft]`, which count what the canvas draws, `data-tilt` and `data-heading` on the same element, the camera's tilt and heading in whole degrees once it comes to rest, and `data-spotlight` and `data-spotlight-at` there while the spotlight (from the Latest now pill or a Latest right now row) rings a dot, its trip and its point on the page. The canvas has no handles inside it: to tap a dot, stop or plane, open the page with `?map=15.00/<lat>/<lon>` centred on it (positions are in `/api/snapshot`, `/api/aircraft` and the timetable's stops) and tap the middle of the viewport, retrying with `expect(...).toPass()` while it draws. The feature files give each feature's handles.

## Evidence

A journey's evidence is `.verify/<run-id>/<journey>/`: the numbered `.png` and `.aria.yml` pairs, `console.txt` and `result.json`. The proof standards:

- Drive the rider's path: the chip, tab, row or tap a rider would use. An address is a path only where the feature map lists it as an entry point (a shared link), and `page.route` fakes nothing: the recording is the only outside system, and it stands at the API seam already.
- Capture the action and the state it led to: a `step()` before and after each action that changes what is shown, never only the last screen.
- Check what the rider can't see but the feature promises: the address after opening a panel, a count in `[data-vehicles]`, the language in `html[lang]`.
- A journey asserts what the ticket or the feature map says a rider sees, in their words. When the recording can't show a precondition, the journey fails and says which, rather than asserting less.

## Cleanup

```sh
.claude/skills/verify-mylder/scripts/cleanup.sh <run-id>
```

Stops the server's whole process group by the pid `launch.sh` recorded, and keeps `.verify/<run-id>/`. Run it after every run, failed ones too, and remove a main worktree with `git worktree remove ../mylder-verify-main` once its run is cleaned up. Evidence stays until the worktree goes; copy what a verdict needs out of it first.

## Helpers

All four are in `scripts/` and executable or run with `node`: `launch.sh <run-id> [port] [recording|timetable|timetable:<folder>|updates:<folder>[/<moment>]]`, `doctor.sh <run-id>`, `drive.ts <run-id> <journey.ts> [--phone]`, `cleanup.sh <run-id>`. Keep this skill honest with `/maintain-verification-skill`.
