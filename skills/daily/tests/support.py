"""Test support for the billables `daily` scripts: fake servers, a day-builder DSL,
and an in-process CLI runner.

Three jobs, in order of how much trouble they save:

1. **Fake ActivityWatch and Harvest servers.** The scripts hit `http://localhost:5600`
   and `https://api.harvestapp.com`. Repointing both at a local `http.server` gives real
   end-to-end coverage of `main()` — URL construction, bucket discovery, JSON parsing,
   error paths — without a single mock of the code under test. The two are redirected
   differently: the activity source through its setting, `TIMESHEET_ACTIVITY_URL`, and
   Harvest by repointing the `harvest_client.API_BASE` constant. `aw_client` used to have
   a matching constant and no longer does — it resolves its address per request.

2. **A day-builder DSL.** AW event streams are the input to every interesting
   calculation, and hand-writing UTC timestamps for a realistic day is both tedious
   and where test bugs come from. `day()` takes local `HH:MM` strings and emits the
   UTC events AW would.

3. **`run_cli()`** — invoke a script's `main()` in-process with a patched `sys.argv`,
   capturing stdout / stderr / exit code. Deliberately NOT `subprocess`: a subprocess
   ignores every fixture in `conftest.py`, so it would read the user's real AW data and
   post to their real Harvest account. See the hermeticity fixture there.
"""
from __future__ import annotations

import contextlib
import datetime as dt
import gc
import io
import json
import sys
import threading
import urllib.parse
import warnings
from pathlib import Path
from zoneinfo import ZoneInfo

SCRIPTS_DIR = Path(__file__).resolve().parents[1] / "scripts"


def bundled_scripts() -> list[Path]:
    """Every `.py` this skill ships, as paths — the population for "any bundled script".

    Derived from the directory rather than listed, because the whole value of a test that
    says *every* script is that a twelfth one is covered the day it is added. A list here
    would cover eleven and go on passing.
    """
    return sorted(SCRIPTS_DIR.glob("*.py"))


def bundled_script_names() -> list[str]:
    """The same population as importable module names, for `parametrize` ids."""
    return [p.stem for p in bundled_scripts()]

# Every key the scripts resolve through `skill_config.setting()`. One list, because two
# tests want it for opposite reasons and a key in one but not the other is a silent hole:
# `conftest._hermetic` clears each from the process environment so a developer's own shell
# can't leak into an assertion about defaults, and `test_config_seam` asserts that any
# script naming one of them goes through the seam.
SETTING_KEYS = (
    "HARVEST_ACCOUNT_ID", "HARVEST_API_KEY", "TIMESHEET_TIMEZONE",
    "TIMESHEET_ACTIVITY_URL", "TIMESHEET_WORKSPACE", "TIMESHEET_SCREENSHOTS_DIR",
    "TIMESHEET_OUTLOOK_CALENDAR",
    "DATAVERSE_URL", "PAC_AUTH_PROFILE",
)
from http.server import BaseHTTPRequestHandler, ThreadingHTTPServer
from typing import Callable, NamedTuple, cast

# The one spelling of the repeated-hour marker, taken from the module that defines it.
# `conftest` puts `scripts/` on `sys.path` before importing this module, which is the only
# way it is ever imported. Spelling the character again here would let a fixture and the
# output it is compared against disagree without anything failing.
from timezone import SECOND_PASS_MARK

# --------------------------------------------------------------------------------------
# Local-time DSL
# --------------------------------------------------------------------------------------

DEFAULT_DATE = dt.date(2026, 5, 28)
# The offset a generated day is *written in*. It is a property of this DSL, not of the
# scripts: they carry no built-in offset any more, so a run either passes `--utc-offset`
# or resolves the zone `conftest._hermetic` configures — which is `Etc/GMT-12`, this same
# fixed +12, chosen for having no daylight saving rather than for being anyone's home.
DEFAULT_OFFSET = 12.0
DEFAULT_HOST = "TESTHOST"


def second_pass(s: str) -> bool:
    """Whether a DSL time carries the marker naming the second pass over a repeated hour.

    Imported from the script rather than spelled again here, so a fixture is written in
    the notation its golden comes back in *by construction* — a second copy of the
    character would let the DSL and the output drift into disagreeing silently.
    """
    return s.strip().endswith(SECOND_PASS_MARK)


def _reject_second_pass(builder: str, *times: str) -> None:
    """`thin()` and `locked()` slice a range into pieces with `_fmt()`, which writes a
    bare `HH:MM:SS` and so cannot carry the marker. Accepting one would silently place
    every generated piece in the *first* pass — a fixture that looks like it straddles the
    change and does not. Refuse it instead; write the pieces out with `active`/`afk`.
    """
    for t in times:
        if second_pass(t):
            raise ValueError(
                f"{builder}() cannot write the second pass ('{t}'): it slices the range "
                f"into generated pieces that lose the marker. Write them as explicit "
                f"active()/afk() calls.")


def parse_local(s: str) -> dt.timedelta:
    """`'HH:MM'` / `'HH:MM:SS'` as an offset from local midnight.

    Hours are not capped at 23: `'25:30'` means 01:30 the next morning, which is how
    an overnight session is written without juggling two dates. A leading `-` reaches
    back into the previous evening (`'-00:45'` = 23:15 yesterday).

    A trailing marker is stripped here and read by `second_pass()`: it says *which* of two
    identical wall clocks is meant, which is a question about the zone rather than about
    the distance from midnight this returns.
    """
    s = s.strip()
    if s.endswith(SECOND_PASS_MARK):
        s = s[:-len(SECOND_PASS_MARK)].strip()
    neg = s.startswith("-")
    parts = [int(p) for p in s.lstrip("-").split(":")]
    while len(parts) < 3:
        parts.append(0)
    h, m, sec = parts
    delta = dt.timedelta(hours=h, minutes=m, seconds=sec)
    return -delta if neg else delta


def _fmt(delta: dt.timedelta) -> str:
    """Inverse of `parse_local`. Hours past 24 are kept, not wrapped, so a generated
    overnight span round-trips."""
    total = int(delta.total_seconds())
    return f"{total // 3600:02d}:{total // 60 % 60:02d}:{total % 60:02d}"


def local_midnight_utc(date: dt.date, offset: float) -> dt.datetime:
    return (dt.datetime.combine(date, dt.time(0, 0), tzinfo=dt.timezone.utc)
            - dt.timedelta(hours=offset))


def fixed(offset: float) -> dt.tzinfo:
    """A zone that is the same offset all year — what `--utc-offset` means."""
    return dt.timezone(dt.timedelta(hours=offset))


def iso_z(moment: dt.datetime) -> str:
    """AW's own wire format: UTC with a `Z` suffix and no sub-second part."""
    return moment.astimezone(dt.timezone.utc).strftime("%Y-%m-%dT%H:%M:%SZ")


class Day:
    """A synthetic workday, written in local time, rendered as AW event streams.

    Every `add_*` returns self, so a day reads top-to-bottom in the order it happened:

        day().afk("07:00", "08:15").active("08:15", "10:57").afk("10:57", "11:45")

    Written at a fixed `offset` by default. Pass `zone=` an IANA name instead when the day
    is *about* the zone — a day containing a daylight-saving change cannot be written at
    one offset, because it does not have one. `live_aw` configures a zone day's
    `TIMESHEET_TIMEZONE` for the scripts, so such a day needs no `--utc-offset` and the
    resolution under test is the real one.
    """

    def __init__(self, date: dt.date = DEFAULT_DATE, offset: float = DEFAULT_OFFSET,
                 host: str = DEFAULT_HOST, zone: str | None = None):
        self.date = date
        self.offset = offset
        self.zone_name = zone
        self.tz = ZoneInfo(zone) if zone else fixed(offset)
        self.host = host
        self._afk: list[tuple[str, str, str]] = []
        self._window: list[tuple[str, str, str, str]] = []
        self._web: list[tuple[str, str, str, str, str]] = []   # browser, start, end, title, url
        self.classes: list[dict] = []

    # -- absolute time helpers ---------------------------------------------------------

    def at(self, local: str) -> dt.datetime:
        """The UTC instant of a local `HH:MM` on this day — for asserting against spans.

        The wall clock is read first and localised second, so `'09:15'` is a quarter past
        nine *whatever the offset was by then*. Adding the delta to a localised midnight
        instead would be absolute-time arithmetic, and on a 25-hour day every time after
        the change would land an hour early — the DSL would then reproduce exactly the
        bug the day was written to catch.

        A trailing `*` asks for the second pass over the hour a fall-back repeats, so a
        day can put events on both sides of a change that leaves the clock unmoved.
        """
        naive = dt.datetime.combine(self.date, dt.time(0, 0)) + parse_local(local)
        return (naive.replace(tzinfo=self.tz, fold=int(second_pass(local)))
                .astimezone(dt.timezone.utc))

    # -- building ----------------------------------------------------------------------

    def afk(self, start: str, end: str) -> "Day":
        self._afk.append((start, end, "afk"))
        return self

    def active(self, start: str, end: str) -> "Day":
        self._afk.append((start, end, "not-afk"))
        return self

    def thin(self, start: str, end: str, active_min: float = 6.0,
             idle_min: float = 4.0) -> "Day":
        """Alternating short active / short idle — what supervising a background agent
        looks like to the AFK watcher.

        No single idle reaches the break threshold, so `afk_blocks` reports no break and
        the stretch stays inside one active span; only `active_ratio` reveals it is thin.
        That combination is the skill's hardest judgement call, so scenarios need to be
        able to write it in one line.
        """
        _reject_second_pass("thin", start, end)
        t, stop = parse_local(start), parse_local(end)
        step_a, step_i = dt.timedelta(minutes=active_min), dt.timedelta(minutes=idle_min)
        while t < stop:
            nxt = min(t + step_a, stop)
            self.active(_fmt(t), _fmt(nxt))
            t = nxt
            if t >= stop:
                break
            nxt = min(t + step_i, stop)
            self.afk(_fmt(t), _fmt(nxt))
            t = nxt
        return self

    def locked(self, start: str, end: str, chunk_min: float = 14.0) -> "Day":
        """A screen lock, as AW actually records it: the AFK run arrives fragmented into
        chunks that each fall *under* the break threshold.

        The consequence is the documented quirk in `references/activitywatch.md` —
        `afk_blocks` reports `breaks: (none)` for a stretch that was plainly a break, and
        it surfaces only as a sub-0.4 `active_ratio` window.
        """
        _reject_second_pass("locked", start, end)
        t, stop = parse_local(start), parse_local(end)
        step = dt.timedelta(minutes=chunk_min)
        while t < stop:
            nxt = min(t + step, stop)
            self.afk(_fmt(t), _fmt(nxt))
            t = nxt
        return self

    def window(self, start: str, end: str, app: str, title: str) -> "Day":
        self._window.append((start, end, app, title))
        return self

    def web(self, start: str, end: str, title: str, url: str, browser: str = "firefox") -> "Day":
        self._web.append((browser, start, end, title, url))
        return self

    def classify(self, label: str, regex: str, ignore_case: bool = True) -> "Day":
        """Add an AW category rule, the way the AW settings endpoint returns them."""
        self.classes.append({"name": label.split(">"),
                             "rule": {"type": "regex", "regex": regex, "ignore_case": ignore_case}})
        return self

    # -- rendering ---------------------------------------------------------------------

    def event(self, start: str, *, seconds: float | None = None,
              minutes: float | None = None, data: dict | None = None, **fields) -> dict:
        """One rendered AW event on this day, not added to it — for a test that hands a
        list straight to a function instead of serving a whole day.

            d.event("10:17:29", seconds=1049, status="afk")
            d.event("09:00", minutes=90, status="not-afk")

        The duration is given in whichever unit the test reasons in, because that is
        the unit a reader checks it in: a threshold one second either side of 1050 is
        unreadable in minutes, and a 90-minute block is unreadable in seconds. `start`
        takes everything `at()` does — seconds, hours past 24, and the marker for the
        second pass over a repeated hour — which is what the edge suites used to hand-roll
        their own builders for. The payload is the keyword arguments, or `data=` when the
        test needs a shape a watcher would never emit.
        """
        if (seconds is None) == (minutes is None):
            raise ValueError("event() takes exactly one of seconds= or minutes=")
        if data is not None and fields:
            raise ValueError("event() takes either data= or keyword fields, not both")
        duration = seconds if seconds is not None else cast(float, minutes) * 60
        return {"timestamp": iso_z(self.at(start)), "duration": duration,
                "data": data if data is not None else fields}

    def _events(self, rows, data_for) -> list[dict]:
        out = []
        for row in rows:
            start, end = self.at(row[0]), self.at(row[1])
            out.append({"timestamp": iso_z(start),
                        "duration": (end - start).total_seconds(),
                        "data": data_for(row)})
        return out

    def afk_events(self) -> list[dict]:
        return self._events(self._afk, lambda r: {"status": r[2]})

    def window_events(self) -> list[dict]:
        return self._events(self._window, lambda r: {"app": r[2], "title": r[3]})

    def web_events(self, browser: str) -> list[dict]:
        rows = [r for r in self._web if r[0] == browser]
        return self._events([(r[1], r[2], r[3], r[4]) for r in rows],
                            lambda r: {"title": r[2], "url": r[3]})

    def buckets(self) -> dict[str, list[dict]]:
        """The bucket -> events mapping a fake AW server serves for this day."""
        out = {
            f"aw-watcher-afk_{self.host}": self.afk_events(),
            f"aw-watcher-window_{self.host}": self.window_events(),
        }
        for browser in ("firefox", "chrome"):
            evs = self.web_events(browser)
            if evs:
                out[f"aw-watcher-web-{browser}_{self.host}"] = evs
        return out

    def settings(self) -> dict:
        return {"classes": self.classes}

    def date_str(self) -> str:
        return self.date.isoformat()


def day(date: dt.date = DEFAULT_DATE, offset: float = DEFAULT_OFFSET,
        host: str = DEFAULT_HOST, zone: str | None = None) -> Day:
    return Day(date, offset, host, zone)


def with_heartbeats(events: list[dict], steps: int = 3) -> list[dict]:
    """Re-emit each event the way AW does while it is still running: same timestamp,
    progressively longer duration. `dedupe_heartbeats` has to collapse these back.

    The partial copies are appended *after* the full-length one so a consumer that
    took the last-seen duration rather than the longest would read short.
    """
    out = []
    for e in events:
        out.append(e)
        for i in range(1, steps):
            out.append({**e, "duration": e["duration"] * i / steps})
    return out


# --------------------------------------------------------------------------------------
# Fake HTTP servers
# --------------------------------------------------------------------------------------

Handler = Callable[[str, str, dict, dict | None], tuple[int, object]]

# A response with no body at all — zero bytes, `Content-Length: 0`. Harvest answers a
# DELETE this way. `json.dumps` cannot say it: `None` comes out as the four bytes `null`,
# which is a body, and a JSON one. Return this as the payload instead.
NO_BODY = object()

# What a route in `harvest_server(routes=...)` may be worth. A route value is declared
# `object` because a bare body is allowed to be anything, which leaves `callable()` as the
# only way to tell a function route from a body that happens to be one — a runtime question
# a type cannot answer. `RouteFn` names what such a function must return, so the `cast` at
# the one place that calls it is saying something checkable rather than silencing a check.
RouteFn = Callable[[dict, dict | None], tuple[int, object]]


class FakeServer:
    """A throwaway localhost HTTP server driven by one `handler(method, path, query, body)`
    callable returning `(status, json_serialisable)`.

    Used as a context manager; `.base` is the URL prefix to patch into the script under
    test. Every request is recorded in `.requests` so a test can assert on the *body sent*
    (which is how the "never post a bare `hours` field" invariant is pinned).
    """

    def __init__(self, handler: Handler):
        self.handler = handler
        self.requests: list[dict] = []
        outer = self

        class _H(BaseHTTPRequestHandler):
            protocol_version = "HTTP/1.1"

            def log_message(self, format, *args):   # keep pytest output clean
                pass

            def _run(self, method):
                parsed = urllib.parse.urlparse(self.path)
                query = {k: v[0] for k, v in urllib.parse.parse_qs(parsed.query).items()}
                length = int(self.headers.get("Content-Length") or 0)
                raw = self.rfile.read(length) if length else b""
                body = json.loads(raw) if raw else None
                outer.requests.append({"method": method, "path": parsed.path, "query": query,
                                       "body": body, "headers": dict(self.headers)})
                try:
                    status, payload = outer.handler(method, parsed.path, query, body)
                except Exception as exc:      # a broken fake must not hang the client
                    status, payload = 500, {"error": repr(exc)}
                data = b"" if payload is NO_BODY else json.dumps(payload).encode("utf-8")
                self.send_response(status)
                self.send_header("Content-Type", "application/json")
                self.send_header("Content-Length", str(len(data)))
                self.end_headers()
                self.wfile.write(data)

            def do_GET(self):
                self._run("GET")

            def do_POST(self):
                self._run("POST")

            def do_PATCH(self):
                self._run("PATCH")

            def do_DELETE(self):
                self._run("DELETE")

        self._server = ThreadingHTTPServer(("127.0.0.1", 0), _H)
        self.port = self._server.server_address[1]
        # poll_interval is how long shutdown() blocks; the 0.5s default made every
        # server-using test pay half a second of teardown.
        self._thread = threading.Thread(target=self._server.serve_forever,
                                        kwargs={"poll_interval": 0.01}, daemon=True)

    @property
    def base(self) -> str:
        return f"http://127.0.0.1:{self.port}"

    def __enter__(self) -> "FakeServer":
        self._thread.start()
        return self

    def __exit__(self, *exc):
        self._server.shutdown()
        self._server.server_close()
        self._thread.join(timeout=5)
        return False

    # -- assertion helpers -------------------------------------------------------------

    def sent(self, method: str, path_contains: str = "") -> list[dict]:
        return [r for r in self.requests
                if r["method"] == method and path_contains in r["path"]]


def _overlaps(event: dict, start: str | None, end: str | None) -> bool:
    """AW returns events overlapping the range, not just those starting inside it."""
    if not start or not end:
        return True
    s = dt.datetime.fromisoformat(event["timestamp"].replace("Z", "+00:00"))
    e = s + dt.timedelta(seconds=event["duration"])
    lo = dt.datetime.fromisoformat(start.replace("Z", "+00:00"))
    hi = dt.datetime.fromisoformat(end.replace("Z", "+00:00"))
    return e > lo and s < hi


def aw_server(buckets: dict[str, list[dict]], settings: dict | None = None,
              last_updated: dict[str, str] | None = None,
              settings_status: int = 200) -> FakeServer:
    """A fake ActivityWatch exposing `/api/0/buckets/`, `.../events` and `/api/0/settings`.

    `settings_status` != 200 simulates an AW build whose settings endpoint is absent,
    which is the real-world reason `load_classes()` has to survive an exception.
    """
    settings = settings if settings is not None else {"classes": []}
    last_updated = last_updated or {}

    def handler(method, path, query, body):
        if path == "/api/0/buckets/":
            return 200, {bid: {"id": bid,
                               "last_updated": last_updated.get(bid, "2026-05-28T12:00:00+00:00")}
                         for bid in buckets}
        if path == "/api/0/settings":
            if settings_status != 200:
                return settings_status, {"error": "not found"}
            return 200, settings
        if path.startswith("/api/0/buckets/") and path.endswith("/events"):
            bid = path[len("/api/0/buckets/"):-len("/events")]
            if bid not in buckets:
                return 404, {"error": "no such bucket"}
            evs = [e for e in buckets[bid] if _overlaps(e, query.get("start"), query.get("end"))]
            # AW hands back newest-first; the scripts must not assume chronological order.
            return 200, sorted(evs, key=lambda e: e["timestamp"], reverse=True)
        return 404, {"error": f"unrouted {path}"}

    return FakeServer(handler)


def harvest_server(routes: dict[tuple[str, str], object] | None = None,
                   handler: Handler | None = None) -> FakeServer:
    """A fake Harvest API. Either give a `(method, path)` -> payload map for the simple
    case, or a full handler for tests that need paging or per-call failures.

    Paths are matched exactly against the part after `/v2`, e.g. `("GET", "/users/me")`.
    """
    routes = routes or {}

    def default_handler(method: str, path: str, query: dict,
                        body: dict | None) -> tuple[int, object]:
        key = (method, path[len("/v2"):] if path.startswith("/v2") else path)
        if key not in routes:
            return 404, {"error": f"unrouted {method} {path}"}
        payload = routes[key]
        if callable(payload):                       # a function gets query + body
            return cast(RouteFn, payload)(query, body)
        if isinstance(payload, tuple) and len(payload) == 2 and isinstance(payload[0], int):
            status, response = payload              # an explicit (status, body) pair
            return status, response
        return 200, payload                         # a bare body means 200

    return FakeServer(handler or default_handler)


# --------------------------------------------------------------------------------------
# The provider's project catalog, as the fake serves it and as the scripts cache it
# --------------------------------------------------------------------------------------

ASSIGNMENTS = ("GET", "/users/me/project_assignments")


def task(tid: int, name: str, billable: bool) -> dict:
    """One task assignment row. `billable` is the assignment's own flag, which is the
    field an invoice is built from — the "(NB)" in a task's name is a human hint."""
    return {"billable": billable, "task": {"id": tid, "name": name}}


def project(pid: int, code: str, name: str = "Some project", tasks=(),
            client: str | None = None) -> dict:
    """One project assignment row, shaped as `/users/me/project_assignments` returns it.
    `client` is the client's name, which `harvest_lookup` matches on as well as the code
    and the name; a row without one is what most fixtures need."""
    row: dict = {"project": {"id": pid, "code": code, "name": name},
                 "task_assignments": list(tasks)}
    if client is not None:
        row["client"] = {"name": client}
    return row


def assignments_page(number: int, last: int, rows=()) -> dict:
    """One page of the catalog, with Harvest's `next_page` wiring: `None` on the last
    page, the next number otherwise. `refresh_catalogs` follows that chain, and a fixture
    that got it wrong would either stop a page early or never stop."""
    return {"project_assignments": list(rows),
            "page": number,
            "total_entries": 7,
            "next_page": None if number >= last else number + 1}


def paged_assignments(pages: list[dict], fail_on: int | None = None) -> dict:
    """Routes for `harvest_server`: serve `pages[n-1]` for `?page=n`, or a 500 for page
    `fail_on` — the mid-refresh outage the catalog write path has to survive intact."""
    def route(query, body):
        n = int(query.get("page", 1))
        if n == fail_on:
            return 500, {"error": "read replica unavailable"}
        return 200, pages[n - 1]
    return {ASSIGNMENTS: route}


def write_catalog(directory, files: dict[str, object]) -> None:
    """Write cached catalog pages the way `refresh_catalogs` leaves them on disk: one JSON
    file per page, `harvest_assignments.json` then `harvest_assignments_p<n>.json`. A test
    of the read path starts from these rather than from a refresh."""
    for name, payload in files.items():
        Path(directory, name).write_text(json.dumps(payload), encoding="utf-8")


# --------------------------------------------------------------------------------------
# Shared fixtures for the write scripts
# --------------------------------------------------------------------------------------

# A well-formed create, without the confirmation gate: project, task, date, start, end,
# notes. A test appends `--confirm` when it means to post. One copy, because a test that
# asserts on the body sent reads its expectation off these values.
CREATE_ARGS = ["48084036", "20753151", "2026-08-12", "09:00", "10:30", "Drafted the spec"]


def resource_warnings_from(fn) -> list:
    """Run `fn`, force a collection, and return any `ResourceWarning` it left behind.

    The warning being hunted is emitted from a destructor during garbage collection, so it
    has no stack relationship to the code that leaked — under this suite's
    `filterwarnings = error` it surfaces as an unraisable exception blamed on whichever
    test happened to be running when the collector fired. Three independent agents hit
    exactly that and each blamed a different test. Forcing the collection here pins the
    warning to its real cause, in the test that owns it.
    """
    with warnings.catch_warnings(record=True) as caught:
        warnings.simplefilter("always")
        fn()
        gc.collect()
    return [w for w in caught if issubclass(w.category, ResourceWarning)]


# --------------------------------------------------------------------------------------
# In-process CLI runner
# --------------------------------------------------------------------------------------

class CliResult(NamedTuple):
    code: int
    out: str
    err: str

    @property
    def lines(self) -> list[str]:
        return [ln for ln in self.out.splitlines() if ln.strip()]

    def json(self):
        return json.loads(self.out)


def run_cli(module, args: list) -> CliResult:
    """Run `module.main()` with `args` as its command line, in this process.

    Handles both `main()` conventions in the skill: `afk_blocks` / `activity_timeline`
    *return* an exit code, while `harvest_post` / `harvest_patch` / `harvest_list` call
    `sys.exit()`. A `sys.exit("message")` is folded back into stderr with code 1, which
    is what the shell would show.
    """
    out, err = io.StringIO(), io.StringIO()
    old_argv = sys.argv
    sys.argv = [getattr(module, "__file__", "script")] + [str(a) for a in args]
    code = 0
    try:
        with contextlib.redirect_stdout(out), contextlib.redirect_stderr(err):
            returned = module.main()
        code = 0 if returned is None else int(returned)
    except SystemExit as e:
        if e.code is None:
            code = 0
        elif isinstance(e.code, int):
            code = e.code
        else:
            err.write(str(e.code) + "\n")
            code = 1
    finally:
        sys.argv = old_argv
    return CliResult(code, out.getvalue(), err.getvalue())


