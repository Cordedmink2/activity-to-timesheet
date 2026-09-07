# The script test suite

Covers `scripts/`. It does **not** cover `SKILL.md`'s behavioural claims — those need a
fresh agent and a control arm, and the method for that lives in `docs/skills/daily/decision-log.md`.

```powershell
python -m pytest                    # everything except benchmarks (~4s)
python -m pytest --bench -s         # add the timing tripwires, with their numbers
python -m pytest tests/test_scenarios.py --regen-golden    # after an intended change
```

Run it from the skill root. `pytest.ini` there sets `testpaths` and the markers, so a
bare `pytest` does the right thing.

## Read this before writing a test

**Never invoke a script with `subprocess`.**

Two live systems are running on the machine this suite runs on: ActivityWatch on
`localhost:5600`, and Harvest — reachable with the real credentials sitting in `.env` at
the skill root. `conftest.py` has an autouse fixture that points both base addresses at an
unroutable one and blanks the credential sources, so an un-stubbed call fails loudly
instead of reading the user's real day or **creating a real time entry on a client's
timesheet**. Note which way round they go: the activity source is redirected by setting
`TIMESHEET_ACTIVITY_URL`, so a `.env` written by the `env_file` or `workspace` fixture
outranks it — do not put that key in one.

A subprocess inherits none of that. It reads the real `.env` and talks to the real API.
Use `support.run_cli(module, args)`, which runs `main()` in this process with a patched
`sys.argv` and captures stdout, stderr and the exit code. One test used to shell out;
it was quietly paging 180 days of real Harvest history on every run.

## The three layers

**Unit** — the pure functions, called directly with hand-built spans. Fastest, and where
a boundary condition belongs.

**Contract** — `test_cli_contracts.py`: what every CLI promises about bad input. A model
reads these scripts' stdout, so a traceback where an `ERR` line belongs sends it
debugging the tool instead of fixing its own argument.

**Scenario** — `scenarios.py` builds whole synthetic days; `test_scenarios.py` runs both
AW scripts over each and diffs the complete output against `golden/`. Each scenario is a
shape the skill has actually had to reason about — a fragmented screen lock, an
end-of-day flicker, two clients in one day, work past midnight.

Scenario tests come in pairs, deliberately. The **golden file** catches change; the
**named assertions** under it state intent. A golden alone would happily record a bug,
so a regeneration that bakes one in still fails the assertions. Keep both.

## Writing a day

`support.Day` takes local `HH:MM` strings and emits the UTC events ActivityWatch would:

```python
d = (day(dt.date(2026, 8, 12))
     .classify("ACME", r"ACME|example-uat")
     .afk("00:00", "08:12")
     .active("08:12", "10:57")
     .locked("10:57", "11:45")                    # lock: sub-threshold AFK fragments
     .thin("11:45", "13:26", active_min=6, idle_min=4)   # supervising an agent
     .window("08:30", "10:57", "Code.exe", "sharepoint-access-sync"))
live_aw(d)
```

Hours past 24 mean the next morning (`"25:30"` is 01:30), so an overnight session needs
no second date. `.locked()` and `.thin()` exist because those two shapes — a lock the
break detector cannot see, and real work whose ratio reads idle — are what the skill gets
wrong, and they should cost one line to write.

A test that calls a function directly, with a list of events rather than a served day,
builds each one with `.event()` on the same day — `d.event("10:17:29", seconds=1049,
status="afk")`, or `minutes=` when that is the unit the test reasons in. The clock
takes seconds and the second-pass marker like everything else on a `Day`, so a boundary
one second either side of a threshold, or an event inside a repeated hour, is written the
same way as the rest of the suite rather than with a builder of the file's own. Every
timestamp comes out in one spelling, which matters: `dedupe_heartbeats` sorts on the raw
string.

### Dating a day: `offset=` or `zone=`, never both

A day is written at a fixed `offset` (default UTC+12) unless you pass `zone=` an IANA name:

```python
d = day(dt.date(2026, 4, 5), zone="Pacific/Auckland")   # the day the clocks go back
```

Use `zone=` when the day is *about* the zone. A day containing a daylight-saving change
cannot be written at one offset because it does not have one, and it is twenty-five hours
long (twenty-three in spring). The clock strings still mean the wall clock either way.

Two things follow, and they are the reason this section exists:

- `live_aw(d)` configures `TIMESHEET_TIMEZONE` for a `zone=` day, so the scripts resolve
  the real thing.
- Such a day must therefore pass **no** `--utc-offset`. `test_scenarios.dating_args(d)`
  is what decides that; a scenario that hands the flag over anyway takes the shortcut the
  scripts are being tested for not needing.

A `*` on a time asks for the **second** pass over the hour a fall-back repeats, which is
otherwise unwritable — `at()` localises with `fold=0`, so `"02:30"` is always the first:

```python
d.active("01:30", "02:30")     # 12:30Z-13:30Z, at UTC+13
d.afk("02:30", "02:30*")       # 13:30Z-14:30Z: an hour, both ends reading 02:30
d.active("02:30*", "04:15")    # 14:30Z-16:15Z, at UTC+12
```

It is the same marker the scripts render and read back, so a fixture is written in the
notation its golden returns. `.thin()` and `.locked()` refuse it: they slice a range into
pieces with `_fmt()`, which cannot carry it, and would otherwise put every generated piece
in the first pass — a fixture that looks like it straddles the change and does not.

## Adding a scenario

Define it in `scenarios.py`, run `pytest --regen-golden`, then **read the generated
golden** and confirm it says what you meant. Commit both. A golden nobody read is a
record of whatever the code happened to do.

## Fakes

`support.aw_server` and `support.harvest_server` are real `http.server` instances on
localhost, not mocks of the code under test — so `main()` gets exercised end to end,
including URL construction, bucket discovery and the unreachable-server path. Both record
every request, which is how the "`harvest_post` must never send a bare `hours` field"
invariant is pinned: assert on the body that was sent, not on what the script printed.

A route's payload is JSON-serialised, so a route that must answer with no body at all —
Harvest's reply to a DELETE — returns `support.NO_BODY` rather than `None`, which would go
out as the four bytes `null`. The provider's project catalog has builders of its own:
`project()` / `task()` / `assignments_page()` shape the rows as the API returns them,
`paged_assignments()` turns a list of pages into routes for the fake (with an optional
page that fails), and `write_catalog()` writes pages to disk the way `refresh_catalogs`
leaves them, for tests of the read path.

`support.CREATE_ARGS` is the one well-formed create, without the gate; append `--confirm`
to post. `support.resource_warnings_from(fn)` is how a leaked response is asserted closed:
the warning fires from a destructor at collection time, so left to chance it fails
whichever unrelated test the collector interrupts.

## Marking a defect

Found a real bug while writing a test? Keep the test, mark it
`@pytest.mark.xfail(strict=True, reason="DEFECT: …")`, and leave the script alone until
the fix is a deliberate change with its own red/green. `strict=True` means the xfail
turns red the moment someone fixes it, which is the reminder to delete the marker.
