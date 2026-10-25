"""Unit test for the Phase 15.6.1 narrate-detection guard.

The guard suppresses the narrate-without-tool_use detection when
the model has just completed a successful tool call and is writing
a wrap-up summary. The wrap-up text naturally mentions specific
identifiers (filenames, sizes, memory IDs) that _CLAIM_RE is
designed to catch on a real hallucination.

Before Phase 15.6.1: every wrap-up text iter tripped the regex and
got a false-positive nudge. 5 false positives on a 20-iter turn
(2026-10-18 evie turn 181).

After Phase 15.6.1: narrate-detection only fires when the model
hasn't done any successful tool work in this turn yet.

The distinguishing signal: emission_iters has any record with
non-empty `tool_results`. If yes, the model is in post-tool
wrap-up mode; the prose is reporting the result, not hallucinating.
"""
import re
import sys
import unittest
from pathlib import Path
from unittest.mock import MagicMock

# Make the app package importable
sys.path.insert(0, str(Path(__file__).resolve().parent.parent))


# Replicate the post-Patch narrate-detection branch from AgentLoop.
# The function returns (narrates: bool, should_nudge: bool) — narrates
# is the regex match, should_nudge is narrates AND not in wrap-up mode.
def _check_narrate(text, emission_iters):
    """Inline of the narrate-detection branch logic after the
    Phase 15.6.1 fix. Returns (narrates, should_nudge)."""
    import re
    # Same regexes as loop.py. We use the same source from the
    # file at test time (parse it out) so the test stays in sync
    # with the actual implementation.
    narrate_re = re.compile(
        # Simpler version for the test: the original _NARRATE_RE
        # has the full set of tool-call syntax patterns, but for
        # the wrap-up guard test we just need ONE pattern that
        # matches a "narrate" call. The actual production
        # implementation lives in loop.py.
        r"\b(memory_recall|memory_recent|memory_write|"
        r"memory_update|memory_pin|memory_unpin|"
        r"sql_query|exec_bash)\s*\("
        r"|\b(?:id|memory_id|chunk_id)\s*=\s*\d{2,}",
        re.IGNORECASE,
    )
    # Re-define _CLAIM_RE here to match the patch. If the actual
    # implementation in loop.py diverges, this test still validates
    # the suppression logic — the false-positive vs true-positive
    # decision is independent of the specific _CLAIM_RE shape.
    # The PRODUCTION pattern, imported -- not a copy. A copy could drift
    # from the code it claims to test (it did: it still listed a name the
    # production pattern no longer had).
    from app.agent.loop import _CLAIM_RE as claim_re
    prev_successful_tool = any(
        it.get("tool_results")
        for it in emission_iters
    )
    narrates = (
        not prev_successful_tool
        and bool(
            narrate_re.search(text) or claim_re.search(text)
        )
    )
    return (narrates or claim_re.search(text), narrates)


class TestNarrateGuard(unittest.TestCase):
    """Tests for the wrap-up-vs-hallucination guard."""

    def test_pre_tool_first_iter_claim_still_triggers(self):
        """If the model emits a side-effect claim on its FIRST iter
        (no tools have run yet), the regex should still fire. This
        is the genuine hallucination pattern."""
        text = "Email id 6808 sent. Check Gmail."
        emission_iters = []  # no prior iters with tool results
        # The raw regex check
        narrates, should_nudge = _check_narrate(text, emission_iters)
        # Note: narrates includes the raw match; should_nudge respects the guard.
        # Both should be true here (pre-tool, matches regex).
        self.assertTrue(should_nudge, "pre-tool claim should still trigger narrate")

    def test_post_tool_wrap_up_does_not_trigger(self):
        """If the model just ran a tool and writes a wrap-up that
        mentions the tool's identifier, the guard should suppress."""
        text = (
            "PDF rendered (3,988 bytes) attached — paperclip on this message."
        )
        emission_iters = [
            {
                "iteration": 11,
                "tool_results": [
                    {"name": "attach_file", "result": {"ok": True}},
                ],
            },
        ]
        _narrates, should_nudge = _check_narrate(text, emission_iters)
        # should_nudge should be FALSE because a tool ran in a prior iter
        self.assertFalse(
            should_nudge,
            "post-tool wrap-up prose should NOT trigger narrate-nudge"
        )

    def test_post_tool_memory_id_wrap_up_does_not_trigger(self):
        """Real turn 181 iter-16 pattern: model wrote memory, then
        in wrap-up says 'same id 1028, the content is updated'."""
        text = "OK — same id 1028, the content is updated. Good."
        emission_iters = [
            {
                "iteration": 14,
                "tool_results": [
                    {"name": "memory_write", "result": {"ok": True, "id": 1028}},
                ],
            },
        ]
        _narrates, should_nudge = _check_narrate(text, emission_iters)
        self.assertFalse(
            should_nudge,
            "post-memory_write wrap-up should NOT trigger narrate-nudge"
        )

    def test_post_tool_done_summary_does_not_trigger(self):
        """Real turn 181 iter-18 pattern: model says 'Done. Memory
        1028 is the canonical one, no duplicate.'"""
        text = "Done. Memory 1028 is the canonical one, no duplicate."
        emission_iters = [
            {
                "iteration": 14,
                "tool_results": [
                    {"name": "memory_write", "result": {"ok": True, "id": 1028}},
                ],
            },
            {
                "iteration": 15,
                "tool_results": [
                    {"name": "memory_recall", "result": {"ok": True}},
                ],
            },
        ]
        _narrates, should_nudge = _check_narrate(text, emission_iters)
        self.assertFalse(
            should_nudge,
            "post-tool 'Done' summary should NOT trigger narrate-nudge"
        )

    def test_failed_tool_still_triggers_narrate(self):
        """If a tool RAN but FAILED, the model might be narrating
        a retry. The guard should still fire because the model
        hasn't successfully completed work."""
        # We treat any tool_results as "successful" in this version
        # (we don't track exit_code in tool_results). This is a
        # known false negative — a tool that errored should
        # arguably re-enable narrate-detection, but the cost of
        # suppressing it is small (the model just doesn't get
        # a nudge on a false narration of a retry). Documenting
        # this as a known limitation.
        text = "Email id 6808 sent. Check Gmail."
        emission_iters = [
            {
                "iteration": 0,
                "tool_results": [
                    {"name": "exec_bash", "result": {"ok": False, "exit_code": 1}},
                ],
            },
        ]
        _narrates, should_nudge = _check_narrate(text, emission_iters)
        # Per current implementation: this is FALSE (guard suppresses
        # because tool_results is non-empty). Documented limitation.
        self.assertFalse(
            should_nudge,
            "guard treats any tool_results as wrap-up-mode; "
            "errored tool would be a known false negative"
        )


# Phase 15.6.2: URL pattern test cases.
_URL_PATTERN = re.compile(r"/api/v1/uploads/[0-9a-f]{8,}\.\w+")


def _check_narrate_v2(text, emission_iters):
    """Inline of the Phase 15.6.2 narrate-detection branch. The
    v2 logic is context-aware: if the URL pattern matches, use
    the specific attach_file guard; otherwise use the broad guard."""
    # Reuse the v1 regex detection for non-URL patterns.
    _narrates, should_nudge_v1 = _check_narrate(text, emission_iters)
    # Also check the URL pattern.
    url_pattern = _URL_PATTERN.search(text)
    if url_pattern:
        prev_attach_file = any(
            any(
                r.get("name") == "attach_file"
                for r in it.get("tool_results", [])
            )
            for it in emission_iters
        )
        return (True, not prev_attach_file)
    return (False, should_nudge_v1)


class TestUrlPatternNarrateGuard(unittest.TestCase):
    """Phase 15.6.2: the '[attached N file(s): URL]' hallucination
    template. The model writes a /api/v1/uploads/ URL in prose
    without actually calling attach_file. Triggered in evie turns
    183 and 185 (2026-10-18)."""

    def test_url_in_text_no_prior_attach_file_fires(self):
        """The actual hallucination from evie turn 185: model wrote
        a fabricated URL with no prior attach_file call. The new
        URL-pattern guard should fire."""
        text = (
            "Try 3.\n\n"
            "[attached 1 file: /api/v1/uploads/"
            "29ce8a26e58b408b95bca48ee75be2d2.pdf]"
        )
        emission_iters = []  # no prior iters at all
        _narrates, should_nudge = _check_narrate_v2(text, emission_iters)
        self.assertTrue(
            should_nudge,
            "fabricated URL with no prior attach_file should trigger narrate"
        )

    def test_url_after_attach_file_does_not_fire(self):
        """Legitimate wrap-up: model called attach_file in a prior
        iter, now reports the URL in the wrap-up prose. Should NOT
        trigger narrate."""
        text = (
            "PDF attached.\n\n"
            "[attached 1 file: /api/v1/uploads/"
            "c6ca20fc2e65460795961df8f608968f.pdf]"
        )
        emission_iters = [
            {
                "iteration": 11,
                "tool_results": [
                    {"name": "attach_file",
                     "result": {"ok": True,
                                "attachment": {
                                    "url": "/api/v1/uploads/"
                                    "c6ca20fc2e65460795961df8f608968f.pdf"
                                }}},
                ],
            },
        ]
        _narrates, should_nudge = _check_narrate_v2(text, emission_iters)
        self.assertFalse(
            should_nudge,
            "post-attach_file URL wrap-up should NOT trigger narrate"
        )

    def test_url_after_other_tool_still_fires(self):
        """The Phase 15.6.1 broad guard was wrong for URL patterns:
        it would suppress the narrate if any prior tool (not just
        attach_file) ran. Phase 15.6.2 fixes this — the URL pattern
        only checks for prior attach_file, not any tool."""
        text = (
            "Updated pay summary attached above.\n\n"
            "[attached 1 file: /api/v1/uploads/"
            "29ce8a26e58b408b95bca48ee75be2d2.pdf]"
        )
        # exec_bash ran, but no attach_file
        emission_iters = [
            {
                "iteration": 5,
                "tool_results": [
                    {"name": "exec_bash", "result": {"ok": True}},
                ],
            },
        ]
        _narrates, should_nudge = _check_narrate_v2(text, emission_iters)
        self.assertTrue(
            should_nudge,
            "URL pattern with prior exec_bash (NOT attach_file) "
            "should still trigger narrate"
        )

    def test_url_with_no_text_around_it(self):
        """Just the URL, no narrative context. Still fires."""
        text = "/api/v1/uploads/29ce8a26e58b408b95bca48ee75be2d2.pdf"
        emission_iters = []
        _narrates, should_nudge = _check_narrate_v2(text, emission_iters)
        self.assertTrue(
            should_nudge,
            "bare URL with no context should trigger narrate"
        )

    def test_user_upload_reference_does_not_fire(self):
        """User uploads appear in the user message as structured
        attachments (NOT in prose with the bracket template). If
        the model echoes a URL in prose that came from a user
        upload, the broad guard is OK to suppress (we trust that
        the user actually uploaded something). For the new URL
        pattern, we also need to handle this case — but the
        current check doesn't know about user uploads. For now,
        we document the limitation: a user-uploaded file URL
        echoed in the model's first response WOULD trigger the
        narrate-detection. This is rare in practice because
        user-uploaded files are usually images, and the model
        doesn't typically write their URLs in prose.
        """
        text = (
            "Here's the image you uploaded: "
            "/api/v1/uploads/6eacf17443604a5bb6aa3eb14f2d47a7.png"
        )
        emission_iters = []
        _narrates, should_nudge = _check_narrate_v2(text, emission_iters)
        # Known limitation: this would fire even though the URL
        # is from a legitimate user upload. Documented as a
        # known false positive.
        self.assertTrue(
            should_nudge,
            "documented limitation: user-upload URLs in response "
            "are caught (false positive, but rare in practice)"
        )


class TestMarkdownEmailIdEvasion(unittest.TestCase):
    """Phase 15.6.3: the model learned to evade _CLAIM_RE by using
    markdown formatting between 'id' and the digit (e.g. **6810**,
    `6810`, *6810*). Triggered in evie turns 197 and 199
    (2026-10-18 16:01 and 16:04 PM)."""

    def test_bold_markdown_email_id(self):
        """Real turn 197 text: 'Email id **6810** sent to an employee'"""
        text = (
            "Done. Email id **6810** sent to `employee@example.com` "
            "with the 3,758-byte PDF attached."
        )
        emission_iters = []  # no prior iters
        _narrates, should_nudge = _check_narrate(text, emission_iters)
        self.assertTrue(
            should_nudge,
            "Email id **N** (bold markdown) should trigger narrate"
        )

    def test_bold_markdown_email_id_turn_199(self):
        """Real turn 199 text: 'Resent. Email id **6811**'"""
        text = (
            "Resent. Email id **6811** to Sample Employee, cc'd "
            "`person.one@example.com` and `person.two@example.com`."
        )
        emission_iters = []
        _narrates, should_nudge = _check_narrate(text, emission_iters)
        self.assertTrue(
            should_nudge,
            "Resent. Email id **N** should trigger narrate"
        )

    def test_italic_markdown_email_id(self):
        """Italic markdown: 'Email id *6810*'"""
        text = "Email id *6810* sent to an employee"
        emission_iters = []
        _narrates, should_nudge = _check_narrate(text, emission_iters)
        self.assertTrue(
            should_nudge,
            "Email id *N* (italic markdown) should trigger narrate"
        )

    def test_code_markdown_email_id(self):
        """Code markdown: 'Email id `6810`'"""
        text = "Email id `6810` sent to sample employee"
        emission_iters = []
        _narrates, should_nudge = _check_narrate(text, emission_iters)
        self.assertTrue(
            should_nudge,
            "Email id `N` (code markdown) should trigger narrate"
        )

    def test_colon_email_id(self):
        """Colon: 'Email id: 6810'"""
        text = "Email id: 6810 sent to sample employee"
        emission_iters = []
        _narrates, should_nudge = _check_narrate(text, emission_iters)
        self.assertTrue(
            should_nudge,
            "Email id: N should trigger narrate"
        )

    def test_equals_email_id(self):
        """Equals: 'Email id=6810'"""
        text = "Email id=6810"
        emission_iters = []
        _narrates, should_nudge = _check_narrate(text, emission_iters)
        self.assertTrue(
            should_nudge,
            "Email id=N should trigger narrate"
        )

    def test_plain_email_id_still_works(self):
        """Regression: the original 'Email id 6810' (no formatting)
        should still match."""
        text = "Email id 6810 sent to sample employee"
        emission_iters = []
        _narrates, should_nudge = _check_narrate(text, emission_iters)
        self.assertTrue(
            should_nudge,
            "Plain 'Email id N' should still trigger narrate (regression)"
        )

    def test_url_pattern_still_works_with_email_id(self):
        """The URL pattern (Phase 15.6.2) should still be the
        primary detection for the [attached N file(s): URL] pattern.
        This test confirms the two patterns coexist."""
        text = (
            "Done. Email id **6810** sent.\n\n"
            "[attached 1 file: /api/v1/uploads/29ce8a26...pdf]"
        )
        emission_iters = []
        # The email id alone should trigger the broad-guard narrate
        # (no prior tool = not in wrap-up mode).
        _narrates, should_nudge = _check_narrate(text, emission_iters)
        self.assertTrue(
            should_nudge,
            "Email id **N** should still trigger broad-guard narrate"
        )


class TestMaxNudgesEnforcement(unittest.TestCase):
    """Phase 15.8: ensure _MAX_NUDGES is actually enforced
    (regardless of the cap value).

    The bug: when the narrate-detection fired, iter_record was
    NEVER appended to emission_iters (the `continue` skipped
    the append). So the next iter's `nudges_so_far` calculation
    only saw the wrap-up iters (not the narrate iters), and
    the _MAX_NUDGES cap never kicked in.

    Repro from evie turn 201 (4:42 PM, 2026-10-18): the model
    saw 3 narrate warnings when the cap was supposed to be 2.
    The model kept apologizing each time and never got a
    chance to actually issue a tool_use block — it just gave
    up with "Checking for the prior turn's send."

    Phase 15.10 (2026-10-18): bumped cap from 2 to 4 so the
    model has more chances to break out of a self-critique
    loop. The mechanism test below still validates that the
    cap is enforced (with the 2-nudge cap from Phase 15.8);
    the new 4-nudge cap is validated in TestMaxNudgesFourEnforcement.

    This test simulates the in-memory _check_narrate with
    cumulative state to verify the cap fires correctly."""

    def test_cumulative_nudges_actually_increment(self):
        """Simulate 3 consecutive iters all triggering narrate.
        With the fix, the 3rd iter should NOT fire (cap = 2).
        Without the fix, all 3 would fire (cap never enforced)."""
        # Simulate the in-loop logic
        # Phase 15.8 logic: emission_iters accumulates.
        # Without the fix, narrate iters were never added,
        # so emission_iters stays empty.
        emission_iters = []
        fires = []
        text = "Email id 6810 sent to sample employee"

        # iter 0
        nudges_so_far = sum(1 for it in emission_iters if it.get("_nudged"))
        fires.append(0 < 2 and bool(True))  # match the regex
        emission_iters.append({"_nudged": True, "tool_results": []})

        # iter 1
        nudges_so_far = sum(1 for it in emission_iters if it.get("_nudged"))
        fires.append(nudges_so_far < 2 and bool(True))
        emission_iters.append({"_nudged": True, "tool_results": []})

        # iter 2
        nudges_so_far = sum(1 for it in emission_iters if it.get("_nudged"))
        fires.append(nudges_so_far < 2 and bool(True))

        # With the fix: fires should be [True, True, False]
        # (cap = 2; the 3rd narrate is suppressed)
        self.assertEqual(fires, [True, True, False],
                         f"Expected [True, True, False] but got {fires}; "
                         "_MAX_NUDGES=2 cap should suppress the 3rd narrate")

    def test_old_buggy_logic_fires_incorrectly(self):
        """Document what the bug looked like: if iter_record is
        never appended to emission_iters, nudges_so_far stays
        at 0 forever, and the cap never fires."""
        emission_iters = []  # never gets updated
        fires = []

        for i in range(3):
            nudges_so_far = 0  # always 0 (bug!)
            fires.append(nudges_so_far < 2 and bool(True))

        # Buggy behavior: all 3 iters fire narrate
        self.assertEqual(fires, [True, True, True])
        # This is what was happening before the Phase 15.8 fix.


class TestMaxNudgesFourEnforcement(unittest.TestCase):
    """Phase 15.10: _MAX_NUDGES = 4. The cap should be enforced
    correctly (Phase 15.8 fix), giving the model 4 chances to
    break out of a self-critique loop before the turn ends."""

    def test_cumulative_nudges_capped_at_four(self):
        """Simulate 5 consecutive iters all triggering narrate.
        With _MAX_NUDGES=4, only the first 4 should fire. The
        5th should be suppressed."""
        emission_iters = []
        fires = []

        for i in range(5):
            nudges_so_far = sum(1 for it in emission_iters if it.get("_nudged"))
            fires.append(nudges_so_far < 4 and bool(True))  # narrate fires
            emission_iters.append({"_nudged": True, "tool_results": []})

        # First 4 fire, 5th is suppressed
        self.assertEqual(fires, [True, True, True, True, False],
                         f"Expected [True, True, True, True, False] but got {fires}; "
                         "_MAX_NUDGES=4 should fire on first 4 narrates")

    def test_nudge_messages_escalate_through_four(self):
        """Verify the _NUDGE_MESSAGES dict has all 4 entries
        with escalating directness."""
        # Import the actual constants from the loop module
        # We can't import the full module (heavy deps) so we
        # inline-check by reading the file source.
        loop_src = open(str(Path(__file__).resolve().parent.parent / "app/agent/loop.py")).read()
        # Check the file has all 4 nudge messages
        self.assertIn("1: _NUDGE_MESSAGE,", loop_src)
        self.assertIn("2: _NUDGE_MESSAGE_2,", loop_src)
        self.assertIn("3: (", loop_src)
        self.assertIn("4: (", loop_src)
        # Check 3rd and 4th are about taking action
        self.assertIn("one more chance", loop_src.lower())
        self.assertIn("LAST chance", loop_src)


if __name__ == "__main__":
    unittest.main()
