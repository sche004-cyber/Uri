import unittest

from uri_core.core.response_validation import (
    MAX_EXPANSION_RATIO,
    MAX_NON_SUCCESS_NARRATIVE_LENGTH,
    MIN_UNGROUNDED_DRAFT_LENGTH,
    ResponseValidationError,
    validate_drafted_response,
)


def _outcome(status="success", action_id=None, known_gaps=None):
    outcome = {"execution": {"status": status}, "response": {}}
    if action_id:
        outcome["response"]["action_id"] = action_id
    if known_gaps is not None:
        outcome["known_gaps"] = known_gaps
    return outcome


class ResponseValidationTests(unittest.TestCase):

    def test_valid_draft_for_a_successful_outcome_passes(self):
        result = validate_drafted_response(
            "I've drafted the office note for your review.",
            _outcome(status="success"),
        )
        self.assertEqual(
            result, "I've drafted the office note for your review."
        )

    def test_empty_draft_is_rejected(self):
        with self.assertRaises(ResponseValidationError):
            validate_drafted_response("   ", _outcome())

    def test_oversized_draft_is_rejected(self):
        with self.assertRaises(ResponseValidationError):
            validate_drafted_response("x" * 3000, _outcome())

    def test_credential_shaped_draft_is_rejected(self):
        with self.assertRaises(ResponseValidationError):
            validate_drafted_response(
                "sk-obviouslysecretvalue", _outcome()
            )

    def test_success_claim_rejected_when_outcome_is_awaiting_approval(
        self,
    ):
        with self.assertRaises(ResponseValidationError):
            validate_drafted_response(
                "Done! I've completed that for you.",
                _outcome(status="awaiting_approval"),
            )

    def test_success_claim_rejected_when_outcome_is_error(self):
        with self.assertRaises(ResponseValidationError):
            validate_drafted_response(
                "I've sent the email successfully.",
                _outcome(status="error"),
            )

    def test_non_success_language_is_fine_for_awaiting_approval(self):
        result = validate_drafted_response(
            "I've prepared this and it needs your approval before I "
            "can proceed.",
            _outcome(status="awaiting_approval"),
        )
        self.assertIn("approval", result)

    def test_success_claim_allowed_when_outcome_is_actually_success(
        self,
    ):
        result = validate_drafted_response(
            "Done - I've completed the note for you.",
            _outcome(status="success"),
        )
        self.assertIn("Done", result)

    def test_forged_action_id_is_rejected(self):
        with self.assertRaises(ResponseValidationError):
            validate_drafted_response(
                "Your action 11111111-1111-1111-1111-111111111111 "
                "has been approved.",
                _outcome(
                    status="awaiting_approval",
                    action_id="22222222-2222-2222-2222-222222222222",
                ),
            )

    def test_matching_action_id_is_allowed(self):
        action_id = "22222222-2222-2222-2222-222222222222"
        result = validate_drafted_response(
            f"Reference: {action_id}. Approval needed.",
            _outcome(status="awaiting_approval", action_id=action_id),
        )
        self.assertIn(action_id, result)

    def test_draft_with_no_action_id_mentioned_is_fine(self):
        action_id = "22222222-2222-2222-2222-222222222222"
        result = validate_drafted_response(
            "This needs your approval before I can proceed.",
            _outcome(status="awaiting_approval", action_id=action_id),
        )
        self.assertTrue(result)

    def test_missing_execution_field_is_handled_safely(self):
        # A malformed outcome dict must not crash validation - status
        # is treated as unknown, which is stricter (any success-shaped
        # language gets rejected), not more permissive.
        with self.assertRaises(ResponseValidationError):
            validate_drafted_response("Done!", {"response": {}})

    def test_draft_is_stripped_of_surrounding_whitespace(self):
        result = validate_drafted_response(
            "  Here is your answer.  ", _outcome(status="success")
        )
        self.assertEqual(result, "Here is your answer.")


class GroundingRatioTests(unittest.TestCase):
    """Issue 2: a non-success narrative must remain an explanation of
    the known runtime outcome, not a solution-generation path - the
    draft may only be so much longer than the actual evidence text
    the runtime gave it. Reproduces the exact shape of the live
    scenario that exposed this (a not_implemented capability gap with
    a short error string, and a model producing a multi-paragraph
    invented troubleshooting guide)."""

    def test_short_non_success_explanation_within_floor_is_allowed(self):
        # Almost no evidence text, but the draft stays within
        # MIN_UNGROUNDED_DRAFT_LENGTH - always allowed regardless of
        # the ratio.
        result = validate_drafted_response(
            "I'm not able to do this yet - it isn't something URI "
            "supports right now.",
            _outcome(status="failed"),
        )
        self.assertTrue(result)

    def test_long_invented_advice_for_a_short_evidence_outcome_is_rejected(
        self,
    ):
        outcome = _outcome(
            status="failed",
            known_gaps=[
                {
                    "id": "pc_system_optimization",
                    "status": "not_implemented",
                    "description": "Optimize this device's performance.",
                    "limitations": "No execution adapter exists yet.",
                }
            ],
        )
        # Deliberately much longer than
        # MAX_EXPANSION_RATIO * evidence_length - simulates the live
        # hallucinated multi-section troubleshooting guide.
        invented_advice = (
            "It seems the system encountered an issue. "
            + "Here are some things you can try: " * 20
            + "restart the process, check administrator privileges, "
            "run disk cleanup, defragment your drive, disable "
            "startup programs, and run a virus scan. " * 10
        )

        with self.assertRaises(ResponseValidationError):
            validate_drafted_response(invented_advice, outcome)

    def test_draft_proportional_to_real_evidence_is_allowed(self):
        outcome = _outcome(
            status="failed",
            known_gaps=[
                {
                    "id": "pc_system_optimization",
                    "status": "not_implemented",
                    "description": (
                        "Inspect and optimize this device's "
                        "performance."
                    ),
                    "limitations": (
                        "No execution adapter exists yet; this entry "
                        "exists so URI can explain the gap honestly."
                    ),
                }
            ],
        )
        # Roughly relays the actual evidence, nothing invented -
        # comfortably within the ratio.
        result = validate_drafted_response(
            "I can't optimize your PC yet - that capability doesn't "
            "have an execution adapter built yet, so I can only tell "
            "you it's a known, planned gap rather than actually do "
            "it.",
            outcome,
        )
        self.assertTrue(result)

    def test_success_outcomes_are_exempt_from_the_ratio_check(self):
        # A real, successful tool result can legitimately be long
        # (e.g. summarizing a full drafted document) even with little
        # "evidence" text in message/error - the ratio only applies to
        # non-success outcomes.
        long_success_text = (
            "I've drafted the full office note for your review. " * 10
        )
        result = validate_drafted_response(
            long_success_text, _outcome(status="success")
        )
        self.assertTrue(result)

    def test_ratio_and_floor_constants_are_the_approved_values(self):
        self.assertEqual(MAX_EXPANSION_RATIO, 3.0)
        self.assertEqual(MIN_UNGROUNDED_DRAFT_LENGTH, 300)

    def test_evidence_from_response_message_and_error_both_count(self):
        outcome = {
            "execution": {"status": "failed"},
            "response": {
                "message": "x" * 30,
                "error": "y" * 30,
            },
        }
        # allowed = min(400, max(300, 60 * 3)) = 300 (floor dominates)
        within_budget = "z" * 250
        with_too_much = "z" * 350

        self.assertTrue(
            validate_drafted_response(within_budget, outcome)
        )
        with self.assertRaises(ResponseValidationError):
            validate_drafted_response(with_too_much, outcome)

    def test_allowed_length_scales_with_evidence_between_floor_and_cap(
        self,
    ):
        outcome = {
            "execution": {"status": "failed"},
            "response": {
                "message": "x" * 60,
                "error": "y" * 60,
            },
        }
        # allowed = min(400, max(300, 120 * 3)) = 360
        within_budget = "z" * 350
        with_too_much = "z" * 370

        self.assertTrue(
            validate_drafted_response(within_budget, outcome)
        )
        with self.assertRaises(ResponseValidationError):
            validate_drafted_response(with_too_much, outcome)

    def test_absolute_cap_holds_even_with_abundant_evidence_text(self):
        # Reproduces the live finding: one well-documented registry
        # capability's own limitations text was long enough that
        # MAX_EXPANSION_RATIO alone still permitted a multi-section
        # invented troubleshooting guide (~1200 chars) through. The
        # absolute cap must reject any non-success draft beyond it
        # regardless of how much evidence text exists.
        outcome = _outcome(
            status="failed",
            known_gaps=[
                {
                    "id": "pc_system_optimization",
                    "status": "not_implemented",
                    "description": "d" * 200,
                    "limitations": "l" * 200,
                }
            ],
        )
        # evidence_length here is 400+ chars, so ratio*evidence is
        # well over 1000 - only the absolute cap can catch this.
        within_cap = "z" * (MAX_NON_SUCCESS_NARRATIVE_LENGTH - 10)
        over_cap = "z" * (MAX_NON_SUCCESS_NARRATIVE_LENGTH + 50)

        self.assertTrue(validate_drafted_response(within_cap, outcome))
        with self.assertRaises(ResponseValidationError):
            validate_drafted_response(over_cap, outcome)


class NotImplementedActionabilityTests(unittest.TestCase):
    """Milestone 8A correction: a not_implemented gap (no execution
    adapter exists at all) must never be explained with language
    implying that more detail, clarification, or authorization would
    make it executable - that was false, and slipped past the length/
    ratio checks alone (live-observed: a short, evidence-proportional
    draft still ended with "this will help in tailoring the
    optimization steps"). unavailable_runtime is the opposite case -
    an adapter exists, so the same phrasing there is honest."""

    def _not_implemented_outcome(self, reason="not_implemented"):
        return _outcome(
            status="failed",
            known_gaps=[
                {
                    "id": "pc_system_optimization",
                    "status": "not_implemented",
                    "reason": reason,
                    "description": "Optimize this device's performance.",
                    "limitations": "No execution adapter exists yet.",
                }
            ],
        )

    def test_live_observed_phrasing_is_rejected(self):
        draft = (
            "It seems there was an issue with the workflow to optimize "
            "your PC. The system was unable to proceed because it "
            "couldn't find any drafted output to review. To move "
            "forward, I recommend providing more details about your "
            "PC's specifications and any specific performance issues "
            "you're experiencing. This will help in tailoring the "
            "optimization steps to your needs."
        )

        with self.assertRaises(ResponseValidationError):
            validate_drafted_response(
                draft, self._not_implemented_outcome()
            )

    def test_tailor_language_alone_is_rejected(self):
        draft = (
            "URI can't optimize your PC yet. Share more about your "
            "setup and I can look at tailoring the steps."
        )

        with self.assertRaises(ResponseValidationError):
            validate_drafted_response(
                draft, self._not_implemented_outcome()
            )

    def test_once_you_authorize_language_is_rejected(self):
        draft = (
            "I can't optimize your PC right now. Once you authorize "
            "this, I can proceed."
        )

        with self.assertRaises(ResponseValidationError):
            validate_drafted_response(
                draft, self._not_implemented_outcome()
            )

    def test_honest_explanation_with_no_implied_actionability_is_allowed(
        self,
    ):
        draft = (
            "I can't optimize your PC yet - that's a capability URI "
            "knows about but doesn't have an execution adapter for "
            "yet, so I can't act on it."
        )

        result = validate_drafted_response(
            draft, self._not_implemented_outcome()
        )
        self.assertTrue(result)

    def test_same_phrasing_is_allowed_for_an_unavailable_runtime_gap(
        self,
    ):
        # A real adapter exists here - a missing credential genuinely
        # would unblock it, so this phrasing is honest, not implied.
        draft = (
            "I can't read that spreadsheet right now - it needs "
            "Google Drive credentials configured. Once you provide "
            "those, I can try again."
        )

        result = validate_drafted_response(
            draft, self._not_implemented_outcome(reason="unavailable_runtime")
        )
        self.assertTrue(result)

    def test_missing_reason_field_falls_back_to_status_for_backward_compat(
        self,
    ):
        # Older/test payloads built before the "reason" field existed
        # (or a caller that only sets status) must still be protected,
        # not silently exempted.
        outcome = _outcome(
            status="failed",
            known_gaps=[
                {
                    "id": "pc_system_optimization",
                    "status": "not_implemented",
                    "description": "Optimize this device's performance.",
                    "limitations": "No execution adapter exists yet.",
                }
            ],
        )
        draft = (
            "I can't do this yet. To move forward, please share more "
            "details - this will help."
        )

        with self.assertRaises(ResponseValidationError):
            validate_drafted_response(draft, outcome)


class ToolResultOwnStatusOverridesDispatchStatusTests(unittest.TestCase):
    """Live testing found a real gap: a tool can be successfully
    DISPATCHED (execution.status = "success") while its own result
    reports the actual task was not accomplished (its own "status" is
    something other than "success", e.g. "unavailable"). Before this
    fix, every honesty check below was gated on execution.status alone
    and never fired for this shape, letting an unrelated "please
    clarify" or an implausible success claim pass validation
    unchecked. Deliberately generic throughout - no capability/domain
    name appears in the fix or these tests."""

    def _incomplete_outcome(self, **response_extra):
        return {
            "execution": {"status": "success", "tool": "some_capability"},
            "response": {
                "status": "unavailable",
                "message": "Could not find the requested record.",
                "error": "Records path not found: some/configured/path",
                **response_extra,
            },
        }

    def test_success_claim_is_rejected_despite_successful_dispatch(self):
        with self.assertRaises(ResponseValidationError):
            validate_drafted_response(
                "Done! I've completed that for you.",
                self._incomplete_outcome(),
            )

    def test_honest_relay_of_the_tools_own_message_is_allowed(self):
        result = validate_drafted_response(
            "I couldn't find that record - the records path isn't "
            "configured on this system.",
            self._incomplete_outcome(),
        )
        self.assertTrue(result)

    def test_length_is_bounded_relative_to_the_tools_own_evidence(self):
        outcome = self._incomplete_outcome(
            message="x" * 30, error="y" * 30
        )
        # allowed = min(400, max(300, 60 * 3)) = 300 (floor dominates)
        within_budget = "z" * 250
        with_too_much = "z" * 350

        self.assertTrue(validate_drafted_response(within_budget, outcome))
        with self.assertRaises(ResponseValidationError):
            validate_drafted_response(with_too_much, outcome)

    def test_a_real_success_status_inside_response_is_unaffected(self):
        # The tool's own status IS "success" here - this must behave
        # exactly like the pre-existing plain-success path.
        outcome = {
            "execution": {"status": "success"},
            "response": {"status": "success", "message": "done"},
        }
        result = validate_drafted_response(
            "Done - I've completed the note for you.", outcome
        )
        self.assertIn("Done", result)

    def test_response_with_no_status_field_is_unaffected(self):
        # Most existing tools/tests never set a nested "status" at all
        # - absence must never be treated as evidence of a problem.
        outcome = {
            "execution": {"status": "success"},
            "response": {"message": "note_sheet contents here"},
        }
        result = validate_drafted_response(
            "Done - here is the note.", outcome
        )
        self.assertIn("Done", result)

    def test_non_dict_response_is_unaffected(self):
        outcome = {
            "execution": {"status": "success"},
            "response": "a plain string response",
        }
        result = validate_drafted_response("Done.", outcome)
        self.assertEqual(result, "Done.")


    # Desktop recovery 2026-10-01: conversational turns (nothing
    # dispatched) are not held to the capability-gap expansion cap.
    _GREETING = (
        "I am URI, your administrative assistant. I help you draft notes "
        "and orders, recall information from memory, convert documents "
        "and manage Gmail. I can also plan workflows for tasks that need "
        "several steps. If you have a specific request, tell me and I "
        "will check which of my available capabilities can help you with "
        "it right now, and tell you plainly when something is not "
        "available yet rather than pretending otherwise."
    )

    def _conversation_outcome(self, **execution_extra):
        execution = {"status": "not_applicable", "capability": None}
        execution.update(execution_extra)
        return {
            "execution": execution,
            "response": {"message": "General inquiry, no tool applies."},
            "known_gaps": None,
        }

    def test_long_conversational_reply_is_accepted(self):
        self.assertGreater(len(self._GREETING), MAX_NON_SUCCESS_NARRATIVE_LENGTH)
        result = validate_drafted_response(
            self._GREETING, self._conversation_outcome()
        )
        self.assertEqual(result, self._GREETING)

    def test_conversational_reply_still_rejects_success_claims(self):
        with self.assertRaises(ResponseValidationError):
            validate_drafted_response(
                "Done! I've sent the email for you.",
                self._conversation_outcome(),
            )

    def test_conversational_reply_still_rejects_oversized_draft(self):
        with self.assertRaises(ResponseValidationError):
            validate_drafted_response(
                "x " * 1500, self._conversation_outcome()
            )

    def test_not_applicable_with_capability_keeps_expansion_cap(self):
        with self.assertRaises(ResponseValidationError):
            validate_drafted_response(
                self._GREETING,
                self._conversation_outcome(capability="draft_note"),
            )

    def test_not_applicable_with_tool_or_branches_keeps_expansion_cap(self):
        for extra in ({"tool": "gmail"}, {"branch_results": [{"x": 1}]}):
            with self.assertRaises(ResponseValidationError):
                validate_drafted_response(
                    self._GREETING, self._conversation_outcome(**extra)
                )

    def test_not_applicable_with_known_gaps_keeps_expansion_cap(self):
        outcome = self._conversation_outcome()
        outcome["known_gaps"] = [{"reason": "unavailable_runtime"}]
        with self.assertRaises(ResponseValidationError):
            validate_drafted_response(self._GREETING, outcome)

    def test_not_applicable_with_tool_status_keeps_expansion_cap(self):
        outcome = self._conversation_outcome()
        outcome["response"]["status"] = "not_found"
        with self.assertRaises(ResponseValidationError):
            validate_drafted_response(self._GREETING, outcome)


if __name__ == "__main__":
    unittest.main()
