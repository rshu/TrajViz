"""Ingest robustness: the never-raise contract of ``load_trajectory`` and metric invariants.

``run_group.build_run_group_scorecard`` calls ``load_trajectory`` with no
``try/except`` (``run_group.py:723``), so a loader that raises does not degrade
one row — it aborts the whole batch. The contract every test in this file
defends is therefore:

    for ANY bytes on disk, ``load_trajectory`` returns a dict that either
    carries ``_error`` (a clean, user-facing failure) or is a parsed
    trajectory. It never raises, never hangs, never consumes unbounded memory.

The second half defends ``compute_metrics``: numbers that reach a report must be
finite, counts must not be negative, and a field whose name says *percent* must
be a percentage. These are asserted as properties over generated well-typed
payloads rather than pinned against today's output.

When a test here is marked ``@unittest.expectedFailure`` it states a contract
the code currently breaks, and names the defect. **Removing the decorator is
part of the fix** — an unexpected success fails the run, which is the intended
signal. Nothing here pins broken behaviour as correct; none of these markers is
outstanding today.
"""

import json
import math
import os
import tempfile
import unittest
import zipfile

from hypothesis import HealthCheck, given, settings
from hypothesis import strategies as st

from claude_native_helpers import native_events

from agent_trajviz.insight.formats.parse import _parse_jsonl_events
from agent_trajviz.insight.loaders import load_trajectory
from agent_trajviz.insight.metrics import build_message_metrics, compute_metrics
from agent_trajviz.insight.parser import parse_steps

# Metric keys whose name promises a non-negative quantity.
_NONNEG_NAME_HINTS = ("count", "total", "duration", "tokens", "seconds", "calls", "steps")


def _write_bytes(tmp, name, data):
    path = os.path.join(tmp, name)
    with open(path, "wb") as handle:
        handle.write(data if isinstance(data, bytes) else data.encode("utf-8"))
    return path


def _write_json(tmp, name, doc):
    return _write_bytes(tmp, name, json.dumps(doc))


def _codex_stream(extra=()):
    """A minimal, valid Codex rollout as a list of events."""
    return [
        {"type": "session_meta", "timestamp": "2026-01-05T12:00:00.000Z",
         "payload": {"id": "s1", "cwd": "/p/proj", "model": "gpt-5", "model_provider": "openai"}},
        {"type": "response_item", "timestamp": "2026-01-05T12:00:01.000Z",
         "payload": {"type": "message", "role": "user", "content": [{"type": "input_text", "text": "fix it"}]}},
        {"type": "response_item", "timestamp": "2026-01-05T12:00:02.000Z",
         "payload": {"type": "message", "role": "assistant",
                     "content": [{"type": "output_text", "text": "done"}]}},
        *extra,
    ]


def _jsonl_text(events):
    return "".join(json.dumps(e, ensure_ascii=False) + "\n" for e in events)


def _opencode_doc(messages, info_time=None):
    return {
        "info": {"id": "s1", "time": info_time or {"created": 0, "updated": 10_000}},
        "messages": messages,
    }


def _opencode_message(*, index=0, role="assistant", tokens=None, parts=None, created=0, elapsed=1000):
    return {
        "role": role,
        "info": {
            "id": f"m{index}", "role": role,
            "time": {"created": created, "completed": created + elapsed},
            "tokens": tokens if tokens is not None else {
                "total": 100, "input": 40, "output": 60, "reasoning": 0,
                "cache": {"read": 0, "write": 0},
            },
        },
        "parts": parts if parts is not None else [],
    }


def _walk_numbers(obj, prefix=""):
    """Yield ``(dotted_key, value)`` for every scalar in a nested metrics dict."""
    if isinstance(obj, dict):
        for key, value in obj.items():
            yield from _walk_numbers(value, f"{prefix}.{key}" if prefix else str(key))
    elif isinstance(obj, list):
        for i, value in enumerate(obj):
            yield from _walk_numbers(value, f"{prefix}[{i}]")
    else:
        yield prefix, obj


def _metrics_for(path):
    raw = load_trajectory(path)
    steps = parse_steps(raw)
    return compute_metrics(steps, raw, build_message_metrics(steps))


class LoadTrajectoryNeverRaises(unittest.TestCase):
    """Every hostile byte sequence must come back as a dict, not an exception.

    One unreadable file in an upload batch must cost that file's row, not the
    whole scorecard.
    """

    def setUp(self):
        self._dir = tempfile.TemporaryDirectory()
        self.tmp = self._dir.name
        self.addCleanup(self._dir.cleanup)

    def _assert_contract(self, path, hint=None):
        try:
            result = load_trajectory(path, hint)
        except Exception as exc:  # noqa: BLE001 - the contract is "no exception of any type"
            self.fail(f"load_trajectory({os.path.basename(path)!r}) raised {type(exc).__name__}: {exc}")
        self.assertIsInstance(result, dict, f"{path} returned {type(result).__name__}, not a dict")
        return result

    def test_degenerate_text_inputs_are_clean_errors_or_parses(self):
        """Empty, whitespace-only, and non-object JSON documents must not crash the loader."""
        cases = {
            "empty.json": b"",
            "empty.jsonl": b"",
            "whitespace.json": b"   \n\t\n  ",
            "whitespace.jsonl": b"   \n\t\n  ",
            "null.json": b"null",
            "true.json": b"true",
            "int.json": b"12345",
            "string.json": b'"hello"',
            "empty_array.json": b"[]",
            "empty_array.jsonl": b"[]",
            "empty_object.json": b"{}",
            "array_of_null.json": b"[null, null]",
            "array_of_string.json": b'["a", "b"]',
            "trailing_comma.json": b'{"info": {}, "messages": [],}',
            "lone_brace.json": b"{",
        }
        for name, data in cases.items():
            with self.subTest(case=name):
                self._assert_contract(_write_bytes(self.tmp, name, data))

    def test_powershell_utf16_bom_loads_and_a_stray_ff_does_not(self):
        """A UTF-8 BOM and a PowerShell UTF-16 BOM both load; a stray 0xFF does not."""
        doc = json.dumps(_opencode_doc([_opencode_message()]))
        bom = self._assert_contract(_write_bytes(self.tmp, "bom.json", b"\xef\xbb\xbf" + doc.encode("utf-8")))
        self.assertNotIn("_error", bom, "a UTF-8 BOM is not a corrupt file")

        for name, encoded in (
            ("utf16-le.json", b"\xff\xfe" + doc.encode("utf-16-le")),
            ("utf16-be.json", b"\xfe\xff" + doc.encode("utf-16-be")),
        ):
            with self.subTest(name=name):
                loaded = self._assert_contract(_write_bytes(self.tmp, name, encoded))
                self.assertNotIn("_error", loaded)
                self.assertEqual(loaded["metadata"]["session_id"], "s1")

        bad = self._assert_contract(
            _write_bytes(self.tmp, "badutf8.json", b'{"info": {}, "messages": [], "x": "\xff\xfe"}')
        )
        self.assertIn("_error", bad)

    def test_wrong_types_in_every_structural_slot(self):
        """A field of the wrong JSON type must not take the loader down."""
        cases = {
            "messages_is_string.json": {"info": {}, "messages": "not a list"},
            "messages_of_null.json": {"info": {}, "messages": [None, None]},
            "parts_is_string.json": {"info": {}, "messages": [{"info": {}, "parts": "nope"}]},
            "parts_of_scalars.json": {"info": {}, "messages": [{"info": {}, "parts": [None, 1, "x"]}]},
            "info_is_null.json": {"info": {"time": None, "id": None},
                                  "messages": [{"info": None, "parts": []}]},
            "time_is_text.json": {"info": {"time": {"created": "yesterday"}}, "messages": []},
            "tokens_is_string.json": {"info": {}, "messages": [{"info": {"tokens": "lots"}, "parts": []}]},
            "cc_content_is_string.json": [{"type": "assistant", "sessionId": "s", "uuid": "a", "message": {"role": "assistant", "content": "nope"}}],
            "cc_content_of_scalars.json": [{"type": "assistant", "sessionId": "s", "uuid": "a", "message": {"role": "assistant", "content": [None, 3, "x"]}}],
            "cc_message_is_string.json": [{"type": "assistant", "sessionId": "s", "uuid": "a", "message": "str"}],
        }
        for name, doc in cases.items():
            with self.subTest(case=name):
                self._assert_contract(_write_json(self.tmp, name, doc))

    def test_pathological_json_shapes(self):
        """Deep nesting and very large scalars must be handled without a crash."""
        deep = {"info": {}, "messages": []}
        cursor = deep
        for _ in range(200):
            nxt = {"a": None}
            cursor["x"] = nxt
            cursor = nxt
        self._assert_contract(_write_json(self.tmp, "deep.json", deep))

        big = {"info": {"id": "x" * 2_000_000}, "messages": []}
        self._assert_contract(_write_json(self.tmp, "bigstring.json", big))

        dup = b'{"info": {}, "messages": [], "messages": [1, 2, 3]}'
        self._assert_contract(_write_bytes(self.tmp, "dupkeys.json", dup))

    def test_truncated_documents_for_every_object_format(self):
        """A file cut off at 10/50/90% must produce ``_error`` or a parse — never a traceback."""
        sources = {
            "opencode.json": json.dumps(_opencode_doc([_opencode_message(index=i, created=i * 1000)
                                                       for i in range(20)])),
            "claude_code.json": json.dumps(native_events([
                    {"role": "assistant", "timestamp": "2026-01-05T12:00:00.000Z",
                     "message_id": f"m{i}", "content": [{"type": "text", "text": "x" * 200}]}
                    for i in range(20)
                ])),
            "codex.jsonl": _jsonl_text(_codex_stream()),
        }
        for name, text in sources.items():
            data = text.encode("utf-8")
            for pct in (10, 50, 90):
                with self.subTest(case=name, pct=pct):
                    cut = data[: max(1, len(data) * pct // 100)]
                    self._assert_contract(_write_bytes(self.tmp, f"trunc{pct}_{name}", cut))

    def test_filesystem_hostility(self):
        """Missing files, directories, broken symlinks and unreadable files are ``_error``, not crashes."""
        missing = self._assert_contract(os.path.join(self.tmp, "does-not-exist.json"))
        self.assertIn("_error", missing)

        empty_dir = os.path.join(self.tmp, "adir.json")
        os.makedirs(empty_dir)
        self.assertIn("_error", self._assert_contract(empty_dir))

        link = os.path.join(self.tmp, "broken.json")
        os.symlink(os.path.join(self.tmp, "nowhere"), link)
        self.assertIn("_error", self._assert_contract(link))

        locked = _write_json(self.tmp, "locked.json", _opencode_doc([]))
        os.chmod(locked, 0)
        self.addCleanup(os.chmod, locked, 0o600)
        if os.access(locked, os.R_OK):
            self.skipTest("running as a user that ignores file permissions")
        self.assertIn("_error", self._assert_contract(locked))

    def test_session_directory_resolves_to_its_session_jsonl(self):
        """A DSH session *directory* must load its ``session.jsonl``, not error out."""
        sess = os.path.join(self.tmp, "sessdir")
        os.makedirs(sess)
        with open(os.path.join(sess, "session.jsonl"), "w", encoding="utf-8") as handle:
            handle.write('{"type": "session", "id": "s1", "createdAt": 0}\n{"type": "user/message"}\n')
        self.assertNotIn("_error", self._assert_contract(sess))

    def test_unsupported_extension_is_refused_by_name(self):
        """``.log`` is explicitly unsupported and must say so rather than parse garbage."""
        result = self._assert_contract(_write_bytes(self.tmp, "x.log", b"{}"))
        self.assertIn("_error", result)

    def test_out_of_range_session_timestamp_is_a_clean_error(self):
        """A microsecond/nanosecond timestamp must not abort the batch.

        ``info.time.created`` / ``info.time.updated`` reach
        ``datetime.fromtimestamp``, which raised ``ValueError: year 56664 is out
        of range`` for a recorder that wrote microseconds instead of
        milliseconds — out of ``load_trajectory``, which ``run_group`` does not
        catch. An unrepresentable instant is now reported as missing rather than
        clamped to a plausible-looking date, and the representable endpoint of
        the same session still converts.
        """
        doc = _opencode_doc([], info_time={"created": 0, "updated": 1_726_000_000_000_000})
        raw = self._assert_contract(_write_json(self.tmp, "microseconds.json", doc))
        self.assertNotIn("_error", raw)
        self.assertEqual(raw["timing"]["started_at"], "1970-01-01T00:00:00+00:00")
        self.assertEqual(raw["timing"]["finished_at"], "")
        # A duration needs BOTH endpoints: pairing epoch 0 with the raw
        # microsecond value would report a 1.7-billion-second session.
        self.assertEqual(raw["timing"]["total_duration"], 0.0)

    def test_string_valued_token_counts_are_a_clean_error(self):
        """Token counts serialized as JSON strings must not abort the batch.

        The session-level token accumulators used ``+=`` with no type check, so
        ``"tokens": {"input": "50"}`` raised ``TypeError: unsupported operand
        type(s) for +=: 'int' and 'str'`` out of ``load_trajectory``
        (``opencode``/``codearts``), as did the ``str + int`` in Claude Code's
        usage extraction. One doc only exercises one converter, so all three
        are covered here. A non-numeric count is now *rejected* (contributes
        nothing), not coerced — the same reading ``usable_token_count`` gives an
        unusable value.
        """
        string_tokens = {"total": "100", "input": "50", "output": "50",
                         "cache": {"read": "0", "write": "0"}}
        opencode = _opencode_doc([_opencode_message(tokens=string_tokens)])
        codearts = _opencode_doc([_opencode_message(tokens=string_tokens)])
        codearts["export_metadata"] = {
            "schema_version": 2, "source_format": "codearts_opencode_sqlite",
            "generator_name": "codearts_consolidator",
        }
        claude_code = native_events([{
                "role": "assistant",
                "content": [{"type": "text", "text": "hi"}],
                "usage": {"input_tokens": "50", "output_tokens": 5,
                          "cache_read_input_tokens": "0",
                          "cache_creation_input_tokens": "0"},
            }])
        for name, doc in (("opencode", opencode), ("codearts", codearts),
                          ("claude_code", claude_code)):
            with self.subTest(format=name):
                raw = self._assert_contract(_write_json(self.tmp, f"tokens_{name}.json", doc))
                self.assertNotIn("_error", raw)
                self.assertEqual(raw["token_usage"]["total_tokens"], 5 if name == "claude_code" else 0)
        # Claude Code sums its per-message usage, so the one usable field in
        # that payload must survive while the strings drop out.
        cc_raw = load_trajectory(os.path.join(self.tmp, "tokens_claude_code.json"))
        self.assertEqual([s["tokens"]["total"] for s in parse_steps(cc_raw)], [5])

    def test_non_finite_token_values_do_not_crash_the_pipeline(self):
        """``NaN``/``Infinity`` literals must not crash metrics computation.

        ``json.dump`` emits bare ``NaN`` / ``Infinity`` by default, so any
        upstream exporter written in Python can produce such a file. The loader
        accepts it, and these values used to reach ``statistics.median`` and
        raise ``ValueError: cannot convert float NaN to integer``. They are now
        dropped at parse time (``parser._finite_token``).
        """
        text = (
            '{"info": {"id": "s"}, "messages": [{"role": "assistant", "info": '
            '{"id": "m", "role": "assistant", "time": {"created": 1000, "completed": 2000}, '
            '"tokens": {"total": NaN, "input": NaN, "output": 1, "cache": {"read": 0, "write": 0}}}, '
            '"parts": []}]}'
        )
        path = _write_bytes(self.tmp, "nan.json", text)
        raw = self._assert_contract(path)
        if "_error" not in raw:
            steps = parse_steps(raw)
            compute_metrics(steps, raw, build_message_metrics(steps))


class JsonlLineSplitting(unittest.TestCase):
    """``formats/parse.py`` is the shared layer every JSONL load now goes through."""

    def setUp(self):
        self._dir = tempfile.TemporaryDirectory()
        self.tmp = self._dir.name
        self.addCleanup(self._dir.cleanup)

    def test_interior_corruption_is_reported_not_silently_dropped(self):
        """A corrupt first or middle line must fail loudly; silently skipping it loses steps."""
        events = _codex_stream()
        for position in (0, 1):
            with self.subTest(position=position):
                lines = _jsonl_text(events).splitlines()
                lines[position] = '{"type": "broken", '
                text = "\n".join(lines) + "\n"
                parsed, err = _parse_jsonl_events(text)
                self.assertIsNone(parsed)
                self.assertIsNotNone(err)
                self.assertIn(f"line {position + 1}", err)

    def test_corrupt_final_line_with_newline_is_an_error(self):
        """A terminated final line is complete, so a decode failure there is real corruption."""
        lines = _jsonl_text(_codex_stream()).splitlines()
        lines[-1] = '{"type": "broken", '
        parsed, err = _parse_jsonl_events("\n".join(lines) + "\n")
        self.assertIsNone(parsed)
        self.assertIsNotNone(err)

    def test_unterminated_final_line_is_treated_as_an_in_progress_append(self):
        """Rollouts are append-only: the last line without a newline may still be being written."""
        lines = _jsonl_text(_codex_stream()).splitlines()
        lines[-1] = '{"type": "broken", '
        parsed, err = _parse_jsonl_events("\n".join(lines))
        self.assertIsNone(err)
        self.assertEqual(len(parsed), len(_codex_stream()) - 1)

    def test_blank_and_crlf_lines_do_not_shift_the_event_stream(self):
        """Blank separators and Windows line endings must not add or drop events."""
        events = _codex_stream()
        text = "\r\n".join(json.dumps(e) for e in events) + "\r\n"
        parsed, err = _parse_jsonl_events(text)
        self.assertIsNone(err)
        self.assertEqual(len(parsed), len(events))

        padded = "\n\n" + "\n\n".join(json.dumps(e) for e in events) + "\n\n"
        parsed, err = _parse_jsonl_events(padded)
        self.assertIsNone(err)
        self.assertEqual(len(parsed), len(events))

        # A lone ``\r`` is also a line end here, and must stay one: a raw CR
        # cannot appear inside a valid JSON string, so splitting on it is safe
        # and some classic-Mac/terminal-captured exports use it alone. Pinned
        # against a future "split on \\n only" simplification.
        old_mac = "\r".join(json.dumps(e) for e in events) + "\r"
        parsed, err = _parse_jsonl_events(old_mac)
        self.assertIsNone(err)
        self.assertEqual(len(parsed), len(events))

    def test_unicode_line_separators_inside_strings_do_not_split_events(self):
        """A valid JSONL event whose text contains U+2028 must still load.

        ``_parse_jsonl_events`` used ``str.splitlines()``, which breaks on
        U+2028, U+2029 and U+0085 as well as ``\\n``. Those three are legal
        *unescaped* inside a JSON string (JSON only forbids U+0000-U+001F), and
        serde_json — the Codex CLI writer — does not escape them, so one agent
        message containing a Unicode line separator turned a valid rollout into
        ``Invalid JSONL at line N: Unterminated string``. JSONL lines end at
        ``\\n`` / ``\\r\\n`` / ``\\r`` and nowhere else.
        """
        for separator in ("\u2028", "\u2029", "\u0085"):
            with self.subTest(separator=hex(ord(separator))):
                events = _codex_stream()
                events[2]["payload"]["content"][0]["text"] = f"before{separator}after"
                text = _jsonl_text(events)
                # The file really is valid JSONL when split the way JSONL defines it.
                for line in text.split("\n"):
                    if line.strip():
                        json.loads(line)
                parsed, err = _parse_jsonl_events(text)
                self.assertIsNone(err, err)
                self.assertEqual(len(parsed), len(events))


class ZipIngestContract(unittest.TestCase):
    """The DSH zip branch reads members in memory and must stay bounded and safe."""

    def setUp(self):
        self._dir = tempfile.TemporaryDirectory()
        self.tmp = self._dir.name
        self.addCleanup(self._dir.cleanup)

    @staticmethod
    def _session_jsonl(session_id="s1"):
        return (
            json.dumps({"type": "session", "id": session_id, "createdAt": 0}) + "\n"
            + json.dumps({"type": "user/message", "body": {"text": "hi"}}) + "\n"
        )

    def _zip(self, name, members):
        path = os.path.join(self.tmp, name)
        with zipfile.ZipFile(path, "w", zipfile.ZIP_DEFLATED, compresslevel=1) as archive:
            for member, payload in members.items():
                archive.writestr(member, payload)
        return path

    def _load(self, path):
        try:
            return load_trajectory(path)
        except Exception as exc:  # noqa: BLE001 - the contract is "no exception of any type"
            self.fail(f"load_trajectory({os.path.basename(path)!r}) raised {type(exc).__name__}: {exc}")

    def test_zip_without_session_jsonl_is_a_clean_error(self):
        """An arbitrary zip is not a DSH export and must say so."""
        result = self._load(self._zip("other.zip", {"readme.txt": "hello"}))
        self.assertIn("_error", result)

    def test_truncated_and_fake_archives_are_clean_errors(self):
        """``PK``-prefixed bytes that are not a zip must not escape as ``BadZipFile``."""
        good = self._zip("good.zip", {"session.jsonl": self._session_jsonl()})
        with open(good, "rb") as handle:
            data = handle.read()
        self.assertIn("_error", self._load(_write_bytes(self.tmp, "cut.zip", data[: len(data) // 2])))
        self.assertIn("_error", self._load(_write_bytes(self.tmp, "fake.zip", b"PKnot-a-zip")))

    def test_traversal_member_names_never_write_outside_the_archive(self):
        """Zip-slip guard: members are read in memory, so no ``../`` path may hit the disk."""
        outside = os.path.join(self.tmp, "evil.txt")
        path = self._zip("traversal.zip", {
            "session.jsonl": self._session_jsonl(),
            "../../evil.txt": "pwned",
            "subagents/../../../evil2/session.jsonl": '{"type": "session", "id": "c1", "createdAt": 0}\n',
        })
        before = sorted(os.listdir(self.tmp))
        self._load(path)
        self.assertFalse(os.path.exists(outside))
        self.assertFalse(os.path.exists(os.path.join(os.path.dirname(self.tmp), "evil.txt")))
        self.assertEqual(sorted(os.listdir(self.tmp)), before)

    def test_oversized_member_is_refused_without_decompressing_it(self):
        """A high-ratio bomb must be rejected on its declared size, not by expanding it."""
        path = os.path.join(self.tmp, "bomb.zip")
        with zipfile.ZipFile(path, "w", zipfile.ZIP_DEFLATED, compresslevel=1) as archive:
            archive.writestr("session.jsonl", b"\0" * (64 * 1024 * 1024))
        self.assertLess(os.path.getsize(path), 1_000_000, "the bomb should be tiny on disk")
        result = self._load(path)
        self.assertIn("_error", result)

    def test_many_members_stay_bounded(self):
        """A zip with thousands of child sessions must load without scanning them all."""
        members = {"session.jsonl": self._session_jsonl()}
        for i in range(2000):
            members[f"subagents/c{i}/session.jsonl"] = self._session_jsonl(f"c{i}")
        result = self._load(self._zip("many.zip", members))
        self.assertIsInstance(result, dict)

    def test_encrypted_member_is_a_clean_error(self):
        """A password-protected member must not abort the batch.

        ``archive.read(member)`` was guarded only against ``KeyError``, so
        ``zipfile`` raised ``RuntimeError: File 'session.jsonl' is encrypted,
        password required for extraction`` straight out of ``load_trajectory``.
        The read now also catches ``RuntimeError`` / ``zipfile.BadZipFile``.
        """
        plain = self._zip("plain.zip", {"session.jsonl": self._session_jsonl()})
        with open(plain, "rb") as handle:
            data = bytearray(handle.read())
        # Set the "encrypted" general-purpose flag in the local (+6) and
        # central-directory (+8) headers without actually encrypting anything.
        for magic, offset in ((b"PK\x03\x04", 6), (b"PK\x01\x02", 8)):
            i = 0
            while True:
                i = data.find(magic, i)
                if i < 0:
                    break
                data[i + offset] |= 0x01
                i += 4
        path = _write_bytes(self.tmp, "encrypted.zip", bytes(data))
        result = self._load(path)
        self.assertIn("_error", result)


class MetricInvariants(unittest.TestCase):
    """Numbers that reach a report must be finite, non-negative, and in range."""

    @classmethod
    def setUpClass(cls):
        cls._dir = tempfile.TemporaryDirectory()
        cls.tmp = cls._dir.name

    @classmethod
    def tearDownClass(cls):
        cls._dir.cleanup()

    def _assert_invariants(self, metrics, doc):
        context = json.dumps(doc)[:400]
        for key, value in _walk_numbers(metrics):
            if isinstance(value, bool) or not isinstance(value, (int, float)):
                continue
            leaf = key.rsplit(".", 1)[-1].split("[")[0]
            if isinstance(value, float):
                self.assertFalse(math.isnan(value), f"{key} is NaN ({context})")
                self.assertFalse(math.isinf(value), f"{key} is infinite ({context})")
            if any(hint in leaf for hint in _NONNEG_NAME_HINTS):
                self.assertGreaterEqual(value, 0, f"{key} = {value} ({context})")
            if "percent" in leaf or leaf.endswith("_pct"):
                self.assertTrue(0 <= value <= 100, f"{key} = {value} is not a percentage ({context})")
        rate = metrics.get("tool_success_rate")
        if isinstance(rate, (int, float)):
            self.assertTrue(0 <= rate <= 100, f"tool_success_rate = {rate} ({context})")
        observed = metrics["tool_success"] + metrics["tool_fail"]
        unknown = metrics.get("tool_unknown_outcomes", 0)
        self.assertEqual(
            metrics["tool_call_count"], observed + unknown,
            f"every tool call has either an observed or an unknown outcome ({context})",
        )
        self.assertEqual(metrics.get("tool_observed_outcomes", observed), observed)
        if unknown:
            self.assertIn("tool_observed_outcomes", metrics)
        # These generated payloads are native transcripts: a session-wide rate
        # needs complete outcome coverage, even when some calls have finished.
        if unknown or not observed:
            self.assertIsNone(rate, f"incomplete or absent outcome evidence has no rate ({context})")
            self.assertIsNone(metrics["tool_system_failure_rate"])
        else:
            self.assertEqual(rate, round(metrics["tool_success"] / observed * 100, 1))
            self.assertEqual(metrics["tool_system_failure_rate"], round(metrics["tool_fail"] / observed, 4))
        self.assertEqual(metrics["tool_call_count"], sum(metrics["tool_breakdown"].values()))
        self.assertEqual(metrics["tool_call_count"], sum(metrics["tool_status_breakdown"].values()))

    @settings(max_examples=40, deadline=None, suppress_health_check=list(HealthCheck))
    @given(
        messages=st.lists(
            st.fixed_dictionaries({
                "role": st.sampled_from(["user", "assistant"]),
                "created": st.integers(min_value=0, max_value=10 ** 12),
                "elapsed": st.integers(min_value=0, max_value=10 ** 6),
                "total": st.integers(min_value=0, max_value=10 ** 6),
                "inp": st.integers(min_value=0, max_value=10 ** 6),
                "out": st.integers(min_value=0, max_value=10 ** 6),
                "cache_read": st.integers(min_value=0, max_value=10 ** 6),
                "cache_write": st.integers(min_value=0, max_value=10 ** 6),
                "tools": st.lists(
                    st.tuples(
                        st.sampled_from(["bash", "read", "edit", "task", "grep"]),
                        st.sampled_from(["completed", "error", "running", "pending"]),
                        st.integers(min_value=0, max_value=10 ** 6),
                    ),
                    max_size=3,
                ),
            }),
            max_size=6,
        ),
    )
    def test_well_typed_payloads_yield_sane_metrics(self, messages):
        """For non-negative, well-ordered inputs no metric may be NaN, negative, or >100%.

        A counterexample here means the dashboard could report a number that is
        arithmetically impossible for the trace it came from.
        """
        docs = []
        for i, spec in enumerate(messages):
            parts = [
                {"type": "tool", "tool": name, "id": f"t{i}-{j}",
                 "state": {"status": status, "input": {}, "output": "",
                           "time": {"start": spec["created"], "end": spec["created"] + dur}}}
                for j, (name, status, dur) in enumerate(spec["tools"])
            ]
            docs.append(_opencode_message(
                index=i, role=spec["role"], created=spec["created"], elapsed=spec["elapsed"],
                tokens={"total": spec["total"], "input": spec["inp"], "output": spec["out"],
                        "reasoning": 0,
                        "cache": {"read": spec["cache_read"], "write": spec["cache_write"]}},
                parts=parts,
            ))
        doc = _opencode_doc(docs)
        path = _write_json(self.tmp, "prop.json", doc)
        raw = load_trajectory(path)
        self.assertNotIn("_error", raw, raw.get("_error"))
        steps = parse_steps(raw)
        metrics = compute_metrics(steps, raw, build_message_metrics(steps))
        self.assertEqual(metrics["total_steps"], len(steps))
        # Check the evidence partition against source records, independently
        # of the metrics implementation's failure predicate.
        statuses = [status for spec in messages for _, status, _ in spec["tools"]]
        self.assertEqual(metrics["tool_success"], statuses.count("completed"))
        self.assertEqual(metrics["tool_fail"], statuses.count("error"))
        self.assertEqual(metrics.get("tool_unknown_outcomes", 0),
                         statuses.count("running") + statuses.count("pending"))
        self._assert_invariants(metrics, doc)

    def test_outcome_rates_require_coverage_and_use_only_finished_calls(self):
        cases = [
            ([("completed", True), ("completed", True), ("error", True),
              ("running", None), ("pending", None)], (2, 1, 2), None),
            ([("running", None), ("pending", None)], (0, 0, 2), None),
            ([("completed", False), ("error", True)], (0, 1, 1), None),
            ([("completed", True), ("completed", True), ("error", True)], (2, 1, 0), 66.7),
        ]
        for index, (outcomes, expected_counts, expected_rate) in enumerate(cases):
            with self.subTest(outcomes=outcomes):
                parts = [{"type": "tool", "tool": "bash", "id": f"call-{i}",
                          "state": {"status": status, "input": {}, "output": "",
                                    "metadata": ({"_outcome_observed": observed} if observed is not None else {})}}
                         for i, (status, observed) in enumerate(outcomes)]
                doc = _opencode_doc([_opencode_message(parts=parts)])
                metrics = _metrics_for(_write_json(self.tmp, f"outcomes-{index}.json", doc))
                self.assertEqual((metrics["tool_success"], metrics["tool_fail"],
                                  metrics.get("tool_unknown_outcomes", 0)), expected_counts)
                self.assertEqual(metrics["tool_call_count"], len(outcomes))
                self.assertEqual(metrics["tool_success_rate"], expected_rate)
                self._assert_invariants(metrics, doc)

    def test_empty_and_single_step_trajectories_are_well_defined(self):
        """The degenerate sizes are where divide-by-zero guards are usually missed."""
        for label, messages in (("empty", []), ("one", [_opencode_message()])):
            with self.subTest(case=label):
                doc = _opencode_doc(messages)
                metrics = _metrics_for(_write_json(self.tmp, f"{label}.json", doc))
                self._assert_invariants(metrics, doc)

    def test_cache_read_above_the_reported_total_is_rejected_not_rendered(self):
        """A record that cannot yield a cache share is excluded and counted, not clamped.

        OpenCode reports a ``total`` that excludes the cache read, so an export
        once rendered ``Avg cache % = 25386.2%`` under a green "strong cache
        reuse" verdict. The shipped fix is
        rejection, not clamping: ``parser.cache_read_share`` is the single source
        of truth and returns ``None`` when ``cache_read > total``, and
        ``metrics`` then reports the headline as absent plus the number of steps
        responsible — a clamped 100% would be just as wrong, only quieter.
        Asserted against that function's behaviour rather than by re-deriving
        the arithmetic here, so the test tracks the single source of truth.
        """
        inconsistent = _opencode_doc([
            _opencode_message(
                index=i, created=i * 1000,
                tokens={"total": 1909, "input": -10739, "output": 248, "reasoning": 0,
                        "cache": {"read": 12400, "write": 0}},
            )
            for i in range(3)
        ])
        with self.subTest(case="cache_read_above_total"):
            metrics = _metrics_for(_write_json(self.tmp, "cache_over.json", inconsistent))
            self.assertIsNone(metrics["avg_cache_ratio"])
            self.assertEqual(metrics["cache_ratio_unusable_steps"], 3)

        # The domain still has to hold wherever the field IS populated.
        consistent = _opencode_doc([
            _opencode_message(
                index=i, created=i * 1000,
                tokens={"total": 20_000, "input": 5_000, "output": 5_000, "reasoning": 0,
                        "cache": {"read": 10_000, "write": 0}},
            )
            for i in range(3)
        ])
        with self.subTest(case="self_consistent"):
            metrics = _metrics_for(_write_json(self.tmp, "cache_ok.json", consistent))
            self.assertEqual(metrics["avg_cache_ratio"], 50.0)
            self.assertLessEqual(metrics["avg_cache_ratio"], 100)
            self.assertEqual(metrics["cache_ratio_unusable_steps"], 0)

    def test_token_totals_are_never_negative(self):
        """A token count is a count; a negative one must never reach a headline number.

        OpenCode subtracts the cache read from the prompt size, which
        double-subtracts against providers whose ``input_tokens`` is already
        cache-exclusive, so such exports carry a negative raw
        ``input``. Those records used to be summed, showing a negative
        ``Input`` chip in the millions. They are now excluded from the sum and counted in
        ``input_tokens_unusable_steps`` so the surface can say so.
        """
        doc = _opencode_doc([
            _opencode_message(
                index=i, created=i * 1000,
                tokens={"total": 1909, "input": -10739, "output": 248, "reasoning": 0,
                        "cache": {"read": 12400, "write": 0}},
            )
            for i in range(3)
        ])
        metrics = _metrics_for(_write_json(self.tmp, "neg_tokens.json", doc))
        self.assertGreaterEqual(metrics["input_tokens"], 0)


class StepSchemaContract(unittest.TestCase):
    """The generic ``parse_steps`` path and the Claude Code fast path share one schema.

    ``parse_steps`` returns ``raw["_claude_code_parsed_steps"]`` verbatim for Claude Code
    (``parser.py``), so ``_cc_build_step`` is the second writer of a schema every
    downstream reader shares. Key drift between the two is invisible until a
    reader stops using ``.get()``.
    """

    # Written out rather than derived, so adding a key to either writer has to
    # be a deliberate edit here too.
    _CANONICAL_STEP_KEYS = frozenset({
        "index", "raw_index", "role", "tokens", "duration", "parts", "tool_calls",
        "tool_call_count", "error_count", "has_reasoning", "text_preview", "finish",
        "model_id", "provider_id", "time_created_ms", "time_completed_ms", "agent",
        "mode", "message_id", "id", "parent_id", "session_id", "cwd", "root",
        "is_sub_agent", "parent_session_id", "session_depth", "session_title",
        "summary", "message_type", "is_compaction_checkpoint", "compaction_reason",
        "_metrics_unavailable_fields",
    })

    def setUp(self):
        self._dir = tempfile.TemporaryDirectory()
        self.tmp = self._dir.name
        self.addCleanup(self._dir.cleanup)

    def _generic_step(self):
        raw = load_trajectory(_write_json(self.tmp, "generic.json",
                                          _opencode_doc([_opencode_message()])))
        self.assertNotIn("_error", raw)
        steps = parse_steps(raw)
        self.assertEqual(len(steps), 1)
        return steps[0]

    def _cc_step(self):
        doc = native_events([{
                "role": "assistant", "timestamp": "2026-01-05T12:00:02.000Z",
                "content": [{"type": "text", "text": "done"}],
                "usage": {"input_tokens": 40, "output_tokens": 60,
                          "cache_read_input_tokens": 0,
                          "cache_creation_input_tokens": 0},
            }])
        raw = load_trajectory(_write_json(self.tmp, "cc.json", doc))
        self.assertNotIn("_error", raw)
        steps = parse_steps(raw)
        self.assertEqual(len(steps), 1)
        return steps[0]

    def test_parse_steps_emits_the_canonical_step_key_set(self):
        """No write-only keys: every step key must have a reader somewhere."""
        self.assertEqual(set(self._generic_step()), set(self._CANONICAL_STEP_KEYS))

    def test_claude_code_steps_carry_the_same_keys_as_the_generic_path(self):
        """The fast path must not be a silent subset of the schema it shares."""
        missing = set(self._generic_step()) - set(self._cc_step())
        self.assertEqual(missing, set())

    def test_claude_code_steps_explicitly_identify_the_main_agent(self):
        step = self._cc_step()
        self.assertIs(step["is_sub_agent"], False)
        self.assertEqual(step["session_id"], "test-session")
        self.assertEqual(step["parent_agent_id"], "")
        self.assertEqual(step["parent_session_id"], "")
        self.assertEqual(step["session_depth"], 0)

    def test_claude_code_normalized_keys_stay_neutral(self):
        """The normalized keys must report "nothing known", not a fabricated value.

        A populated ``_metrics_unavailable_fields`` would change which per-step
        rows render as "Metrics unavailable"; a true
        ``is_compaction_checkpoint`` would invent a compaction event.
        """
        step = self._cc_step()
        self.assertIs(step["is_compaction_checkpoint"], False)
        self.assertIs(step["summary"], False)
        self.assertEqual(step["message_type"], "")
        self.assertEqual(step["_metrics_unavailable_fields"], [])
        self.assertEqual(step["raw_index"], step["index"])


if __name__ == "__main__":
    unittest.main()
