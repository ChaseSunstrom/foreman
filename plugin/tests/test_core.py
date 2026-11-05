"""Unit tests for fmcore: paths, locking, writes, redaction, ledger, briefs, intake, queue."""
import json
import multiprocessing
import os
import re
import subprocess
import time
import unittest
from unittest import mock

from helpers import ForemanTestCase, read_text, stub_claude

from sampo import core as c


class PathsAndProjects(ForemanTestCase):
    def setUp(self):
        super().setUp()
        # T-3222: run.py --sandbox turns the state fallback off for every class; these tests are about the fallback
        was = os.environ.pop("FOREMAN_STATE_FALLBACK", None)
        if was is not None:
            self.addCleanup(os.environ.__setitem__, "FOREMAN_STATE_FALLBACK", was)

    def test_foreman_home_honours_env(self):
        self.assertEqual(c.foreman_home(), self.home)
        self.assertEqual(c.state_dir(), os.path.join(self.home, "state"))

    def test_state_falls_back_when_foreman_home_is_read_only(self):
        # Sandboxes (claude plugin eval) and containers can mount ~/.claude read-only; fm must keep working.
        os.chmod(self.home, 0o500)
        try:
            os.environ["XDG_STATE_HOME"] = os.path.join(self.tmp, "xdg")
            self.assertEqual(c.state_dir(), os.path.join(self.tmp, "xdg", "foreman"))
            p = c.init_project(self.repo)
            self.assertTrue(p.dir.startswith(os.path.join(self.tmp, "xdg", "foreman")))
        finally:
            os.chmod(self.home, 0o700)

    def test_a_sandboxed_job_never_copies_state_to_a_fallback(self):
        # T-3222: inside sampo sandbox run the real state is read-only by design; copying all of it (361k files) into
        # the job's /tmp each time ran /tmp out of inodes. FOREMAN_STATE_FALLBACK=0 keeps the default, read-only.
        from unittest import mock
        os.environ["XDG_STATE_HOME"] = os.path.join(self.tmp, "xdg")
        default = os.path.join(self.home, "state")
        os.makedirs(default, exist_ok=True)
        os.chmod(default, 0o500)
        try:
            with mock.patch.dict(os.environ, {"FOREMAN_STATE_FALLBACK": "0"}):
                self.assertEqual(c.state_dir(), default)
            self.assertFalse(os.path.exists(os.path.join(self.tmp, "xdg", "foreman")), "nothing copied")
        finally:
            os.chmod(default, 0o700)

    def test_fallback_is_sticky_and_shared_and_migrates_existing_state(self):
        # A sandboxed fm (default read-only) and the hooks (default writable) must end up in the same place.
        os.environ["XDG_STATE_HOME"] = os.path.join(self.tmp, "xdg")
        alt = os.path.join(self.tmp, "xdg", "foreman")
        p = c.init_project(self.repo)
        c.log_event(p, "note", data={"x": 1})
        default = os.path.join(self.home, "state")
        os.chmod(self.home, 0o500)
        os.chmod(default, 0o500)
        try:
            self.assertEqual(c.state_dir(), alt)  # the sandboxed side activates the fallback
        finally:
            os.chmod(self.home, 0o700)
            os.chmod(default, 0o700)
        self.assertEqual(c.state_dir(), alt, "the unsandboxed side (hooks) follows the marker")
        self.assertTrue(any(e["event"] == "note" for e in c.ledger_tail(c.find_project(self.repo))),
                        "existing state was copied across")

    def test_a_link_someone_else_planted_is_refused(self):
        # T-1317: _private stat'ed through links, so another user's /tmp/foreman-state-<uid> link to one of our 0700
        # dirs (~/.ssh) passed, and the fallback copied state into it
        from unittest import mock
        victim, link = os.path.join(self.tmp, "ssh"), os.path.join(self.tmp, "fallback")
        os.makedirs(victim, mode=0o700)
        os.symlink(victim, link)
        real = os.lstat

        def lstat(path, *a, **k):
            st = real(path, *a, **k)
            return os.stat_result(tuple(st)[:4] + (os.getuid() + 1,) + tuple(st)[5:]) if str(path) == link else st
        default = os.path.join(self.home, "state")
        os.makedirs(default, exist_ok=True)
        os.chmod(self.home, 0o500)
        os.chmod(default, 0o500)
        try:
            with mock.patch.object(c, "state_fallbacks", lambda: [link]):
                with mock.patch.object(c.os, "lstat", lstat):
                    self.assertEqual(c.state_dir(), default, "someone else's link is never a fallback")
                self.assertEqual(os.listdir(victim), [])
                self.assertEqual(c.state_dir(), link, "a link of our own still is")
        finally:
            os.chmod(self.home, 0o700)
            os.chmod(default, 0o700)

    def test_a_marker_others_could_have_planted_is_ignored(self):
        # /tmp is shared: a marker in a dir other users can write would redirect all of this user's state.
        alt = os.path.join(self.tmp, "xdg", "foreman")
        os.makedirs(alt)
        with open(os.path.join(alt, ".foreman-state.json"), "w") as f:
            json.dump({"default": os.path.join(self.home, "state")}, f)
        os.chmod(alt, 0o777)
        self.assertEqual(c.state_dir(), os.path.join(self.home, "state"))
        os.chmod(alt, 0o755)
        self.assertEqual(c.state_dir(), alt)

    def test_restore_moves_fallback_state_back_once_the_default_is_writable(self):
        default = os.path.join(self.home, "state")
        c.init_project(self.repo)
        os.chmod(self.home, 0o500)
        os.chmod(default, 0o500)
        try:
            alt = c.state_dir()
            self.assertNotEqual(alt, default)
            with self.assertRaises(OSError):  # still read-only (the sandbox is still there): nothing moves
                c.restore_default_state()
            self.assertEqual(c.state_dir(), alt)
        finally:
            os.chmod(self.home, 0o700)
            os.chmod(default, 0o700)
        c.log_event(c.find_project(self.repo), "note", data={"in": "fallback"})
        self.assertEqual(c.restore_default_state(), default)
        self.assertEqual(c.state_dir(), default)
        self.assertTrue(any(e["event"] == "note" for e in c.ledger_tail(c.find_project(self.repo))))
        c.log_event(c.find_project(self.repo), "note", data={"in": "default"})
        os.chmod(self.home, 0o500)
        os.chmod(default, 0o500)
        try:  # a later fallback starts from the current default, not the stale copy left behind
            self.assertEqual(c.state_dir(), alt)
            self.assertIn({"in": "default"}, [e.get("data") for e in c.ledger_tail(c.find_project(self.repo))])
        finally:
            os.chmod(self.home, 0o700)
            os.chmod(default, 0o700)

    def test_worktree_id_tracks_edits_and_leaves_the_real_index_alone(self):
        f = os.path.join(self.repo, "README.md")
        index = os.path.join(self.repo, ".git", "index")
        before = c.worktree_id(self.repo)
        with open(index, "rb") as fh:
            idx = fh.read()
        with open(f, "w") as fh:  # same size, same second as the commit: stat data alone can't tell
            fh.write("# APP\n")
        after = c.worktree_id(self.repo)
        self.assertNotEqual(before, after)
        with open(os.path.join(self.repo, "new.py"), "w") as fh:
            fh.write("x = 1\n")
        self.assertNotEqual(after, c.worktree_id(self.repo), "untracked files count")
        with open(index, "rb") as fh:
            self.assertEqual(fh.read(), idx)
        subprocess.run(["git", "-C", self.repo, "add", "-A"], check=True)
        subprocess.run(["git", "-C", self.repo, "commit", "-qm", "x"], check=True)
        self.assertEqual(c.worktree_id(self.repo), c.worktree_id(self.repo))

    def test_foreman_state_env_overrides(self):
        os.environ["FOREMAN_STATE"] = os.path.join(self.tmp, "elsewhere")
        self.assertEqual(c.state_dir(), os.path.join(self.tmp, "elsewhere"))

    def test_foreman_home_defaults_under_user_home(self):
        del os.environ["FOREMAN_HOME"]
        os.environ["HOME"], old = self.tmp, os.environ["HOME"]
        try:
            self.assertEqual(c.foreman_home(), os.path.join(self.tmp, ".claude", "foreman"))
        finally:
            os.environ["HOME"] = old
            os.environ["FOREMAN_HOME"] = self.home

    def test_slug_is_dirname_plus_stable_hash(self):
        s1 = c.slug_for("/a/b/My App")
        self.assertRegex(s1, r"^my-app-[0-9a-f]{6}$")
        self.assertEqual(s1, c.slug_for("/a/b/My App"))
        self.assertNotEqual(s1, c.slug_for("/other/My App"))

    def test_git_root_found_from_subdir(self):
        sub = os.path.join(self.repo, "src", "deep")
        os.makedirs(sub)
        self.assertEqual(c.git_root(sub), self.repo)
        self.assertIsNone(c.git_root(self.tmp))

    def test_init_project_creates_state_and_registry(self):
        p = c.init_project(self.repo)
        self.assertTrue(os.path.isdir(os.path.join(p.dir, "tasks")))
        meta = c.read_meta(p)
        self.assertEqual(meta["path"], self.repo)
        self.assertFalse(meta["sensitive"])
        with open(os.path.join(c.state_dir(), "registry.md")) as f:
            self.assertIn(p.slug, f.read())

    def test_find_project_auto_registers_git_repo_only_when_asked(self):
        self.assertIsNone(c.find_project(self.repo))
        p = c.find_project(self.repo, create=True)
        self.assertEqual(p.root, self.repo)
        self.assertEqual(c.find_project(os.path.join(self.repo)).slug, p.slug)

    def test_find_project_non_git_dir_needs_init(self):
        plain = os.path.join(self.tmp, "plain")
        os.makedirs(plain)
        self.assertIsNone(c.find_project(plain, create=True))
        p = c.init_project(plain)
        self.assertEqual(c.find_project(os.path.join(plain)).slug, p.slug)

    def test_detects_sensitive_repo_from_local_settings(self):
        os.makedirs(os.path.join(self.repo, ".claude"))
        with open(os.path.join(self.repo, ".claude", "settings.local.json"), "w") as f:
            json.dump({"permissions": {"defaultMode": "default"}}, f)
        p = c.init_project(self.repo)
        self.assertTrue(c.read_meta(p)["sensitive"])


class WritesAndLocks(ForemanTestCase):
    def test_write_atomic_replaces_content_and_leaves_no_temp(self):
        path = os.path.join(self.tmp, "x", "f.txt")
        c.write_atomic(path, "one")
        c.write_atomic(path, "two")
        with open(path) as f:
            self.assertEqual(f.read(), "two")
        self.assertEqual(os.listdir(os.path.dirname(path)), ["f.txt"])

    def test_lock_times_out_when_held_by_another_process(self):
        d = os.path.join(self.tmp, "lockdir")
        os.makedirs(d)
        ready = multiprocessing.Event()
        proc = multiprocessing.Process(target=_hold_lock, args=(d, ready, 1.5))
        proc.start()
        try:
            ready.wait(5)
            t0 = time.monotonic()
            with self.assertRaises(c.LockTimeout):
                with c.lock(d, timeout=0.3):
                    pass
            self.assertLess(time.monotonic() - t0, 1.2)  # wall clock: the lock timeout=0.3 deadline (waits on a child)
        finally:
            proc.join()
        with c.lock(d, timeout=0.3):
            pass


def _hold_lock(d, ready, secs):
    with c.lock(d, timeout=1):
        ready.set()
        time.sleep(secs)


class Redaction(unittest.TestCase):
    CASES = [
        "export ANTHROPIC_API_KEY=sk-ant-api03-abcdefghijklmnop",  # pragma: allowlist secret
        "token: ghp_ABCDEFGHIJKLMNOPQRSTUVWXYZ012345",  # pragma: allowlist secret
        "curl -H 'Authorization: Bearer abc.def.ghi' https://x",
        "password=hunter2hunter2",
        "aws AKIAABCDEFGHIJKLMNOP",  # pragma: allowlist secret
        "git clone https://user:s3cretpass@github.com/x/y",  # pragma: allowlist secret
        "-----BEGIN OPENSSH PRIVATE KEY-----\nAAAA\n-----END OPENSSH PRIVATE KEY-----",  # pragma: allowlist secret
        "jwt eyJhbGciOiJIUzI1NiJ9.eyJzdWIiOiIxMjM0NTY3ODkwIn0.SflKxwRJSMeKKF2QT4fwpMeJf36POk6yJV_adQssw5c",  # pragma: allowlist secret
    ]
    SECRETS = ["sk-ant-api03-abcdefghijklmnop", "ghp_ABCDEFGHIJKLMNOPQRSTUVWXYZ012345", "abc.def.ghi",  # pragma: allowlist secret
               "hunter2hunter2", "AKIAABCDEFGHIJKLMNOP", "s3cretpass", "AAAA", "SflKxwRJSMeKKF2QT4fwpMeJf36POk6yJV_adQssw5c"]  # pragma: allowlist secret

    def test_known_secret_shapes_are_redacted(self):
        for text, secret in zip(self.CASES, self.SECRETS):
            with self.subTest(text=text):
                out = c.redact(text)
                self.assertNotIn(secret, out)
                self.assertIn("REDACTED", out)

    def test_ordinary_text_is_untouched(self):
        for text in ["run pytest -q", "the token count is 400", "password field validation", "key: value"]:
            self.assertEqual(c.redact(text), text)

    def test_a_credential_named_json_key_is_redacted(self):  # T-1733
        for s in (json.dumps({"password": "hunter2x", "user": "ann"}), "{'api_key': 'abcd1234'}",  # pragma: allowlist secret
                  json.dumps(json.dumps({"client_secret": "s3cr3tvalue"})),  # pragma: allowlist secret
                  '"auth_token" : "zzzz9999"'):  # pragma: allowlist secret
            with self.subTest(s=s):
                out = c.redact(s)
                for secret in ("hunter2x", "abcd1234", "s3cr3tvalue", "zzzz9999"):
                    self.assertNotIn(secret, out)
                self.assertIn("REDACTED", out)
        self.assertIsInstance(json.loads(c.redact(json.dumps({"password": "hunter2x"}))), dict)  # pragma: allowlist secret
        self.assertEqual(c.redact('{"tokens": 1234, "token_count": "5000", "secret_kinds": "a JWT"}'),
                         '{"tokens": 1234, "token_count": "5000", "secret_kinds": "a JWT"}')

    def test_redact_obj_reads_key_names(self):  # T-1733: log_event stored {"password": "x"} as it was
        got = c.redact_obj({"password": "x", "nested": [{"apiKey": "abcd"}, {"AUTH_TOKEN": "t"}], "tokens": 400,
                            "subagent_tokens": 12, "token_count": 3, "secret_kinds": ["a JWT"], "pwd": None})
        self.assertEqual(got["password"], "[REDACTED]")
        self.assertEqual(got["nested"], [{"apiKey": "[REDACTED]"}, {"AUTH_TOKEN": "[REDACTED]"}])
        self.assertEqual((got["tokens"], got["subagent_tokens"], got["token_count"], got["secret_kinds"], got["pwd"]),
                         (400, 12, 3, ["a JWT"], None))

    def test_redacted_json_stays_valid(self):
        s = json.dumps({"cmd": "export TOKEN=abcd1234efgh && curl -H \"Authorization: Bearer xyz123\""})
        self.assertIsInstance(json.loads(c.redact(s)), dict)


class Ledger(ForemanTestCase):
    def test_lane_worktree_paths_map_to_repo_paths(self):
        # T-0807: builders edit in .claude/worktrees/<lane>/, so after the merge the close's scope check saw those
        # paths, not the repo files they stand for (T-0779, T-0786, T-0804 each needed a logged reason)
        p = c.init_project(self.repo)
        wt = os.path.join(p.root, ".claude", "worktrees", "agent-a1b2", "plugin", "lib", "a.py")
        c.log_event(p, "touched", task="T-0001", data={"file": wt})
        c.log_event(p, "touched", task="T-0001", data={"file": os.path.join(p.root, "README.md")})
        self.assertEqual(sorted(c.task_touches(p, "T-0001")), ["README.md", "plugin/lib/a.py"])

    def test_tail_returns_n_events_beyond_64k(self):
        p = c.init_project(self.repo)
        c.log_event(p, "touched", task="T-0001", data={"file": "x.py"})
        for i in range(600):  # ~120 KB of later events
            c.log_event(p, "tool", data={"pad": "y" * 150, "i": i})
        events = c.ledger_tail(p, 1000)
        self.assertEqual(len(events), 601)
        self.assertEqual(events[0]["event"], "touched")
        self.assertEqual(len(c.ledger_tail(p, 5)), 5)

    def test_log_event_appends_redacted_json_lines(self):
        p = c.init_project(self.repo)
        c.log_event(p, "note", task="T-0001", data={"cmd": "export API_KEY=abcdef123456"}, session="s1")
        c.log_event(p, "note2")
        with open(os.path.join(p.dir, "ledger.jsonl")) as f:
            lines = [json.loads(l) for l in f]
        self.assertEqual([l["event"] for l in lines[-2:]], ["note", "note2"])
        rec = lines[-2]
        self.assertEqual(set(rec), {"prev", "ts", "session_id", "project", "task", "event", "data"})  # T-1065: chained
        self.assertEqual(rec["session_id"], "s1")
        self.assertNotIn("abcdef123456", json.dumps(rec))
        self.assertRegex(rec["ts"], r"^\d{4}-\d\d-\d\dT\d\d:\d\d:\d\dZ$")


SAMPLE = """---
id: T-0012
type: FIX
tier: M
status: active
priority: normal
scope: [src/auth/**, tests/auth/**]
depends_on: [T-0003]
source: user   # user|discovered
allow: []
created: 2026-09-25T10:00:00Z
updated: 2026-09-25T10:00:00Z
---
# Fix login timeout on slow networks
## Raw request
> FIX: login times out after 30s on slow networks
## Acceptance criteria
- [ ] login succeeds at 3G latency — verify with `pytest tests/auth -k slow`
- [x] no regression — verify with `pytest`
## Steps
1. [x] Reproduce with a failing test
2. [ ] Add retry with backoff  <- CURRENT
3. [ ] Update docs
## Resume here
Retry helper half written.
## Verification evidence
- (step 1) `pytest tests/auth -k slow` → 1 failed as expected (2026-09-25T10:05:00Z)
- (ac 2) `pytest` → 40 passed (2026-09-25T10:06:00Z)
## Log
- 2026-09-25T10:00:00Z created
"""


class Briefs(unittest.TestCase):
    def test_parse_frontmatter_lists_comments_and_title(self):
        b = c.Brief.parse(SAMPLE)
        self.assertEqual(b.id, "T-0012")
        self.assertEqual(b.type, "FIX")
        self.assertEqual(b.meta["scope"], ["src/auth/**", "tests/auth/**"])
        self.assertEqual(b.meta["depends_on"], ["T-0003"])
        self.assertEqual(b.meta["source"], "user")
        self.assertEqual(b.meta["allow"], [])
        self.assertEqual(b.title, "Fix login timeout on slow networks")

    def test_round_trip_is_lossless(self):
        self.assertEqual(c.Brief.parse(SAMPLE).render(), SAMPLE)

    def test_plain_strips_hidden_characters_and_passes_printable_text_through(self):
        # T-2017: plain() checked every character in Python; printable text now skips the scan
        for bad in ("\x1b", "\x07", "\n", "‮", "​", " ", " ", "️", "\U000e0100"):
            self.assertEqual(c.plain(f"a{bad}b"), "ab", repr(bad))
        for good in ("café 日本 ✓", "a b", "x" * 500, ""):
            self.assertEqual(c.plain(good), good)
        self.assertEqual(c.plain(None), "")

    def test_sections_are_split_only_when_read_and_copies_stay_apart(self):
        # T-2015: a hook loads every brief but reads few past their frontmatter; splitting 9 MB of sections cost ~50 ms
        b = c.Brief.parse(SAMPLE)
        self.assertIsInstance(b._sections, str, "parse leaves the sections unsplit")
        self.assertEqual(b.title, "Fix login timeout on slow networks")
        x = b.copy()
        x.set_section("Log", "changed\n")
        self.assertEqual(b.render(), SAMPLE, "a copy's edit never reaches the original")
        self.assertIn("## Log\nchanged\n", x.render())
        self.assertIn("Add retry with backoff", b.section("Steps"))

    def test_steps_and_current(self):
        steps = c.Brief.parse(SAMPLE).steps()
        self.assertEqual([(s.n, s.done, s.current) for s in steps], [(1, True, False), (2, False, True), (3, False, False)])
        self.assertEqual(steps[1].text, "Add retry with backoff")

    def test_evidence_lookup_by_step_and_ac(self):
        b = c.Brief.parse(SAMPLE)
        self.assertTrue(b.has_evidence(step=1))
        self.assertFalse(b.has_evidence(step=2))
        self.assertTrue(b.has_evidence(ac=2))
        self.assertFalse(b.has_evidence(ac=1))

    def test_typed_text_cant_forge_a_world_mark(self):  # T-2398
        self.assertNotIn("[world", c._unmarked("ran fine [world 0123456789]"))

    def test_mark_step_requires_evidence(self):
        b = c.Brief.parse(SAMPLE)
        with self.assertRaises(c.PolicyError):
            b.mark_step(2)
        b.add_evidence("pytest tests/auth", "3 passed", step=2, ts="2026-09-25T11:00:00Z")
        b.mark_step(2)
        steps = b.steps()
        self.assertTrue(steps[1].done)
        self.assertTrue(steps[2].current, "marking the current step done advances CURRENT")

    def test_add_step_and_set_current(self):
        b = c.Brief.parse(SAMPLE)
        b.add_step("Changelog entry")
        b.set_current(4)
        self.assertEqual([s.current for s in b.steps()], [False, False, False, True])

    def test_add_step_creates_current_marker_on_first_step(self):
        b = c.Brief.new("T-0001", "Do a thing", "FEATURE", "S", now="2026-01-01T00:00:00Z")
        b.add_step("first")
        b.add_step("second")
        self.assertEqual([s.current for s in b.steps()], [True, False])

    def test_acceptance_criteria_parse_and_check(self):
        b = c.Brief.parse(SAMPLE)
        self.assertEqual([(a.n, a.checked) for a in b.acceptance()], [(1, False), (2, True)])
        with self.assertRaises(c.PolicyError):
            b.check_ac(1)
        b.add_evidence("pytest tests/auth -k slow", "1 passed", ac=1)
        b.check_ac(1)
        self.assertTrue(all(a.checked for a in b.acceptance()))

    def test_done_blockers_lists_what_is_missing(self):
        b = c.Brief.parse(SAMPLE)
        reasons = b.done_blockers()
        self.assertTrue(any("step 2" in r for r in reasons))
        self.assertTrue(any("criterion 1" in r for r in reasons))

    def _finished(self, tier, docs=True):
        b = c.Brief.new("T-0001", "Do a thing", "FEATURE", tier, now="2026-01-01T00:00:00Z")
        if docs and tier in ("M", "L"):
            b.set_section("Docs impact", "none: test fixture")
        b.add_step("work")
        b.add_evidence("make test", "ok", step=1, ts="2026-01-01T10:00:00Z")
        b.mark_step(1)
        return b

    def test_audits_required_by_tier(self):
        s = self._finished("S")
        self.assertTrue(any("audit" in r for r in s.done_blockers()))
        s.add_audit("intent", "fm-reviewer", "ok", ts="2026-01-01T11:00:00Z")
        self.assertIn("audit missing: self", s.done_blockers(), "one lens doesn't replace the five-lens self checklist")
        s.add_audit("self", "lens checklist", "no findings", ts="2026-01-01T11:00:00Z")
        self.assertEqual(s.done_blockers(), [])
        m = self._finished("M")
        m.add_audit("intent", "fm-reviewer", "ok", ts="2026-01-01T11:00:00Z")
        self.assertTrue(any("audit" in r for r in m.done_blockers()))
        m.add_audit("edge", "fm-reviewer", "1 finding fixed", ts="2026-01-01T11:00:00Z")
        self.assertEqual(m.done_blockers(), [])
        big = self._finished("L")
        for lens in ("intent", "adversary", "edge", "operator"):
            big.add_audit(lens, "fm-reviewer", "ok", ts="2026-01-01T11:00:00Z")
        self.assertEqual([r for r in big.done_blockers() if "audit" in r], ["audit missing: maintainer"])
        big.add_audit("maintainer", "fm-reviewer", "ok", ts="2026-01-01T11:00:00Z")
        self.assertEqual(big.done_blockers(), [])

    def test_m_and_l_need_a_docs_impact_before_done(self):
        m = self._finished("M", docs=False)
        m.add_audit("intent", "fm-reviewer", "ok", ts="2026-01-01T11:00:00Z")
        m.add_audit("edge", "fm-reviewer", "ok", ts="2026-01-01T11:00:00Z")
        self.assertIn("docs impact", " ".join(m.done_blockers()))
        m.set_section("Docs impact", "none: internal refactor, no user-visible change")
        self.assertEqual(m.done_blockers(), [])
        s = self._finished("S")
        s.add_audit("self", "checklist", "ok", ts="2026-01-01T11:00:00Z")
        self.assertEqual(s.done_blockers(), [], "S tasks don't need it")

    def test_audit_must_postdate_the_last_change(self):
        b = self._finished("S")
        b.add_audit("self", "checklist", "ok", ts="2026-01-01T09:00:00Z")  # before the step evidence
        self.assertTrue(any("audit" in r for r in b.done_blockers()))
        b.add_audit("self", "checklist", "ok", ts="2026-01-01T11:00:00Z")
        self.assertEqual(b.done_blockers(), [])
        self.assertTrue(any("audit" in r for r in b.done_blockers(since="2026-01-01T12:00:00Z")), "edited after audit")

    def test_unknown_lens_is_rejected(self):
        with self.assertRaises(ValueError):
            self._finished("S").add_audit("vibes", "x", "y")

    def test_new_brief_has_frontmatter_and_raw_request(self):
        b = c.Brief.new("T-0007", "Export CSV", "FEATURE", "M", raw="FEATURE: export report as CSV @src/reports",
                        scope=["src/reports"], now="2026-01-01T00:00:00Z")
        text = b.render()
        self.assertTrue(text.startswith("---\nid: T-0007\n"))
        self.assertIn("> FEATURE: export report as CSV @src/reports", text)
        self.assertEqual(c.Brief.parse(text).meta["scope"], ["src/reports"])
        self.assertEqual(c.Brief.parse(text).status, "planned")

    def test_resume_auto_block_is_replaced_not_duplicated(self):
        b = c.Brief.parse(SAMPLE)
        b.set_resume_auto("- step 2/3\n- git: 1 changed")
        b.set_resume_auto("- step 3/3")
        sec = b.section("Resume here")
        self.assertIn("Retry helper half written.", sec)
        self.assertEqual(sec.count("<!-- auto -->"), 1)
        self.assertIn("step 3/3", sec)
        self.assertNotIn("step 2/3", sec)


class BriefLines(unittest.TestCase):
    """T-1616: step and criterion lines parse in linear time (a lazy scan before \\s*$ was quadratic on a run of
    spaces: 20,000 took 1.5 s, and a pulled brief can hold one)."""

    def test_a_long_run_of_spaces_parses_fast_with_the_same_groups(self):
        import time
        for rx, line in ((c._STEP_RE, "1. [ ] a" + " " * 50000 + "b  <- CURRENT"), (c._AC_RE, "- [ ] a" + " " * 50000 + "b")):
            t = time.process_time()
            m = rx.match(line)
            self.assertLess(time.process_time() - t, 0.5)  # CPU: in-process regex
            self.assertTrue(m.groups()[-2 if rx is c._STEP_RE else -1].endswith("b"))
        self.assertEqual(c._STEP_RE.match("1. [x] build it  <- CURRENT").groups(), ("1", "x", "build it", "  <- CURRENT"))
        self.assertEqual(c._STEP_RE.match("3. [X]  <- CURRENT").groups(), ("3", "X", "<- CURRENT", None))  # as before
        self.assertEqual(c._STEP_RE.match("3. [ ] <- CURRENT x").groups(), ("3", " ", "<- CURRENT x", None))
        self.assertEqual(c._AC_RE.match("- [x] a  b  ").groups(), ("x", "a  b"))
        self.assertEqual(c._AC_RE.match("- [ ]  ").groups(), (" ", ""))


class Stages(unittest.TestCase):
    """The harness derives stage and the one next required action from the brief itself (T-0012)."""

    def setUp(self):  # T-2341: these read plan_gaps' own content; the cold rival read has its tests in test_second
        env = mock.patch.dict(os.environ, {"FOREMAN_NO_RIVAL": "1"})
        env.start()
        self.addCleanup(env.stop)

    def brief(self, tier="S", type_="FIX", status="planned"):
        b = c.Brief.new("T-0001", "Fix login", type_, tier, now="2026-01-01T00:00:00Z", status=status)
        return b

    def plan(self, b):
        b.set_section("Interpretation", "Reading 1: login times out on slow networks.\nReading 2: the server is slow.")
        b.set_section("Approach (options → choice → why)",
                      "1) retry with backoff; fails if: retries pile up 2) use what exists: a longer timeout; likely outcome: too slow "
                      "3) do less: a queue; breaks ordering. Choice 1 (80%): cheapest.")
        b.set_section("Risks and rollback", "Retries pile up; revert the commit.")
        b.add_ac("login works on 3G", verify="pytest -k slow")
        b.add_step("reproduce")
        return b

    def test_plan_gaps_check_content_by_tier(self):  # T-2269
        def gaps(b):
            return " | ".join(c.plan_gaps(b, "full"))
        AP = "Approach (options → choice → why)"
        for tier in ("M", "L"):
            b = self.plan(self.brief(tier))
            self.assertEqual(c.plan_gaps(b, "full"), [])
            b.set_section(AP, "Retry with backoff vs longer timeout → retry. Choice: retry. In 2 steps, 3 files.")
            self.assertIn("3+ options", gaps(b))
            self.assertIn("sampo task set", gaps(b))  # the gap names its fix
            a, b2, c3 = "reuse existing code; fails if: x", "do less, skip it; fails if: y", "a queue; breaks z"  # T-2335
            for text in (f"1. {a}\n2. {b2}\n3. {c3}\nChosen: a (80%)", f"- {a}\n- {b2}\n- {c3}\nchose a (80%)",
                         f"Option A: {a}\nOption B: {b2}\nOption C: {c3}\nChoice: B (80%)"):
                b.set_section(AP, text)
                self.assertEqual(c.plan_gaps(b, "full"), [], text)
            b.set_section(AP, "1) a 2) b 3) c")
            self.assertIn("choice", gaps(b))
        m = self.plan(self.brief("M"))
        m.set_section("Interpretation", "One reading.")
        m.set_section("Risks and rollback", "")
        self.assertIn("2+ readings", gaps(m))  # T-2335: M needs 2 readings too, but not the risks section
        m.set_section("Interpretation", "Reading 1: a. Reading 2: b.")
        self.assertEqual(c.plan_gaps(m, "full"), [])
        big = self.plan(self.brief("L"))
        big.set_section("Interpretation", "One reading.")
        self.assertIn("2+ readings", gaps(big))
        big.set_section("Interpretation", "1. this\n2. that")
        self.assertEqual(c.plan_gaps(big, "full"), [])
        big.set_section("Risks and rollback", "")
        self.assertIn("Risks and rollback", gaps(big))

    def test_a_low_confidence_assumption_waits_for_research_or_a_spike(self):  # T-2269
        b = self.plan(self.brief("M"))
        b.add_assumption("the API is paged (low)")
        self.assertIn("research", " ".join(c.plan_gaps(b, "full")))
        b.set_section(c.Brief.ASSUMPTIONS, "- [assumed] the API is paged (low)\n- [assumed] other (high)\n")
        self.assertIn("research", " ".join(c.plan_gaps(b, "full")))
        for line in ("- [assumed] the API is paged (low); see research/api-paging",  # T-2338: a typed line is no evidence
                     "- [assumed] the API is paged (low); spike T-0042",
                     "- [verified: ran it] the API is paged (low)"):
            b.set_section(c.Brief.ASSUMPTIONS, line + "\n")
            self.assertIn("cold reader", " ".join(c.plan_gaps(b, "full")), line)
        b.mark_assumption(1, "verified", "ran it", cold=True)  # fm's own mark: a command passed and a cold reader agreed
        self.assertEqual(c.plan_gaps(b, "full"), [])
        s = self.brief("S")
        s.add_ac("works")
        s.add_step("do it")
        s.add_assumption("x (low)")
        self.assertIn("research", " ".join(c.plan_gaps(s, "full")))  # any tier

    def test_a_task_already_started_is_not_regated(self):  # T-2269
        b = self.plan(self.brief("L"))
        b.set_section("Approach (options → choice → why)", "just do it")
        b.add_assumption("x (low)")
        self.assertTrue(c.plan_gaps(b, "full"))
        for st in ("active", "verifying", "done"):
            b.meta["status"] = st
            self.assertEqual(c.plan_gaps(b, "full"), [], st)
        b.meta["status"] = "planned"  # a paused task is planned again: ever started is what exempts it
        self.assertTrue(c.plan_gaps(b, "full"))
        for key in ("plan0_at", "base", "base_tree"):
            q = self.plan(self.brief("L"))
            q.set_section("Approach (options → choice → why)", "just do it")
            q.meta[key] = "x"
            self.assertEqual(c.plan_gaps(q, "full"), [], key)
        q = self.plan(self.brief("L"))
        q.set_section("Approach (options → choice → why)", "just do it")
        q.add_evidence("true", "ok", step=1)
        q.mark_step(1)
        self.assertEqual(c.plan_gaps(q, "full"), [], "a done step")
        d = self.plan(self.brief("L"))
        d.set_section("Approach (options → choice → why)", "just do it")
        d.add_evidence("true", "ok", ac=1)
        self.assertEqual(c.plan_gaps(d, "full"), [], "evidence")

    def test_option_formats_and_hollow_markers(self):  # T-2269 review
        AP = "Approach (options → choice → why)"
        e, l, o = "reuse existing code; fails if: p", "do less, skip it; fails if: q", "a queue; breaks r"  # T-2335
        real = (f"Options: (1) {e} (2) {l} (3) {o} Choice 2 (80%): two",
                f"1) --bench on evidence; fails if: p 2) `fm bench` verb, reuse existing; breaks r 3) \"last commit\" compare, "
                f"do less; fails if: q. Choice 1 (80%)",  # T-2285: flags, code
                f"1) {e} 2) {l} 3) {o} Choice 1 (80%)",
                f"Options: (A) {e} (B) {l} (C) {o} Choice: A (80%)",
                f"A) {e}\nB. {l}\nC) {o}\nDecision: A (80%)",
                f"Option A: {e}\nApproach B: {l}\nOption C: {o}\nGo with B (80%)",
                f"**Option 1** {e}\n**Option 2** {l}\n### Option 3\n{o}\nChoose 1 (80%)",
                f"1. {e} 2. {l} 3. {o} Chosen: 1 (80%)")
        for text in real:
            b = self.plan(self.brief("M"))
            b.set_section(AP, text)
            self.assertEqual(c.plan_gaps(b, "full"), [], text)
        for text in ("1) … 2) … 3) … Choice 1 (80%): …", "- …\n- …\n- …\nChoice: …", "Option A:\nOption B:\nOption C:\nChoice"):
            b = self.plan(self.brief("M"))
            b.set_section(AP, text)
            self.assertTrue(c.plan_gaps(b, "full"), text)
        b.set_section(AP, "1) a 2) b Choice 1")
        self.assertIn("names 2 options", " ".join(c.plan_gaps(b, "full")))
        self.assertIn("T-0001", " ".join(c.plan_gaps(b, "full")))
        big = self.plan(self.brief("L"))
        big.set_section("Interpretation", "A reading of the request that reads it once; reading it again changes nothing, reading.")
        self.assertIn("2+ readings", " ".join(c.plan_gaps(big, "full")))
        big.set_section("Interpretation", "- first\n- second")  # T-2335: a bullet is a scope line, not a reading
        self.assertIn("2+ readings", " ".join(c.plan_gaps(big, "full")))
        big.set_section("Interpretation", "Reading 1: first thing. Reading 2: second thing.")
        self.assertEqual(c.plan_gaps(big, "full"), [])

    def test_plan_gaps_by_tier(self):
        s = self.brief("S")
        self.assertEqual(sorted(c.plan_gaps(s)), ["acceptance criterion", "step"])
        s.add_ac("works")
        s.add_step("do it")
        self.assertEqual(c.plan_gaps(s), [])
        m = self.brief("M")
        m.add_ac("works")
        m.add_step("do it")
        self.assertEqual(sorted(c.plan_gaps(m)), ["Approach", "Interpretation", "verify command on criterion 1"])
        big = self.plan(self.brief("L"))
        self.assertEqual(c.plan_gaps(big), ["approval (L tier, standard autonomy)"])
        self.assertEqual(c.plan_gaps(big, autonomy="full"), [])
        big.meta["approved"] = True
        self.assertEqual(c.plan_gaps(big), [])

    def test_a_confirm_gap_says_why_the_task_waits(self):  # T-1750
        s = self.brief("S")
        s.add_ac("works")
        s.add_step("do it")
        s.meta["confirm"] = True
        self.assertIn("a child found this request in an old session", c.plan_gaps(s)[0])  # the default
        s.meta["confirm_why"] = "it arrived from the repo's .foreman/ (fm sync)\x1b[2J"
        gap = c.plan_gaps(s)[0]
        self.assertIn("it arrived from the repo's .foreman/ (fm sync)", gap)
        self.assertNotIn("\x1b", gap)

    def test_stage_and_next_action_follow_the_brief(self):
        b = self.brief("M", status="captured")
        self.assertEqual(c.stage(b), "captured")
        self.assertIn("sampo task new", c.next_action(b))
        b.meta["status"] = "planned"
        self.assertEqual(c.stage(b), "planning")
        self.assertIn("Interpretation", c.next_action(b))
        self.plan(b)
        self.assertEqual(c.stage(b), "ready")
        self.assertIn("sampo focus T-0001", c.next_action(b))
        b.meta["status"] = "active"
        self.assertEqual(c.stage(b), "executing")
        nxt = c.next_action(b)
        self.assertIn("step 1/1", nxt)
        self.assertIn("Skill foreman:debug-test", c.skill_for(b, c.stage(b)), "FIX names its procedure (T-1701)")
        self.assertNotIn("debug-test", nxt, "once a stage through the hooks, not on every step's line (T-1697)")
        b.add_evidence("pytest -k slow", "1 failed as expected", step=1, ts="2026-01-01T10:00:00Z")
        b.mark_step(1)
        self.assertEqual(c.stage(b), "verifying")
        self.assertIn("sampo task finish T-0001", c.next_action(b), "finish runs the criterion's own check")
        b.add_evidence("pytest -k slow", "1 passed", ac=1)
        b.check_ac(1)
        self.assertEqual(c.stage(b), "documenting")
        self.assertIn("Docs impact", c.next_action(b))
        b.set_section("Docs impact", "README usage updated")
        self.assertEqual(c.stage(b), "auditing")
        self.assertIn("audit.md", c.next_action(b))
        b.add_audit("intent", "fm-reviewer", "ok", ts="2026-01-01T11:00:00Z")
        b.add_audit("edge", "fm-reviewer", "ok", ts="2026-01-01T11:00:00Z")
        self.assertEqual(c.stage(b), "closing")
        self.assertIn("sampo task done T-0001", c.next_action(b))

    def test_every_skill_a_hint_loads_exists_and_the_model_may_load_it(self):
        # T-1701: FIX and RESEARCH name the job skills; a hint naming a missing or user-only skill sends Claude nowhere
        self.assertIn("Skill foreman:research", c.SKILL_FOR["RESEARCH"])
        for key, hint in c.SKILL_FOR.items():
            for name in re.findall(r"Skill foreman:([\w-]+)", hint):
                with self.subTest(key=key, skill=name):
                    path = os.path.join(c.PLUGIN_ROOT, "skills", name, "SKILL.md")
                    self.assertTrue(os.path.isfile(path))
                    with open(path, encoding="utf-8") as f:
                        self.assertNotIn("\ndisable-model-invocation: true", f.read())


    def test_next_moves_past_a_step_with_evidence_and_ends_at_finish(self):
        # T-0193: fm next said 'step 1/2 … fm task step done' until fm task finish marked the steps, with typed
        # evidence; fm usage: followed 2 of 7 times
        b = self.plan(self.brief("S"))
        b.add_step("fix it")
        b.meta["status"] = "active"
        b.add_evidence("pytest -k slow", "✗ exit 1", step=1)
        nxt = c.next_action(b)
        self.assertIn("step 2/2", nxt)
        self.assertIn("sampo task evidence T-0001 --step 2 --run", nxt)
        b.add_evidence("pytest -k slow", "exit 0", step=2)
        self.assertIn("sampo task finish T-0001", c.next_action(b))


class PlanContent(unittest.TestCase):
    """T-2335: an M or L plan names 2+ readings (or the one it ruled out), an outcome or failure mode per option, a
    use-what-exists or do-less option, and near-copy options count once."""
    AP = "Approach (options → choice → why)"

    def setUp(self):  # T-2341: these read the plan's own content; the cold rival read has its tests in test_second
        env = mock.patch.dict(os.environ, {"FOREMAN_NO_RIVAL": "1"})
        env.start()
        self.addCleanup(env.stop)

    GOOD = ("1) add `--strict` to the gate; fails if: callers pass old flags. "
            "2) use what exists: the audit table already has it; fails if: it lacks the column. "
            "3) do less: only warn; likely outcome: the gap stays. Choice 2 (80%): no new code.")

    def brief(self, tier="M", interp="Reading 1: the gate counts. Reading 2: the gate reads the text.", ap=GOOD):
        b = c.Brief.new("T-0001", "Gate plans", "FEATURE", tier, now="2026-01-01T00:00:00Z")
        b.set_section("Interpretation", interp)
        b.set_section(self.AP, ap)
        b.set_section("Risks and rollback", "Refuses good plans; revert the commit.")
        b.add_ac("gate refuses", verify="verify with pytest -k x")
        b.add_step("red test")
        return b

    def gaps(self, b):
        return " | ".join(c.plan_gaps(b, "full"))

    def test_a_complete_plan_starts_and_s_is_untouched(self):
        for tier in ("M", "L"):
            self.assertEqual(c.plan_gaps(self.brief(tier), "full"), [], tier)
        s = self.brief("S", interp="One.", ap="just do it")
        self.assertEqual(c.plan_gaps(s, "full"), [])

    def test_one_reading_is_refused_unless_it_names_the_one_ruled_out(self):
        for tier in ("M", "L"):
            g = self.gaps(self.brief(tier, interp="The gate counts options."))
            self.assertIn("1 distinct reading", g)
            self.assertIn("sampo task set T-0001", g)  # the gap names its fix
            ok = self.brief(tier, interp="The gate counts options. Ruled out: a skill nudge, because 0 of 29 briefs follow prose.")
            self.assertEqual(c.plan_gaps(ok, "full"), [], tier)

    def test_near_copy_readings_count_once(self):
        b = self.brief("M", interp="Reading 1: the plan gate counts the options in a brief.\n"
                                   "Reading 2: the plan gate counts the options in the brief.")
        self.assertIn("1 distinct reading", self.gaps(b))

    def test_an_option_without_an_outcome_is_refused_with_its_number(self):
        ap = ("1) add `--strict` to the gate; fails if: callers pass old flags. 2) use what exists: the audit table. "
              "3) do less: only warn; likely outcome: the gap stays. Choice 1 (80%): why")
        g = self.gaps(self.brief(ap=ap))
        self.assertIn("option 2", g)
        self.assertNotIn("option 1", g)
        self.assertIn("sampo task set T-0001", g)

    def test_no_use_what_exists_or_do_less_option_is_refused(self):
        ap = ("1) add `--strict`; fails if: old flags. 2) a new `gate` verb; breaks the CLI surface. "
              "3) a cold child judges the plan; breaks on a slow call. Choice 1 (80%): smallest.")
        g = self.gaps(self.brief(ap=ap))
        self.assertIn("use-what-exists", g)
        self.assertIn("do-less", g)
        one = "1) add `--strict`; fails if: old flags. "
        exists, less = "2) reuse the existing audit table; fails if: no column. ", "3) do nothing; likely outcome: the gap stays. "
        self.assertEqual(c.plan_gaps(self.brief(ap=one + exists + less + "Choice 1 (80%): smallest."), "full"), [])
        g = self.gaps(self.brief(ap=one + exists + "3) a queue; breaks on a slow call. Choice 1 (80%): smallest."))
        self.assertIn("do-less", g)
        self.assertNotIn("use-what-exists", g)
        g = self.gaps(self.brief(ap=one + "2) a queue; breaks on a slow call. " + less + "Choice 1 (80%): smallest."))
        self.assertIn("use-what-exists", g)
        self.assertNotIn("do-less", g)

    def test_near_copy_options_count_once(self):
        ap = ("1) use what exists: reuse the audit table for the gate checks; fails if: no column. "
              "2) use what exists: reuse the audit table for the gate checks now; fails if: no column. "
              "3) use what exists: reuse the audit table for the gate checks here; fails if: no column. Choice 1 (80%): why")
        g = self.gaps(self.brief(ap=ap))
        self.assertIn("names 1 option", g)
        self.assertIn("share most of their words", g)

    def test_flag_and_code_led_options_still_count(self):  # T-2285
        ap = ("1) --strict flag; fails if: old flags. 2) `fm gate` verb reusing the existing table; breaks the surface. "
              "3) \"do less\" warn only; likely outcome: the gap stays. Choice 1 (80%): why")
        self.assertEqual(c.plan_gaps(self.brief(ap=ap), "full"), [])

    def test_numbered_options_with_indented_sub_bullets_split_by_the_numbers(self):
        ap = ("1) add `--strict` to the gate; fails if: callers pass old flags\n"
              "   1. read the table\n   2. write the column\n   - a detail\n   - another detail\n"
              "2) use what exists: the audit table already has it; fails if: it lacks the column\n   - a detail\n   - more\n"
              "3) do less: only warn; likely outcome: the gap stays\n   - a detail\n   - more\n"
              "Choice 2 (80%): no new code.")
        parts = c._split_options(ap)
        self.assertEqual(len(parts), 3, parts)
        self.assertIn("fails if: callers", parts[0])
        self.assertEqual(c.plan_gaps(self.brief(ap=ap), "full"), [])
        inline = "1) add it; steps 1. read 2. write; fails if: x 2) use what exists: b; fails if: y 3) do less: c; fails if: z"
        self.assertEqual(len(c._split_options(inline)), 3)

    def test_bullets_are_options_only_when_no_run_of_markers_reaches_three(self):
        bullets = "- add it; fails if: x\n- use what exists: b; fails if: y\n- do less: c; fails if: z\nChoice 1 (80%): a"
        self.assertEqual(c.plan_gaps(self.brief(ap=bullets), "full"), [])
        self.assertEqual(len(c._split_options("1) a b c\n- x y\n- z w\n- v u\n- t s")), 4)  # a run of 1 loses to bullets

    def test_bullets_are_not_readings(self):
        for tier in ("M", "L"):
            g = self.gaps(self.brief(tier, interp="- scope: the gate counts options\n- scope: the gate reads the text"))
            self.assertIn("1 distinct reading", g, tier)

    def test_use_what_exists_and_do_less_come_from_different_options(self):
        ap = ("1) add `--strict`; fails if: old flags. 2) reuse the existing table and do less; fails if: no column. "
              "3) a queue; breaks on a slow call. Choice 1 (80%): smallest.")
        g = self.gaps(self.brief(ap=ap))
        self.assertIn("different options", g)
        self.assertIn("sampo task set T-0001", g)

    def test_a_ruled_out_reading_needs_its_reason(self):
        for text in ("The gate counts options. Ruled out.", "No other reading.", "One reading; the other is rejected."):
            self.assertIn("1 distinct reading", self.gaps(self.brief(interp=text)), text)
        ok = "No other reading: the request names one file and one verb, so nothing else fits."
        self.assertEqual(c.plan_gaps(self.brief(interp=ok), "full"), [])

    def test_loose_words_are_no_outcome(self):
        for word in ("but slower", "only if time", "it stays", "gives a table", "cuts a step", "results come", "likely slow"):
            ap = f"1) add it; fails if: x 2) use what exists: the table, {word} 3) do less: c; fails if: z Choice 1 (80%): a"
            self.assertIn("option 2", self.gaps(self.brief(ap=ap)), word)
        arrow = "1) add it; fails if: x 2) use what exists: the table → slower 3) do less: c; breaks y Choice 1 (80%): a"
        self.assertEqual(c.plan_gaps(self.brief(ap=arrow), "full"), [])

    def test_short_options_with_the_same_few_words_stay_distinct(self):
        ap = ("1) add it; fails if: x 2) use what exists: skip it; fails if: it is slow "
              "3) do less: skip it; fails if: it is slow Choice 1 (80%): a")
        self.assertEqual(c.plan_gaps(self.brief(ap=ap), "full"), [])  # 2 content words: too few to call a copy

    def test_a_long_run_of_dots_and_spaces_is_not_quadratic(self):
        import time
        t = time.process_time()
        c.plan_gaps(self.brief(ap="1) a; fails if: x 2) use what exists: b; fails if: y 3) do less: c; fails if: z " + ". " * 30000), "full")
        self.assertLess(time.process_time() - t, 2)

    def test_a_harness_plan_is_exempt_with_its_reason(self):
        for tier in ("M", "L"):
            b = self.brief(tier, interp="one", ap="x")
            self.assertTrue(c.plan_gaps(b, "full"))
            b.meta["harness_plan"] = "code"
            self.assertEqual(c.plan_gaps(b, "full"), [], tier)
            b.set_section("Interpretation", "")
            b.set_section(self.AP, "")
            self.assertEqual(c.plan_gaps(b, "full"), [], tier)

    def test_a_pulled_brief_with_huge_numbers_or_5000_bullets_neither_raises_nor_crawls(self):
        import time
        for text in ("1" * 5000 + ") x. 2) y 3) z Choice 1", "\n".join("- use what exists, fails if: x%d" % i for i in range(5000))):
            t = time.process_time()
            self.assertIsInstance(c.plan_gaps(self.brief(ap=text), "full"), list)
            self.assertLess(time.process_time() - t, 2)

    def test_a_started_task_is_not_regated(self):
        b = self.brief(interp="One.", ap="1) a 2) b 3) c Choice 1")
        self.assertTrue(c.plan_gaps(b, "full"))
        b.meta["plan0_at"] = "x"
        self.assertEqual(c.plan_gaps(b, "full"), [])


class WorkRequests(unittest.TestCase):
    def test_plain_work_requests(self):
        for text in ("add a --verbose flag to the CLI", "fix the login timeout on slow wifi",
                     "Please refactor the date helpers", "can you rename add to add_numbers?"):
            with self.subTest(text=text):
                self.assertTrue(c.is_work_request(text))
        for text in ("what does this function do?", "yes", "FIX: login", "super improve it", "thanks!", ""):
            with self.subTest(text=text):
                self.assertFalse(c.is_work_request(text))


class OpenEnded(unittest.TestCase):
    def test_vague_requests_are_open_ended(self):
        for text in ("Just get it done", "super improve it", "make it better!", "improve everything",
                     "brainstorm some features for this", "what should we build next?", "go wild",
                     "Just get it done etc, super improve it"):
            with self.subTest(text=text):
                self.assertTrue(c.is_open_ended(text))

    def test_concrete_requests_are_not(self):
        for text in ("fix the login timeout on slow wifi", "FIX: login times out", "improve the error message in parse_ts",
                     "add a --verbose flag to the CLI", "yes", "PAUSE", ""):
            with self.subTest(text=text):
                self.assertFalse(c.is_open_ended(text))
                self.assertFalse(c.is_exhaustive(text))
                self.assertFalse(c.is_broad(text))

    def test_real_phrasings_reach_the_brainstorm(self):
        # T-0364: the user's own words from Volt and Foreman sessions; none reached a brainstorm, so plans covered only
        # what came to mind first and the user asked for the rest one request at a time
        for text in ("can you make the language interop limitless? no caveats or non implemented things for rust, zig, "
                     "c, especially C++, etc.?",
                     "the recursive brainstorm isn't great, it doesn't think of every possible solution/capability",
                     "make it more featurefull", "support all possible shapes"):
            with self.subTest(text=text):
                self.assertTrue(c.is_exhaustive(text))
        for text in ("can you add even more benchmarks to compare against C/C++? like a lot more, not just simple things "
                     "either, like a ton of C++/C/Volt language features, truly showcasing the speed",
                     "add tons of tests for the parser"):
            with self.subTest(text=text):
                self.assertTrue(c.is_broad(text))
                self.assertFalse(c.is_exhaustive(text))
        for text in ("make it way better", "make the app much nicer"):
            with self.subTest(text=text):
                self.assertTrue(c.is_open_ended(text))
        for text in ("there's a lot of chat spam from your messages", "every test passes now", "no caveats here, ship it",
                     "is this a lot more readable?"):
            with self.subTest(text=text):
                self.assertFalse(c.is_exhaustive(text) or c.is_broad(text))

    def test_a_repo_cleanup_is_a_sweep(self):
        # T-0364: "clean up all docs, code, UI, settings, environment" was tiered S and closed after a few files
        for text in ("clean up all docs, code, UI, settings, environment stuff",
                     "clean up the repo, docs, briefs, dead code, unused functionality that's been replaced",
                     "remove dead code", "CLEAN: the whole codebase"):
            with self.subTest(text=text):
                self.assertTrue(c.is_sweep(text))
        for text in ("clean up the panel spacing", "fix the login timeout", "clean up after the test in test_io",
                     "clean up all of the panels, they still look weird"):
            with self.subTest(text=text):
                self.assertFalse(c.is_sweep(text))

    def test_a_long_request_with_a_work_verb_is_still_a_work_request(self):
        # T-0364: "can you make music-findr which is basically spot dl, but…" (90 words) got no intake note at all
        self.assertTrue(c.is_work_request("can you make a web app that " + "does one more thing and " * 20 + "works"))


class PlanOnly(unittest.TestCase):
    def test_plan_only_requests_hold_drive(self):
        for text in ("FIX: a\n\nCapture and plan these; don't implement anything yet.", "Just plan it.",
                     "Plan only, no code.", "don't implement yet", "Do not change anything for now.",
                     "only plan this", "no code yet please", "capture only"):
            with self.subTest(text=text):
                self.assertTrue(c.is_plan_only(text))

    def test_constraints_and_mentions_of_a_plan_do_not(self):
        for text in ("fix the login bug; don't change the API", "the plan only covers X", "don't write to the db",
                     "don't build a new parser, reuse the old one", "add retries, don't change anything else",
                     "is the plan first-class?", "the only plan we have is this one"):
            with self.subTest(text=text):
                self.assertFalse(c.is_plan_only(text))


class Intake(unittest.TestCase):
    BLOCK = """FIX: login times out after 30s on slow networks
FEATURE: export report as CSV @src/reports #T-0003
  include the totals row
clean!: collapse the three date helpers into one
PERF?: dashboard first paint takes 4s
SECURITY: review the upload endpoint
CONTEXT: Django app; don't touch migrations
NEVER: push to main
DONE-WHEN: all tests pass and the CSV opens in Excel
SKIP: mobile layout
"""

    def test_items_tags_modifiers_and_continuations(self):
        r = c.parse_intake(self.BLOCK)
        self.assertEqual([i.type for i in r.items], ["FIX", "FEATURE", "CLEAN", "PERFORMANCE", "SECURITY"])
        feat = r.items[1]
        self.assertIn("include the totals row", feat.text)
        self.assertEqual(feat.scopes, ["src/reports"])
        self.assertEqual(feat.refs, ["T-0003"])
        self.assertTrue(r.items[2].urgent)
        self.assertTrue(r.items[3].explore)
        self.assertEqual(r.context, ["Django app; don't touch migrations"])
        self.assertEqual(r.constraints, ["NEVER: push to main"])
        self.assertEqual(r.done_when, ["all tests pass and the CSV opens in Excel"])
        self.assertEqual(r.skip, ["mobile layout"])

    def test_an_at_path_line_under_an_item_scopes_it(self):
        # T-1989: an unindented "@path" line under an item went to untagged text, its scope lost
        r = c.parse_intake("FIX: totals are wrong\n@src/reports @src/csv.py\n  in every report\nFEATURE: export\n"
                           "DONE-WHEN: it opens\n@src/export.py\n  and keeps the header\n\n@stray/path")
        self.assertEqual(r.items[0].scopes, ["src/reports", "src/csv.py"])
        self.assertEqual(r.items[1].scopes, ["src/export.py"])
        self.assertEqual(r.untagged, "@stray/path")  # after a blank line it belongs to no item

    def test_aliases(self):
        r = c.parse_intake("BUG: a\nREFACTOR: b\nSPIKE: c\nADD: d\nSEC: e\nNOTE: n\nMUST: m\nACCEPT: x\nOUT: o")
        self.assertEqual([i.type for i in r.items], ["FIX", "CLEAN", "RESEARCH", "FEATURE", "SECURITY"])
        self.assertEqual(r.context, ["n"])
        self.assertEqual(r.constraints, ["MUST: m"])
        self.assertEqual(r.done_when, ["x"])
        self.assertEqual(r.skip, ["o"])

    def test_untagged_request_and_non_tags(self):
        r = c.parse_intake("make the build faster\nsee http://example.com/x for details")
        self.assertEqual(r.items, [])
        self.assertIn("make the build faster", r.untagged)

    def test_override_words(self):
        self.assertEqual(c.parse_intake("NOW: prod is down").overrides, ["NOW"])
        self.assertEqual(c.parse_intake("NOW: FIX: prod is down").items[0].type, "FIX")
        self.assertTrue(c.parse_intake("NOW: FIX: prod is down").items[0].urgent)
        for word in ["pause", "PAUSE", "hold on", "stop"]:
            self.assertEqual(c.parse_intake(word).overrides, ["PAUSE"], word)
        self.assertEqual(c.parse_intake("resume").overrides, ["RESUME"])
        self.assertEqual(c.parse_intake("status").overrides, ["STATUS"])
        self.assertEqual(c.parse_intake("that's for the current task").overrides, ["STEER"])
        self.assertEqual(c.parse_intake("please stop the server when done").overrides, [])

    def test_bang_tag_marks_urgent(self):
        r = c.parse_intake("FIX!: prod 500s on login")
        self.assertTrue(r.items[0].urgent)

    def test_tier_guess(self):
        self.assertEqual(c.guess_tier("FIX", "typo in header"), "S")
        self.assertEqual(c.guess_tier("FEATURE", "export report as CSV with totals and filters"), "M")
        self.assertEqual(c.guess_tier("FEATURE", "migrate the auth schema to OAuth2"), "L")


def _b(id, type, status="planned", priority="normal", deps=()):
    b = c.Brief.new(id, f"task {id}", type, "S", now="2026-01-01T00:00:00Z")
    b.meta["status"] = status
    b.meta["priority"] = priority
    b.meta["depends_on"] = list(deps)
    return b


class Queue(unittest.TestCase):
    def test_canonical_order(self):
        briefs = [_b("T-0001", "FEATURE"), _b("T-0002", "FIX"), _b("T-0003", "CLEAN"),
                  _b("T-0004", "SECURITY"), _b("T-0005", "PERFORMANCE"), _b("T-0006", "RESEARCH")]
        q, cycles, dangling = c.order_queue(briefs)
        self.assertEqual([b.id for b in q], ["T-0006", "T-0003", "T-0005", "T-0004", "T-0002", "T-0001"])
        self.assertEqual((cycles, dangling), ([], []))

    def test_active_first_then_urgent(self):
        briefs = [_b("T-0001", "CLEAN"), _b("T-0002", "FEATURE", priority="urgent"), _b("T-0003", "FIX", status="active")]
        q, _, _ = c.order_queue(briefs)
        self.assertEqual([b.id for b in q], ["T-0003", "T-0002", "T-0001"])

    def test_dependencies_override_canonical_order(self):
        briefs = [_b("T-0001", "CLEAN", deps=["T-0002"]), _b("T-0002", "FEATURE")]
        q, _, _ = c.order_queue(briefs)
        self.assertEqual([b.id for b in q], ["T-0002", "T-0001"])

    def test_done_dependency_is_satisfied_and_dangling_reported(self):
        briefs = [_b("T-0001", "FIX", deps=["T-0009", "T-0002"]), _b("T-0002", "CLEAN", status="done")]
        q, _, dangling = c.order_queue(briefs)
        self.assertEqual([b.id for b in q], ["T-0001"])
        self.assertEqual(dangling, [("T-0001", "T-0009")])

    def test_cycles_are_reported_not_dropped(self):
        briefs = [_b("T-0001", "FIX", deps=["T-0002"]), _b("T-0002", "FIX", deps=["T-0001"]), _b("T-0003", "CLEAN")]
        q, cycles, _ = c.order_queue(briefs)
        self.assertEqual([b.id for b in q][0], "T-0003")
        self.assertEqual(sorted(b.id for b in q), ["T-0001", "T-0002", "T-0003"])
        self.assertEqual(cycles, [["T-0001", "T-0002"]])

    def test_captured_blocked_and_closed_are_not_in_queue(self):
        briefs = [_b("T-0001", "FIX", status="captured"), _b("T-0002", "FIX", status="blocked"),
                  _b("T-0003", "FIX", status="dropped"), _b("T-0004", "FIX")]
        q, _, _ = c.order_queue(briefs)
        self.assertEqual([b.id for b in q], ["T-0004"])


class RoundFirst(ForemanTestCase):  # T-2327 (user steer 2026-10-31, 2): no new maintenance before the round is done
    def setUp(self):
        super().setUp()
        self.fm("init")
        self.p = c.find_project(self.repo)
        g = os.path.join(self.p.dir, "research", "genesis")
        os.makedirs(os.path.join(g, "gen-1"))
        for rel in ("gen-0.md", "gen-1/seed.md"):
            with open(os.path.join(g, rel), "w", encoding="utf-8") as f:
                f.write("# x\n")
        self.g = g

    def offered(self):
        b, _, _ = c._next_for(c.find_project(self.repo))
        return b.id if b else None

    def capture(self, text, *flags):
        out = self.fm("capture", text, "--json", *flags).stdout
        return json.loads(out)["id"]

    def test_the_friction_pass_waits_for_the_round_too(self):
        # T-2460: with pace drops off, fm next offered the self-improvement pass during round 1, which the steer bars
        from sampo import friction
        with mock.patch.object(friction, "due", return_value=True), mock.patch("sampo.budget.degrade", return_value=None):
            self.assertEqual(c._next_for(c.find_project(self.repo))[1], "reflect")
            self.fm("drive", "on", "--round-first", "on")
            _, kind, text = c._next_for(c.find_project(self.repo))
            self.assertNotEqual(kind, "reflect")
            self.assertIn("self-improvement pass waits for Genesis round 1", text)

    def test_the_drives_side_work_offer_holds_them_too(self):
        # T-2459: while background jobs ran, the Stop hook's side-work offer named a Foreman capture the round held
        from sampo import hooks
        mine = self.capture("FIX: a discovered nit in the parser", "--source", "discovered")
        self.fm("task", "new", "Active work", "--type", "FIX", "--tier", "S", "--ac", "ok :: true", "--step", "s",
                "--focus")
        p = c.find_project(self.repo)
        briefs = c.load_briefs(p)
        work = c.active_brief(briefs)
        offer = lambda: hooks._side_work(c.state_dict(p, briefs), briefs, {"id": work.id}, True, [], p)  # noqa: E731
        self.assertEqual((offer() or {}).get("id"), mine)  # the switch is off: offered as before
        self.fm("drive", "on", "--round-first", "on")
        self.assertIsNone(offer())

    def test_foremans_own_captures_wait_for_the_round_unless_urgent_or_depended_on(self):
        mine = self.capture("FIX: a discovered nit in the parser", "--source", "discovered")
        self.assertEqual(self.offered(), mine)  # the switch is off: offered as before
        self.fm("drive", "on", "--round-first", "on")
        self.assertIsNone(self.offered())
        urgent = self.capture("FIX: the gates are red on main", "--source", "discovered", "--urgent")
        self.assertEqual(self.offered(), urgent)
        self.fm("task", "drop", urgent, "--reason", "test")
        user = self.capture("FEATURE: add an export button")
        self.assertEqual(self.offered(), user)  # the user's own request is never held
        self.fm("task", "drop", user, "--reason", "test")
        os.makedirs(os.path.join(self.g, "gen-2"))
        with open(os.path.join(self.g, "gen-2", "seed.md"), "w", encoding="utf-8") as f:
            f.write("# gen 2\n")
        self.assertEqual(self.offered(), mine)  # gen 2's seed is filed: the round is done, the hold lapses


if __name__ == "__main__":
    unittest.main()


class HookImportCost(unittest.TestCase):
    """Round 6: every tool call starts a hook process; traceback (~15 ms) and dataclasses (~9 ms) stay off its path."""

    def test_hook_modules_do_not_import_the_slow_ones(self):
        import subprocess
        import sys
        code = ("import sys; sys.path.insert(0, %r); from sampo import hooks; import fmguard; "
                "print(sorted(m for m in ('traceback', 'dataclasses', 'inspect') if m in sys.modules))") % os.path.join(c.PLUGIN_ROOT, "lib")
        out = subprocess.run([sys.executable, "-c", code], capture_output=True, text=True, check=True).stdout.strip()
        self.assertEqual(out, "[]")

    def test_record_behaves_like_the_dataclasses_it_replaced(self):
        @c.record
        class R:
            a: int
            b: list = []
            c_: str = "x"
        r1, r2 = R(1), R(a=1)
        self.assertEqual(r1, r2)
        r1.b.append(5)
        self.assertEqual(r2.b, [], "list defaults are per instance")
        self.assertEqual(repr(R(2, [3], "y")), "R(a=2, b=[3], c_='y')")
        with self.assertRaises(TypeError):
            R()
        with self.assertRaises(TypeError):
            R(1, nope=2)
        self.assertNotEqual(R(1), R(2))


class RunCommand(unittest.TestCase):
    def test_a_pipe_cannot_hide_a_failing_test_run(self):
        # T-0773: 'unittest … | tail -3' exits with tail's 0; evidence read "exit 0 · FAILED (errors=1)" twice in a day
        root = os.path.dirname(__file__)
        for summary in ("FAILED (errors=1)", "FAILED (failures=2, errors=1)", "==== 3 failed, 10 passed in 1.2s ====",
                        "Tests:       1 failed, 4 passed, 5 total", "test result: FAILED. 3 passed; 1 failed",
                        "--- FAIL: TestX (0.00s)"):
            code, out = c.run_command(root, f"printf 'Ran 3 tests in 0.1s\\n\\n{summary}\\n' | tail -3")
            self.assertNotEqual(code, 0, summary)
            self.assertIn("reports failing tests", out)
        for ok in ("Ran 3 tests in 0.1s\\n\\nOK", "==== 10 passed in 1.2s ====", "test result: ok. 3 passed; 0 failed"):
            code, _ = c.run_command(root, f"printf '{ok}\\n' | tail -3")
            self.assertEqual(code, 0, ok)
        import tempfile  # the real producer, not a hand-written summary (T-0750's lesson)
        with tempfile.TemporaryDirectory() as d:
            with open(os.path.join(d, "test_x.py"), "w") as f:
                f.write("import unittest\nclass T(unittest.TestCase):\n    def test_a(self):\n        self.fail('no')\n")
            code, out = c.run_command(d, "python3 -m unittest test_x 2>&1 | tail -3")
            self.assertEqual(code, 1, out)

    def test_kill_group_takes_the_children_and_never_raises(self):
        # T-1094: fmbench's own killpg had no except, so a child that exited first crashed the bench
        import subprocess
        import time
        pr = subprocess.Popen(["sh", "-c", "sleep 30 & echo $!; wait"], stdout=subprocess.PIPE, text=True,
                              start_new_session=True)
        child = int(pr.stdout.readline())
        c.kill_group(pr)
        pr.wait(timeout=5)
        time.sleep(0.2)
        self.assertFalse(os.path.exists(f"/proc/{child}") and "Z" not in open(f"/proc/{child}/stat").read().split()[2])
        c.kill_group(pr)  # already gone: no exception
        done = subprocess.Popen(["true"], start_new_session=True)
        done.wait()
        c.kill_group(done)

    def test_a_run_never_inherits_the_test_skip_list(self):
        # T-1114: an exported FOREMAN_SKIP_TESTS would make an evidence run of run.py leave modules out silently
        from unittest import mock
        with mock.patch.dict(os.environ, {"FOREMAN_SKIP_TESTS": "test_guard"}):
            _, out = c.run_command(os.path.dirname(__file__), 'echo "skip=${FOREMAN_SKIP_TESTS:-none}"')
        self.assertIn("skip=none", out)


class NativeClaude(unittest.TestCase):
    def test_the_native_install_is_found_when_path_lacks_it(self):
        # T-0990: the npm claude was removed; the native one is in ~/.local/bin, which fm's shells didn't have
        import tempfile
        with tempfile.TemporaryDirectory() as home:
            local = os.path.join(home, ".local", "bin")
            os.makedirs(local)
            exe = os.path.join(local, "claude")
            with open(exe, "w") as f:
                f.write("#!/bin/sh\n")
            os.chmod(exe, 0o755)
            empty = os.path.join(home, "empty")  # never the host's PATH: its claude comes and goes
            os.makedirs(empty)
            env = {"HOME": home, "PATH": empty}
            self.assertEqual(c.claude_path(env)["PATH"].split(os.pathsep)[0], local)
            other = os.path.join(home, "other")
            os.makedirs(other)
            os.symlink(exe, os.path.join(other, "claude"))
            env = {"HOME": home, "PATH": other + ":" + empty}
            self.assertEqual(c.claude_path(env)["PATH"], other + ":" + empty, "one on PATH already wins")
            os.remove(exe)
            self.assertEqual(c.claude_path({"HOME": home, "PATH": empty})["PATH"], empty)


class ActiveFast(ForemanTestCase):
    def test_the_fast_active_brief_matches_the_full_scan(self):
        # T-1140: PreToolUse parsed every brief (1,069 here) to find the active one, half of each hook call
        self.fm("init")
        p = c.find_project(self.repo)
        for i in range(5):
            self.fm("task", "new", f"t{i}", "--type", "FIX", "--tier", "S", "--ac", "ok :: true", "--step", "s")
        self.assertIsNone(c.active_brief_fast(p))
        self.fm("focus", "T-0003")
        self.assertEqual(c.active_brief_fast(p).id, c.active_brief(c.load_briefs(p)).id)
        b = c.find_brief(p, "T-0004")
        b.meta.update(status="verifying", lane="/elsewhere")  # another lane's active task
        c.save_brief(p, b)
        self.assertEqual(c.active_brief_fast(p).id, "T-0003")
        self.assertEqual(c.active_brief_fast(p, "/elsewhere").id, "T-0004")
        self.assertIsNone(c.active_brief_fast(p, "/nowhere"))


class WaitWhile(unittest.TestCase):
    """T-2010: one wait for fm check and fm ship: says what it waits for, and when it stops waiting and goes ahead."""
    def test_wait_while_says_what_it_waits_for_and_when_it_gives_up(self):
        import io
        out = io.StringIO()
        self.assertFalse(c.wait_while(lambda: False, "x", "fm t", limit=1, out=out))
        self.assertEqual(out.getvalue(), "", "nothing running: no wait, no line")
        left = [2]

        def busy():
            left[0] -= 1
            return left[0] >= 0
        self.assertTrue(c.wait_while(busy, "a running sampo check", "fm t", limit=30, out=out, step=0.01))
        self.assertIn("fm t: waiting for a running sampo check to finish first (at most 30 seconds)", out.getvalue())
        self.assertNotIn("going ahead", out.getvalue())
        out = io.StringIO()
        t0 = time.time()
        self.assertTrue(c.wait_while(lambda: True, "the ambient test run", "fm t", limit=1, out=out, step=0.05))
        self.assertLess(time.time() - t0, 3)  # wall clock: wait_while's limit=1 deadline (it sleeps)
        self.assertIn("the ambient test run is still running after 1 seconds; going ahead beside it", out.getvalue())


class LazyPatterns(unittest.TestCase):
    """T-2020: every hook spent ~25 ms compiling ~190 module-level patterns; a PreToolUse call uses about 44."""

    def test_lazy_importing_the_hook_modules_compiles_no_module_level_pattern(self):
        import sys
        from helpers import LIB
        code = ("import re, sys\nsys.path.insert(0, sys.argv[1])\norig, hits = re.compile, []\n"
                "def counting(*a, **k):\n"
                "    f = sys._getframe(1)\n"
                "    while f and f.f_code.co_name != '<module>':\n"
                "        f = f.f_back\n"
                "    path = f.f_code.co_filename if f else ''\n"
                "    name = path.rsplit('/', 1)[-1]\n"
                "    if name.startswith('fm') or '/sampo/' in path:\n"
                "        hits.append(f'{name}:{f.f_lineno}')\n"
                "    return orig(*a, **k)\n"
                "re.compile = counting\nfrom sampo import core\nimport fmguard\nfrom sampo import hooks\nprint(hits)\n")
        out = subprocess.run([sys.executable, "-c", code, LIB], capture_output=True, text=True, timeout=60)
        self.assertEqual(out.stdout.strip(), "[]", out.stderr)

    def test_lazy_a_pattern_compiles_on_first_use_and_keeps_its_methods(self):
        rx = c.lazy(r"a+", re.I)
        self.assertEqual(rx.search("bAab").group(), "Aa")
        self.assertIs(rx.search, rx.search)  # compiled once, then a plain attribute
        self.assertEqual((rx.pattern, rx.flags & re.I), ("a+", re.I))

    def test_lazy_every_deferred_pattern_still_compiles(self):
        import fmguard
        from sampo import hooks
        found = []

        def walk(v):
            if type(v).__name__ == "lazy":
                found.append(v)
            elif isinstance(v, (list, tuple, set, frozenset)):
                for x in v:
                    walk(x)
            elif isinstance(v, dict):
                for x in v.values():
                    walk(x)
        for mod in (c, fmguard, hooks):
            for v in list(vars(mod).values()):
                walk(v)
        for rx in found:
            rx.flags  # a bad pattern raises re.error here, not at import
        self.assertGreater(len(found), 150)


class BriefIndex(ForemanTestCase):
    """T-2022: closed briefs load from a stat-checked index instead of 1,100+ file reads per hook."""

    def setUp(self):
        super().setUp()
        self.fm("init")
        self.p = c.find_project(self.repo)
        for i in range(3):
            self.fm("task", "new", f"t{i}", "--type", "FIX", "--tier", "S", "--ac", "ok :: true", "--step", "s")
        b = c.find_brief(self.p, "T-0001")
        b.meta["status"] = "done"
        c.save_brief(self.p, b)
        self.age()
        c._BRIEF_MEMO.clear()

    def age(self, secs=60):
        for path in c.brief_paths(self.p):
            os.utime(path, (time.time() - secs, time.time() - secs))

    def opened(self, fn):
        from unittest import mock
        real, seen = open, []

        def spy(f, *a, **k):
            seen.append(str(f))
            return real(f, *a, **k)
        with mock.patch("builtins.open", spy):
            out = fn()
        c._BRIEF_MEMO.clear()
        return out, seen

    def test_brief_index_closed_briefs_load_without_opening_their_files(self):
        first = c.load_briefs(self.p)
        c._BRIEF_MEMO.clear()
        self.assertTrue(os.path.exists(os.path.join(self.p.dir, "briefs-index.json")))
        second, seen = self.opened(lambda: c.load_briefs(self.p))
        done = c.find_brief(self.p, "T-0001").path
        self.assertNotIn(done, seen)
        self.assertIn(c.find_brief(self.p, "T-0002").path, seen, "open briefs are read as before")
        for a, b in zip(first, second):
            self.assertEqual((a.id, a.meta, a.title, a.preamble), (b.id, b.meta, b.title, b.preamble))
            self.assertEqual(a.render(), b.render())
            self.assertEqual([list(x) for x in a.sections], [list(x) for x in b.sections])
        _, seen = self.opened(lambda: c.active_brief_fast(self.p))
        self.assertNotIn(done, seen, "the fast active scan skips indexed closed briefs too")

    def test_brief_index_an_edited_brief_is_read_again(self):
        c.load_briefs(self.p)
        c._BRIEF_MEMO.clear()
        path = c.find_brief(self.p, "T-0001").path
        with open(path, encoding="utf-8") as f:
            text = f.read()
        with open(path, "w", encoding="utf-8") as f:
            f.write(text.replace("# t0", "# renamed"))
        self.age(30)
        c._BRIEF_MEMO.clear()
        b = [x for x in c.load_briefs(self.p) if x.id == "T-0001"][0]
        self.assertEqual(b.title, "renamed")

    def test_brief_index_a_corrupt_index_is_ignored(self):
        want = [x.render() for x in c.load_briefs(self.p)]
        idx = os.path.join(self.p.dir, "briefs-index.json")
        name = os.path.basename(c.find_brief(self.p, "T-0001").path)
        for bad in ("{", "[]", '{"v":1,"e":[]}', json.dumps({"v": 1, "e": {name: [1]}}),
                    json.dumps({"v": 1, "e": {name: "x"}}), json.dumps({"v": 1, "e": {name: [1, 2, 3, [], ""]}})):
            with open(idx, "w", encoding="utf-8") as f:
                f.write(bad)
            c._BRIEF_MEMO.clear()
            self.assertEqual([x.render() for x in c.load_briefs(self.p)], want, bad)
            c._BRIEF_MEMO.clear()
            self.assertIsNone(c.active_brief_fast(self.p), bad)

    def test_brief_index_the_fast_scan_reads_only_the_closed_keys(self):
        # T-2031: once the small keys file exists, the fast scan never opens the 700 KB index
        c.load_briefs(self.p)
        c._BRIEF_MEMO.clear()
        keys, idx = (os.path.join(self.p.dir, n) for n in ("briefs-closed.json", "briefs-index.json"))
        done = c.find_brief(self.p, "T-0001")
        got, seen = self.opened(lambda: c.active_brief_fast(self.p))
        self.assertIsNone(got)
        self.assertNotIn(idx, seen)
        self.assertNotIn(done.path, seen)
        for bad in ("{", "[]"):  # unreadable: back to the index, still skipping the closed brief
            with open(keys, "w", encoding="utf-8") as f:
                f.write(bad)
            got, seen = self.opened(lambda: c.active_brief_fast(self.p))
            self.assertIsNone(got, bad)
            self.assertNotIn(done.path, seen, bad)
        os.remove(keys)
        c._BRIEF_MEMO.clear()
        c.load_briefs(self.p)
        self.assertTrue(os.path.exists(keys), "a missing keys file is written again")
        done.meta["status"] = "active"  # reopened: a stale key no longer matches, so the brief is read
        c.save_brief(self.p, done)
        self.age(30)
        c._BRIEF_MEMO.clear()
        self.assertEqual(c.active_brief_fast(self.p).id, "T-0001")

    def test_brief_index_a_just_written_brief_is_indexed_and_a_rewrite_is_not_served_stale(self):
        """T-2324: indexed at once (a later load must not rewrite the caches); the rewrite's new inode misses it."""
        b = c.find_brief(self.p, "T-0002")
        b.meta["status"] = "done"
        c.save_brief(self.p, b)
        c._BRIEF_MEMO.clear()
        c.load_briefs(self.p)
        with open(os.path.join(self.p.dir, "briefs-index.json"), encoding="utf-8") as f:
            names = json.load(f)["e"]
        self.assertIn(os.path.basename(b.path), names)
        b.meta["tier"] = "M"
        c.save_brief(self.p, b, touch=False)  # same size, same tick, a new inode
        self.assertEqual([x for x in c.load_briefs(self.p) if x.id == "T-0002"][0].meta["tier"], "M")

    def test_brief_index_a_stub_copies_edits_and_renders_like_a_parsed_brief(self):
        c.load_briefs(self.p)
        c._BRIEF_MEMO.clear()
        path = c.find_brief(self.p, "T-0001").path
        c._BRIEF_MEMO.clear()
        stub = [x for x in c.load_briefs(self.p) if x.id == "T-0001"][0]
        with open(path, encoding="utf-8") as f:
            text = f.read()
        full = c.Brief.parse(text, path)
        self.assertEqual(stub.copy().render(), text)
        for b in (stub, full):
            b.meta["status"] = "dropped"
            b.sections[0][1] += "more\n"
        self.assertEqual(stub.render(), full.render())
        stub2 = [x for x in c.load_briefs(self.p) if x.id == "T-0001"][0]
        stub2.sections = [["Only", "x\n"]]
        self.assertTrue(stub2.render().endswith("## Only\nx\n"))


class LaterImports(ForemanTestCase):
    """T-2023: every hook paid ~5 ms importing subprocess, shutil and glob, which an ordinary tool call never uses."""
    HEAVY = ("subprocess", "glob")  # not shutil: tempfile imports it, and the guard needs tempfile each call

    def loaded_after(self, event, payload):
        site = os.path.join(self.tmp, "report")
        os.makedirs(site, exist_ok=True)
        out = os.path.join(site, "loaded")
        with open(os.path.join(site, "sitecustomize.py"), "w") as f:
            f.write(f"import atexit, sys\natexit.register(lambda: open({out!r}, 'w').write("
                    f"' '.join(m for m in {self.HEAVY!r} if m in sys.modules)))\n")
        r = self.hook(event, payload, env={"PYTHONPATH": site})
        with open(out) as f:
            return r, f.read().split()

    def test_later_a_plain_tool_call_loads_no_heavy_module(self):
        self.fm("init")
        r, loaded = self.loaded_after("PreToolUse", {"tool_name": "Bash", "tool_input": {"command": "ls"}})
        self.assertEqual((r.returncode, loaded), (0, []), r.stderr)

    def test_later_a_stand_in_imports_on_first_use_and_mocks_still_reach_callers(self):
        from unittest import mock
        s = c._Later("subprocess")
        self.assertIs(s.PIPE, subprocess.PIPE)
        with mock.patch("subprocess.run", return_value="patched"):
            self.assertEqual(s.run(["true"]), "patched")
        with mock.patch.object(c.subprocess, "run", return_value="via fmcore"):
            self.assertEqual(c.subprocess.run(["true"]), "via fmcore")
        self.assertIs(c.subprocess.run, subprocess.run)

    def test_later_claude_path_still_adds_the_native_folder_only_when_needed(self):
        native = os.path.join(self.tmp, "native")
        os.makedirs(native)
        claude = os.path.join(native, "claude")
        with open(claude, "w") as f:
            f.write("#!/bin/sh\n")
        os.chmod(claude, 0o755)
        env = c.claude_path({"FOREMAN_NATIVE_BIN": native, "PATH": "/nonexistent"})
        self.assertEqual(env["PATH"], native + os.pathsep + "/nonexistent")
        on = native + os.pathsep + "/usr/bin"
        self.assertEqual(c.claude_path({"FOREMAN_NATIVE_BIN": native, "PATH": on})["PATH"], on)


class ConfidenceRoutes(ForemanTestCase):  # T-2338 (Mission 5, #8): one stated number routes the next step
    OPTS = "1) a; fails if: x 2) use what exists: b; fails if: y 3) do less: c; fails if: z "
    HOLDS = "HOLDS: the output shows it."
    CHECK = "test -d .git"  # lint_verify-clean (ls, true and echo can't fail) and passes in the test repo

    def setUp(self):
        super().setUp()
        self.fm("init")
        self.p = c.find_project(self.repo)

    def task(self, tier="M", choice="Choice 1 (80%): a", assume=None):
        self.fm("task", "new", "Parser", "--type", "FEATURE", "--tier", tier, "--interpretation",
                "Reading 1: a. Reading 2: b.", "--approach", self.OPTS + choice, "--ac", "ok :: ls", "--step", "s")
        if tier == "L":
            self.fm("task", "set", "T-0001", "--section", "Risks and rollback", "--text", "It breaks; revert.")
        for a in assume or ():
            self.fm("task", "assume", "T-0001", "add", a)
        return "T-0001"

    def focus(self, **kw):
        return self.fm("focus", "T-0001", check=False, **kw)

    def refused(self, r, *words):
        self.assertNotEqual(r.returncode, 0, r.stdout)
        for w in words:
            self.assertIn(w, r.stderr + r.stdout)

    def test_an_m_choice_without_a_confidence_is_refused(self):
        self.task("M", choice="Choice 1: a")
        self.refused(self.focus(), "confidence", "Choice N (NN%)")

    def test_an_l_choice_without_a_confidence_is_refused(self):
        self.task("L", choice="Choice 1: a")
        self.refused(self.focus(), "confidence", "Choice N (NN%)")

    def test_s_pays_nothing(self):
        self.task("S", choice="Choice 1: a")
        self.assertEqual(self.focus().returncode, 0)

    def test_the_stated_number_is_one_parser_for_the_gate_and_the_ledger(self):
        self.assertEqual(c.stated_confidence("1) a 2) b Choice 2 (70%): why"), 70)
        self.assertEqual(c.stated_confidence("Choice 1: a (65%)"), 65)
        self.assertEqual(c.stated_confidence("Choice 1 (40%): a. Choice 2 (90%): changed my mind"), 90)  # the last one
        self.assertIsNone(c.stated_confidence("Choice 1: a, about 70% sure"))
        self.assertIsNone(c.stated_confidence("an option (80%) and no choice"))
        self.assertEqual(c.assumption_confidence("the API is paged (50%)"), 50)
        self.assertEqual(c.assumption_confidence("the API is paged (low)"), c.LOW_CONFIDENCE)
        self.assertIsNone(c.assumption_confidence("the API is paged"))

    def test_a_number_over_100_is_not_a_confidence(self):
        self.task(choice="Choice 1 (150%): a")
        self.refused(self.focus(), "confidence")

    def test_a_started_task_is_not_regated_for_its_confidence(self):  # T-2269's rule: only an unstarted brief
        b = c.find_brief(self.p, self.task(choice="Choice 1: a"))
        b.meta["plan0_at"] = "2026-01-01T00:00:00Z"
        self.assertEqual([g for g in c.plan_gaps(b, "full") if "confidence" in g], [])

    def test_an_assumption_under_the_bar_is_refused_until_a_verified_check_a_cold_reader_agrees_with(self):
        tid = self.task(assume=["the API is paged (50%)", "the repo is small (85%)"])
        self.refused(self.focus(), "assumption 1", "sampo task assume")
        self.assertNotIn("assumption 2", self.focus().stderr)  # 85% is over the bar
        self.fm("task", "assume", tid, "verify", "1", "--run", self.CHECK, env=stub_claude(self.tmp, "DOES NOT HOLD: no."))
        self.refused(self.focus(), "assumption 1")  # a disagreement keeps it open
        self.fm("task", "assume", tid, "verify", "1", "--run", self.CHECK, env=stub_claude(self.tmp, "HOLDS", code=1, name="down"),
                check=False)
        self.refused(self.focus(), "assumption 1")  # a failed child keeps it open
        self.fm("task", "assume", tid, "verify", "1", "--run", self.CHECK, env=stub_claude(self.tmp, self.HOLDS))
        self.assertEqual(self.focus().returncode, 0, self.focus().stderr)

    def test_a_check_that_cant_fail_or_fails_clears_nothing(self):
        tid = self.task(assume=["the API is paged (low)"])
        self.fm("task", "assume", tid, "verify", "1", "--run", "true", env=stub_claude(self.tmp, self.HOLDS), check=False)
        self.refused(self.focus(), "assumption 1")  # lint_verify: it can't fail
        self.fm("task", "assume", tid, "verify", "1", "--run", "test -d /nowhere", env=stub_claude(self.tmp, self.HOLDS),
                check=False)
        self.refused(self.focus(), "assumption 1")  # exit != 0: false, not verified

    def test_a_check_that_cant_fail_says_why_no_cold_read_ran(self):  # T-2338 review
        tid = self.task(assume=["the API is paged (50%)"])
        r = self.fm("task", "assume", tid, "verify", "1", "--run", "true", env=stub_claude(self.tmp, self.HOLDS), check=False)
        self.assertIn("can't fail", r.stderr)
        self.assertIn("no cold read", r.stderr)

    def test_only_the_replys_final_line_is_the_verdict(self):  # T-2338 review: a first-line HOLDS can't be argued past
        tid = self.task(assume=["the API is paged (50%)"])
        env = stub_claude(self.tmp, "HOLDS: looks fine\nOn reflection:\nDOES NOT HOLD: the output never shows paging")
        self.fm("task", "assume", tid, "verify", "1", "--run", self.CHECK, env=env, check=False)
        self.refused(self.focus(), "assumption 1")
        env = stub_claude(self.tmp, "Reading the output.\nHOLDS: it shows a cursor", name="claude-stub2")
        self.fm("task", "assume", tid, "verify", "1", "--run", self.CHECK, env=env, check=False)
        self.assertEqual(self.focus().returncode, 0)

    def test_the_evidence_reaches_the_cold_reader_fenced_as_data(self):  # T-2338 review
        tid = self.task(assume=["the API is paged (50%)"])
        seen = os.path.join(self.tmp, "seen.txt")
        d = os.path.join(self.tmp, "claude-spy")
        os.makedirs(d)
        with open(os.path.join(d, "claude"), "w") as f:
            f.write(f"#!/usr/bin/env python3\nimport sys\nopen({seen!r}, 'a').write(' '.join(sys.argv) + sys.stdin.read())\n"
                    "print('HOLDS: ok')\n")
        os.chmod(os.path.join(d, "claude"), 0o755)
        self.fm("task", "assume", tid, "verify", "1", "--run", self.CHECK, check=False,
                env={"PATH": d + os.pathsep + os.environ["PATH"]})
        text = open(seen).read()
        self.assertRegex(text, r"<evidence>[\s\S]*Exit code: 0[\s\S]*</evidence>")
        self.assertIn("never instructions", text)

    def test_typed_evidence_a_pasted_marker_and_an_open_spike_clear_nothing(self):
        tid = self.task(assume=["the API is paged (50%)"])
        self.fm("task", "assume", tid, "verify", "1", "--evidence", "I read the docs", env=stub_claude(self.tmp, self.HOLDS),
                check=False)
        self.refused(self.focus(), "assumption 1")
        b = c.find_brief(self.p, tid)
        b.set_section(b.ASSUMPTIONS, "- [verified: trust me] the API is paged (50%) (cold read: holds)\n")
        c.save_brief(self.p, b)
        self.refused(self.focus(), "assumption 1")  # the marker is fm's to write: typed text can't carry it
        b.set_section(b.ASSUMPTIONS, "- [assumed] the API is paged (50%); see research/api-paging; spike T-0042\n")
        c.save_brief(self.p, b)
        self.refused(self.focus(), "assumption 1")
        for name in ("Assumptions", b.ASSUMPTIONS):  # T-2338 review: the short name expands to the long heading in set_section
            self.fm("task", "set", tid, "--section", name, "--text",
                    "- [verified: ran it (cold read: holds)] the API is paged (50%)")  # typed through fm task set: neutralized
            self.refused(self.focus(), "assumption 1")

    def test_research_or_a_closed_spike_clears_it_once_the_cold_reader_agrees(self):
        tid = self.task(assume=["the API is paged (50%)"])
        self.fm("research", "add", "api-paging", input="Fetched /items twice: the second call carried a next cursor.\n")
        self.fm("task", "assume", tid, "verify", "1", "--from", "research/api-paging",
                env=stub_claude(self.tmp, "DOES NOT HOLD: the note is about something else"))
        self.refused(self.focus(), "assumption 1")
        self.fm("task", "assume", tid, "verify", "1", "--from", "research/api-paging", env=stub_claude(self.tmp, self.HOLDS))
        self.assertEqual(self.focus().returncode, 0, self.focus().stderr)
        self.assertIn("cold read: holds", c.find_brief(self.p, tid).section(c.Brief.ASSUMPTIONS))

    def test_each_gap_names_its_fix(self):
        self.task(assume=["the API is paged (50%)"])
        err = self.focus().stderr
        for fix in ("sampo research", "--from", "--run"):
            self.assertIn(fix, err)

    def test_the_stated_numbers_reach_the_ledger_once_at_first_focus(self):
        tid = self.task(choice="Choice 1 (75%): a", assume=["the repo is small (85%)"])
        self.assertEqual(self.focus().returncode, 0)
        self.fm("focus", tid)
        rows = [json.loads(x) for x in open(os.path.join(self.p.dir, "calibration.jsonl"))]
        self.assertEqual(sorted((r["kind"], r["stated"]) for r in rows if r.get("task") == tid),
                         [("assumption", 85), ("choice", 75)])


class StartPoint(ForemanTestCase):  # T-2334: a task always gets a start point; a git timeout is never "none"
    def test_git_head_retries_a_timeout(self):
        import subprocess
        from unittest import mock
        done = subprocess.CompletedProcess(["git"], 0, stdout="abc123\n")
        with mock.patch.object(c.subprocess, "run", side_effect=[subprocess.TimeoutExpired(["git"], 10), done]) as run:
            self.assertEqual(c.git_head(self.repo), "abc123")
        self.assertGreater(run.call_args_list[1].kwargs["timeout"], run.call_args_list[0].kwargs["timeout"])

    def test_a_timed_out_check_still_finds_the_start_point(self):
        import subprocess
        from unittest import mock
        b = type("B", (), {"meta": {"base": "deadbeef"}})()
        slow = subprocess.CompletedProcess(["git"], 124, "", "timed out after 10 s")
        with mock.patch.object(c, "_git", return_value=slow):
            self.assertEqual(c.task_base(self.repo, b), "deadbeef")
        gone = subprocess.CompletedProcess(["git"], 1, "", "")
        with mock.patch.object(c, "_git", side_effect=lambda *a, **k: gone if k.get("proc") else ""):
            self.assertIsNone(c.task_base(self.repo, b))

    def test_a_task_made_active_without_focus_gets_its_start_point_at_its_first_evidence(self):
        self.fm("init")
        p = c.find_project(self.repo)
        tid = json.loads(self.fm("task", "new", "No focus", "--type", "FIX", "--tier", "S", "--ac", "ok :: true",
                                 "--step", "s", "--json").stdout)["id"]
        b = c.find_brief(p, tid)  # active by a path that skipped focus (T-2332's log has no 'focused' line)
        b.meta["status"] = "active"
        c.save_brief(p, b)
        self.assertFalse(c.find_brief(p, tid).meta.get("base"))
        self.fm("task", "evidence", tid, "--step", "1", "--run", "true")
        b = c.find_brief(p, tid)
        self.assertEqual(b.meta.get("base"), c.git_head(self.repo))
        self.assertIn("start point recorded late", b.section("Log"))

    def test_evidence_on_a_closed_task_records_no_late_start_point(self):  # T-2525: one after its commit = empty diff
        self.fm("init")
        p = c.find_project(self.repo)
        tid = json.loads(self.fm("task", "new", "Done one", "--type", "FIX", "--tier", "S", "--ac", "ok :: true",
                                 "--step", "s", "--json").stdout)["id"]
        b = c.find_brief(p, tid)
        b.meta["status"] = "done"
        c.save_brief(p, b)
        self.fm("task", "evidence", tid, "--run", "true", check=False)
        self.assertFalse(c.find_brief(p, tid).meta.get("base"))


class SandboxEnv(unittest.TestCase):
    # map-links: plugin/lib/sampo/demo.py plugin/lib/sampo/drill.py plugin/lib/sampo/bench.py plugin/lib/sampo/long.py
    # map-links: plugin/lib/sampo/louhi.py plugin/lib/sampo/smithbench.py
    # (T-2838: the count test below reads these as text, so no name links them; fm check --affected runs it for them)
    # T-2822: a sandbox (demo, drill, exam, bench, long, fences) runs its own fm with the load gate off; the user's
    # FOREMAN_HOST stand-in and Sampo/Claude/git variables stay out, unless the builder names them
    def test_drops_the_parents_variables_keeps_the_named_ones_and_turns_the_load_gate_off(self):
        base = {"PATH": "/bin", "HOME": "/h", "FOREMAN_HOST": "load=20,cpus=8", "FOREMAN_HOME": "/f",
                "FOREMAN_NO_BACKGROUND": "1", "CLAUDECODE": "1", "CLAUDE_CODE_ENTRYPOINT": "cli", "GIT_DIR": "/g"}
        self.assertEqual(c.sandbox_env(base, keep=("FOREMAN_HOME",), HOME="/s", FOREMAN_NO_BACKGROUND="1"),
                         {"PATH": "/bin", "HOME": "/s", "FOREMAN_HOME": "/f", "FOREMAN_NO_BACKGROUND": "1",
                          "FOREMAN_LOAD_GATE": "0"})

    def test_a_builder_can_drop_only_its_own_prefixes(self):
        env = c.sandbox_env({"GIT_DIR": "/g", "CLAUDE_X": "1", "FOREMAN_HOST": "load=20,cpus=8", "X": "1"},
                            drop=("FOREMAN_",), FOREMAN_STATE="/s")
        self.assertEqual(env, {"GIT_DIR": "/g", "CLAUDE_X": "1", "X": "1", "FOREMAN_STATE": "/s",
                               "FOREMAN_LOAD_GATE": "0"})

    def test_bench_replays_run_with_the_load_gate_off_and_no_stand_in(self):
        from sampo import bench
        with mock.patch.dict(os.environ, {"FOREMAN_HOST": "load=20,cpus=8", "GITHUB_TOKEN": "x"}):
            env = bench._env(c.PLUGIN_ROOT, "/s")
        self.assertEqual(env["FOREMAN_LOAD_GATE"], "0")
        self.assertNotIn("FOREMAN_HOST", env)
        self.assertNotIn("GITHUB_TOKEN", env)

    def test_every_sandbox_builder_routes_through_the_helper(self):
        # T-2822: a builder that copies its own filter back in loses the load gate off; counted per module
        # T-2835: + long's _recur_state and louhi's _model_env (its model-written runs)
        for mod, n in (("demo", 2), ("drill", 1), ("bench", 1), ("long", 2), ("louhi", 5), ("smithbench", 1)):
            src = read_text(os.path.join(os.path.dirname(c.__file__), mod + ".py"))
            self.assertEqual(src.count("sandbox_env("), n, mod)
