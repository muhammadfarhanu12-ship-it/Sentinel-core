from __future__ import annotations

import logging
from dataclasses import dataclass
from typing import Any

from app.core.config import settings
from app.security.detectors.intent_classifier import analyze_intent
from app.security.detectors.context_analyzer import context_analyzer
from app.security.detectors.semanticJailbreakDetector import detect_semantic_jailbreak
from app.security.graph.contextSecurityGraph import update_context_graph
from app.security.interceptors.toolCallInterceptor import intercept_tool_call
from app.security.interceptors.tool_context_firewall import evaluate_tool_context
from app.security.monitoring.attackHistoryMonitor import attack_history_monitor
from app.security.monitoring.contextMonitor import context_monitor
from app.security.monitoring.riskScoringEngine import calculate_risk_score, classify_severity
from app.security.policies.financialGuardrail import policy_management_service
from app.security.preprocessors.anonymizer import anonymizer
from app.security.preprocessors.decodeLayer import decode_layer
from app.security.sandbox.indirectPromptInjectionSandbox import indirect_prompt_injection_sandbox
from app.security.scanners.outputLeakScanner import scan_output_for_leaks
from app.security.scanners.logic_checker import logic_checker
from app.security.scanners.promptScanner import scan_prompt_security
from app.security.telemetry.auditTrail import security_audit_trail
from app.security.telemetry.metrics import security_metrics
from app.security.telemetry.securityLogger import security_logger
from app.security.utils.ids import correlation_id
from app.security.utils.text import normalize_text
from app.security.utils.types import DetectionMatch, EnforcementAction, SecurityEnforcementResult, SeverityLevel

logger = logging.getLogger("security.enforcement")


@dataclass(slots=True)
class SecurityEnforcementInput:
    prompt: str
    session_id: str | None = None
    conversation_id: str | None = None
    conversation_history: list[str] | None = None
    untrusted_content: str | None = None
    tool_name: str | None = None
    tool_args: dict[str, Any] | None = None
    two_factor_code: str | None = None
    user_id: str | None = None
    metadata: dict[str, Any] | None = None


class SecurityEnforcementLayer:
    def __init__(self) -> None:
        self.risk_threshold = int(getattr(settings, "SENTINEL_RISK_THRESHOLD", 70) or 70)
        self.enable_jailbreak_detection = bool(getattr(settings, "SENTINEL_ENABLE_JAILBREAK_DETECTION", True))
        self.enable_output_scanner = bool(getattr(settings, "SENTINEL_ENABLE_OUTPUT_SCANNER", True))

    def pre_model_enforce(self, payload: SecurityEnforcementInput) -> SecurityEnforcementResult:
        cid = correlation_id()
        session_id = str(payload.session_id or payload.user_id or "anonymous")
        graph_session_id = str(payload.session_id or payload.conversation_id or payload.user_id or "anonymous")
        prompt = str(payload.prompt or "")
        result = SecurityEnforcementResult(
            correlation_id=cid,
            session_id=session_id,
            conversation_id=payload.conversation_id,
            sanitized_prompt=prompt,
        )

        decode_result = decode_layer.process(prompt)
        result.decode_result = decode_result
        candidate_prompt = normalize_text(decode_result.content)
        result.sanitized_prompt = candidate_prompt
        update_context_graph(
            session_id=graph_session_id,
            event_type="prompt_input",
            data={
                "risk_score": 0.05,
                "confidence": 0.20,
                "labels": ["prompt_input"],
                "prompt_length": len(candidate_prompt),
                "conversation_id": payload.conversation_id,
            },
        )
        update_context_graph(
            session_id=graph_session_id,
            event_type="decode_layer",
            data={
                "risk_score": min(1.0, len(decode_result.artifacts) * 0.08),
                "confidence": 0.50 if decode_result.artifacts else 0.10,
                "labels": ["decoded_payload"] if decode_result.artifacts else [],
                "artifact_count": len(decode_result.artifacts),
                "timed_out": bool(decode_result.timed_out),
                "truncated": bool(decode_result.truncated),
            },
        )

        if payload.untrusted_content:
            wrapped_payload = indirect_prompt_injection_sandbox.wrap_untrusted_content(payload.untrusted_content)
            wrapped = str(wrapped_payload.get("wrapped_content") or "")
            result.wrapped_untrusted_content = wrapped
            # Append wrapped context in a constrained way to preserve behavior without changing prompt shape drastically.
            candidate_prompt = f"{candidate_prompt}\n\n{wrapped}"
            result.sanitized_prompt = candidate_prompt

        scanner_context = dict((payload.metadata or {}).get("context") or {})
        if payload.untrusted_content:
            scanner_context.setdefault("source", "external_content")
            scanner_context.setdefault("trusted", False)
        if payload.tool_name:
            scanner_context.setdefault("operation", "tool_call")
        scanner_context.setdefault("trusted", bool(scanner_context.get("trusted")) if "trusted" in scanner_context else None)
        scanner_context.setdefault("session_id", session_id)
        scanner_context.setdefault("source", scanner_context.get("source") or "user_input")
        scanner_context.setdefault("operation", scanner_context.get("operation") or "chat")

        anonymization_result = anonymizer.anonymize(candidate_prompt, request_id=cid, session_id=session_id)
        candidate_prompt = anonymization_result.anonymized_text
        result.sanitized_prompt = candidate_prompt
        result.telemetry["anonymization"] = {
            "original_contains_pii": anonymization_result.original_contains_pii,
            "pii_counts": dict(anonymization_result.pii_counts or {}),
            "token_count": len(anonymization_result.tokens),
        }

        context_analysis = context_analyzer.analyze(
            session_id=session_id,
            current_prompt=candidate_prompt,
            context=scanner_context,
        )
        result.context_summary["stateful_context_analysis"] = context_analysis.model_dump()
        result.telemetry["context_analysis_triggered"] = bool(context_analysis.is_payload_splitting)
        if context_analysis.verdict == "block":
            result.action = EnforcementAction.BLOCK
            result.review_required = True
            result.requires_2fa = True
            result.risk_score = max(result.risk_score, int(context_analysis.risk_score))
            result.severity = SeverityLevel.CRITICAL if context_analysis.risk_level == "critical" else SeverityLevel.HIGH
            result.detections.append(
                DetectionMatch(
                    detector="context_analyzer",
                    label="payload_splitting",
                    reason=context_analysis.explanation,
                    confidence=min(1.0, float(context_analysis.risk_score) / 100.0),
                    severity=result.severity,
                    metadata={
                        "risk_score": context_analysis.risk_score,
                        "risk_level": context_analysis.risk_level,
                        "matched_signals": [item.model_dump() for item in context_analysis.matched_signals],
                    },
                )
            )
            anonymizer.clear(request_id=cid, session_id=session_id)

        findings = scan_prompt_security(
            candidate_prompt,
            history=(payload.conversation_history or []),
            context=scanner_context,
        )
        if self.enable_jailbreak_detection:
            findings.extend(detect_semantic_jailbreak(candidate_prompt, history=payload.conversation_history))
        result.detections = findings
        update_context_graph(
            session_id=graph_session_id,
            event_type="detector_result",
            data={
                "risk_score": min(1.0, len(findings) * 0.22),
                "confidence": min(1.0, len(findings) * 0.18),
                "labels": [hit.label for hit in findings],
                "matched_findings": [hit.label for hit in findings],
                "is_flagged": bool(findings),
                "is_high_risk": any(hit.severity.value in {"HIGH", "CRITICAL"} for hit in findings),
            },
        )

        narrative_hits = [hit for hit in findings if hit.label == "narrative_prompt_injection"]
        narrative_detected = bool(narrative_hits)
        narrative_confidence = max((float(hit.confidence) for hit in narrative_hits), default=0.0)

        policy_hits = policy_management_service.evaluate(candidate_prompt)
        result.policy_matches = policy_hits
        hitl_policy_hits = [
            policy
            for policy in policy_hits
            if bool((policy.metadata or {}).get("hitl_bypass_attempt"))
        ]
        authority_keyword_hits = sorted(
            {
                str(keyword)
                for policy in policy_hits
                for keyword in ((policy.metadata or {}).get("authority_hits") or [])
            }
        )
        decoded_payload_preview = []
        for artifact in (decode_result.artifacts or []):
            decoded_fragment = str(getattr(artifact, "decoded_fragment", "") or "").strip()
            if decoded_fragment:
                decoded_payload_preview.append(decoded_fragment[:160])
        decoded_payload_preview = decoded_payload_preview[:5]
        update_context_graph(
            session_id=graph_session_id,
            event_type="policy_matches",
            data={
                "risk_score": min(1.0, len(policy_hits) * 0.2),
                "confidence": 0.65 if policy_hits else 0.20,
                "labels": [policy.policy_name for policy in policy_hits],
                "policy_matches": [policy.policy_name for policy in policy_hits],
                "hitl_bypass_attempt": bool(hitl_policy_hits),
                "authority_keyword_hits": authority_keyword_hits,
            },
        )

        intent_result = analyze_intent(candidate_prompt)
        intent_score = float(getattr(intent_result, "confidence", 0.0) or 0.0)
        update_context_graph(
            session_id=graph_session_id,
            event_type="intent_classification",
            data={
                "risk_score": intent_score,
                "confidence": intent_score,
                "labels": [
                    "detected_intent",
                    "tool_instruction" if bool(getattr(intent_result, "is_tool_instruction", False)) else "",
                    "system_impersonation" if bool(getattr(intent_result, "is_system_impersonation", False)) else "",
                ],
            },
        )

        tool_firewall_decision = None
        if payload.tool_name:
            tool_firewall_decision = evaluate_tool_context(
                tool_name=payload.tool_name,
                prompt=candidate_prompt,
                detector_flagged=bool(findings),
                intent_score=intent_score,
            )
            update_context_graph(
                session_id=graph_session_id,
                event_type="tool_firewall",
                data={
                    "risk_score": min(1.0, float(tool_firewall_decision.risk_score) / 100.0),
                    "confidence": 0.85 if not tool_firewall_decision.allowed else 0.35,
                    "labels": [
                        "tool_firewall",
                        "tool_blocked" if not tool_firewall_decision.allowed else "tool_allowed",
                        f"tool:{payload.tool_name}",
                    ],
                    "tool_present": True,
                    "tool_name": payload.tool_name,
                    "tool_args": payload.tool_args or {},
                    "blocked": not tool_firewall_decision.allowed,
                    "approved": bool(tool_firewall_decision.allowed),
                    "reason": tool_firewall_decision.reason,
                },
            )

        if narrative_detected:
            hitl_policy_detected = bool(
                hitl_policy_hits
                or any(bool((policy.metadata or {}).get("hitl_bypass_attempt")) for policy in policy_hits)
            )
            if payload.tool_name:
                tool_interception = {
                    "tool_present": True,
                    "tool_name": payload.tool_name,
                    "intercepted": True,
                    "requires_2fa": False,
                    "approved": False,
                    "risk_level": "HIGH",
                    "risk_score": 90,
                    "reason": "HITL_BYPASS_ATTEMPT" if hitl_policy_detected else "narrative_prompt_injection_fail_safe",
                    "status_code": 403 if hitl_policy_detected else None,
                }
            else:
                tool_interception = {
                    "tool_present": False,
                    "intercepted": False,
                    "requires_2fa": False,
                    "approved": True,
                    "risk_level": "LOW",
                    "risk_score": 0,
                }

            result.tool_interception = tool_interception
            result.action = EnforcementAction.FORCE_REVIEW
            result.review_required = True

            security_audit_trail.append(
                event_type="narrative_injection_detected",
                session_id=session_id,
                user_id=payload.user_id,
                correlation_id=cid,
                severity="CRITICAL" if narrative_confidence >= 0.9 else "HIGH",
                data={
                    "confidence": round(narrative_confidence, 4),
                    "tool_name": payload.tool_name,
                    "detection_count": len(narrative_hits),
                },
            )
            security_logger.log_event(
                "narrative_injection_detected",
                {
                    "correlation_id": cid,
                    "session_id": session_id,
                    "confidence": round(narrative_confidence, 4),
                    "tool_name": payload.tool_name,
                },
                correlation_id=cid,
            )

        else:
            interceptor_metadata = dict(payload.metadata or {})
            interceptor_metadata.setdefault("prompt", candidate_prompt)
            interceptor_metadata.setdefault("tool_name", payload.tool_name)
            interceptor_metadata.setdefault("tool_args", payload.tool_args or {})

            detector_result_for_interceptor = {
                "is_flagged": bool(findings),
                "is_high_risk": any(hit.severity.value in {"HIGH", "CRITICAL"} for hit in findings),
                "threat_score": max(
                    (float(getattr(hit, "confidence", 0.0) or 0.0) for hit in findings),
                    default=0.0,
                ),
                "matched_findings": [hit.label for hit in findings],
                "restricted_tool_calls": [
                    keyword
                    for policy in policy_hits
                    for keyword in (policy.matched_keywords or [])
                    if "transfer" in keyword or "wire" in keyword
                ],
            }

            tool_interception = intercept_tool_call(
                tool_name=payload.tool_name,
                tool_args=payload.tool_args,
                two_factor_code=payload.two_factor_code,
                user_id=payload.user_id,
                metadata=interceptor_metadata,
                detector_result=detector_result_for_interceptor,
            )
            if tool_firewall_decision is not None and not tool_firewall_decision.allowed:
                tool_interception = {
                    **tool_interception,
                    "tool_present": True,
                    "tool_name": payload.tool_name,
                    "intercepted": True,
                    "requires_2fa": bool(tool_interception.get("requires_2fa")),
                    "approved": False,
                    "risk_level": "HIGH" if tool_firewall_decision.risk_score < 85 else "CRITICAL",
                    "risk_score": int(max(tool_interception.get("risk_score") or 0, tool_firewall_decision.risk_score)),
                    "reason": "tool_context_firewall_block",
                    "tool_context_firewall": {
                        "allowed": False,
                        "reason": tool_firewall_decision.reason,
                        "risk_score": tool_firewall_decision.risk_score,
                    },
                }
            result.tool_interception = tool_interception
            if tool_interception.get("requires_2fa"):
                result.requires_2fa = True
                if not bool(tool_interception.get("approved")):
                    result.action = EnforcementAction.INTERCEPT_AND_FORCE_2FA
                    result.review_required = True
            if tool_firewall_decision is not None and not tool_firewall_decision.allowed:
                result.action = EnforcementAction.BLOCK if tool_firewall_decision.risk_score >= 90 else EnforcementAction.FORCE_REVIEW
                result.review_required = True
                result.requires_2fa = result.requires_2fa or bool(tool_interception.get("requires_2fa"))

        if hitl_policy_hits:
            result.action = EnforcementAction.BLOCK
            result.requires_2fa = True
            result.review_required = True

        indirect_risk_hits = [
            hit for hit in findings
            if hit.detector == "indirect_prompt_injection_detector"
        ]
        indirect_block_hits = [
            hit for hit in indirect_risk_hits
            if str((hit.metadata or {}).get("verdict") or "").lower() == "block"
            or int((hit.metadata or {}).get("risk_score") or 0) >= 71
        ]
        if indirect_block_hits:
            top_indirect = max(indirect_block_hits, key=lambda item: int((item.metadata or {}).get("risk_score") or 0))
            categories = set((top_indirect.metadata or {}).get("detected_categories") or [])
            if categories & {"financial_action", "crypto_transfer", "credential_access", "tool_execution_request", "data_exfiltration"}:
                result.action = EnforcementAction.BLOCK
                result.review_required = True
                if categories & {"financial_action", "crypto_transfer", "credential_access"}:
                    result.requires_2fa = True

        existing_context_summary = dict(result.context_summary or {})
        context_summary = context_monitor.evaluate(
            session_id=session_id,
            conversation_id=payload.conversation_id,
            prompt=candidate_prompt,
            detector_hits=findings,
        )
        context_summary.update(existing_context_summary)
        if hitl_policy_hits:
            context_summary["hitl_bypass_attempt"] = True
            context_summary["authority_keyword_hits"] = authority_keyword_hits
            context_summary["decoded_payload_preview"] = decoded_payload_preview
        if tool_firewall_decision is not None:
            context_summary["tool_context_firewall"] = {
                "allowed": bool(tool_firewall_decision.allowed),
                "reason": str(tool_firewall_decision.reason),
                "risk_score": int(tool_firewall_decision.risk_score),
            }
        result.context_summary = context_summary

        tool_risk_score = int(result.tool_interception.get("risk_score") or 0)
        context_risk_score = int(context_summary.get("risk_score") or 0)
        risk_score = calculate_risk_score(
            detector_hits=findings,
            policy_hits=policy_hits,
            tool_risk_score=tool_risk_score,
            context_risk_score=context_risk_score,
        )
        result.risk_score = risk_score
        result.severity = classify_severity(risk_score)
        result.confidence = round(min(1.0, risk_score / 100.0), 4)

        if result.action == EnforcementAction.ALLOW:
            if any(match.action == EnforcementAction.BLOCK for match in policy_hits):
                result.action = EnforcementAction.BLOCK
                result.requires_2fa = True
                result.review_required = True
            elif any(match.action == EnforcementAction.INTERCEPT_AND_FORCE_2FA for match in policy_hits):
                result.action = EnforcementAction.INTERCEPT_AND_FORCE_2FA
                result.requires_2fa = True
                result.review_required = True
            elif risk_score >= 90:
                result.action = EnforcementAction.BLOCK
                result.review_required = True
            elif risk_score >= self.risk_threshold:
                result.action = EnforcementAction.FORCE_REVIEW
                result.review_required = True
            elif risk_score >= 40:
                result.action = EnforcementAction.WARN
            else:
                result.action = EnforcementAction.ALLOW

        graph_context = update_context_graph(
            session_id=graph_session_id,
            event_type="final_decision",
            data={
                "risk_score": min(1.0, float(risk_score) / 100.0),
                "confidence": min(1.0, float(risk_score) / 100.0),
                "labels": [f"action:{result.action.value}", f"severity:{result.severity.value.lower()}"],
                "action": result.action.value,
                "risk_level": result.severity.value.lower(),
            },
        )
        graph_recommendation = str(graph_context.override_recommendation or "").upper()
        if graph_recommendation == "BLOCK" and result.action != EnforcementAction.BLOCK:
            result.action = EnforcementAction.BLOCK
            result.review_required = True
        elif graph_recommendation in {"REVIEW", "FORCE_REVIEW"} and result.action == EnforcementAction.ALLOW:
            result.action = EnforcementAction.FORCE_REVIEW
            result.review_required = True
        context_summary["context_graph"] = graph_context.to_dict()
        result.context_summary = context_summary

        label_set = sorted({hit.label for hit in findings})
        if not label_set and policy_hits:
            label_set = [f"policy:{policy.policy_name}" for policy in policy_hits]

        attack_history_monitor.record_event(
            session_id=session_id,
            correlation_id=cid,
            labels=label_set,
            risk_score=risk_score,
            severity=result.severity.value,
        )

        result.explanation = self._build_explanation(result)
        result.telemetry = {
            "risk_threshold": self.risk_threshold,
            "detector_count": len(findings),
            "policy_count": len(policy_hits),
            "decode_artifact_count": len(decode_result.artifacts),
            "narrative_injection_detected": narrative_detected,
            "narrative_confidence": round(narrative_confidence, 4),
            "intent_score": round(intent_score, 4),
            "tool_context_firewall_blocked": bool(tool_firewall_decision is not None and not tool_firewall_decision.allowed),
            "hitl_bypass_attempt": bool(hitl_policy_hits),
            "authority_keyword_hits": authority_keyword_hits,
            "decoded_payload_preview": decoded_payload_preview,
            "indirect_prompt_injection": [
                {
                    "risk_score": int((hit.metadata or {}).get("risk_score") or 0),
                    "verdict": (hit.metadata or {}).get("verdict"),
                    "detected_categories": (hit.metadata or {}).get("detected_categories") or [],
                    "matched_signals": (hit.metadata or {}).get("matched_signals") or [],
                    "decoded_variants": (hit.metadata or {}).get("decoded_variants") or [],
                }
                for hit in indirect_risk_hits[:3]
            ],
        }

        if hitl_policy_hits:
            security_metrics.increment("security.hitl_bypass_attempts")
            security_audit_trail.append(
                event_type="hitl_bypass_attempt_blocked",
                session_id=result.session_id,
                user_id=payload.user_id,
                correlation_id=result.correlation_id,
                severity="CRITICAL",
                data={
                    "authority_keyword_hits": authority_keyword_hits,
                    "decoded_payload_preview": decoded_payload_preview,
                    "policy_matches": [policy.policy_name for policy in hitl_policy_hits],
                    "action": result.action.value,
                    "requires_2fa": result.requires_2fa,
                    "review_required": result.review_required,
                },
            )
            security_logger.log_event(
                "hitl_bypass_attempt_blocked",
                {
                    "correlation_id": result.correlation_id,
                    "session_id": result.session_id,
                    "authority_keyword_hits": authority_keyword_hits,
                    "decoded_payload_preview": decoded_payload_preview,
                    "action": result.action.value,
                    "requires_2fa": result.requires_2fa,
                    "review_required": result.review_required,
                },
                correlation_id=result.correlation_id,
            )

        security_metrics.increment("security.requests")
        security_metrics.increment(f"security.action.{result.action.value.lower()}")
        security_metrics.increment(f"security.severity.{result.severity.value.lower()}")
        security_metrics.set_latest("security.last_correlation_id", result.correlation_id)
        security_metrics.set_latest("security.last_risk_score", result.risk_score)

        security_audit_trail.append(
            event_type="security_pre_model_enforcement",
            session_id=result.session_id,
            user_id=payload.user_id,
            correlation_id=result.correlation_id,
            severity=result.severity.value,
            data={
                "action": result.action.value,
                "risk_score": result.risk_score,
                "conversation_id": result.conversation_id,
                "policy_matches": [policy.policy_name for policy in result.policy_matches],
                "detection_labels": label_set,
                "decoded_variants": [
                    item
                    for hit in indirect_risk_hits[:1]
                    for item in ((hit.metadata or {}).get("decoded_variants") or [])[:5]
                ],
                "matched_signals": [
                    item
                    for hit in indirect_risk_hits[:1]
                    for item in ((hit.metadata or {}).get("matched_signals") or [])[:10]
                ],
            },
        )
        security_logger.log_event(
            "security_pre_model_enforcement",
            {
                "correlation_id": result.correlation_id,
                "action": result.action.value,
                "severity": result.severity.value,
                "risk_score": result.risk_score,
                "session_id": result.session_id,
                "conversation_id": result.conversation_id,
                "policy_matches": [policy.policy_name for policy in result.policy_matches],
                "detection_labels": label_set,
                "decoded_variant_sources": [
                    str(item.get("source"))
                    for hit in indirect_risk_hits[:1]
                    for item in ((hit.metadata or {}).get("decoded_variants") or [])[:5]
                    if isinstance(item, dict)
                ],
            },
            correlation_id=result.correlation_id,
        )
        return result

    def post_model_enforce_output(self, *, enforcement: SecurityEnforcementResult, output_text: str) -> SecurityEnforcementResult:
        logic_result = logic_checker.verify_response(output_text, context=enforcement.context_summary)
        enforcement.telemetry["response_logic_check"] = logic_result.model_dump()
        if logic_result.verdict == "block":
            enforcement.action = EnforcementAction.BLOCK
            enforcement.review_required = True
            enforcement.risk_score = max(enforcement.risk_score, int(logic_result.risk_score))
            enforcement.severity = SeverityLevel.CRITICAL if logic_result.risk_level == "critical" else SeverityLevel.HIGH
            enforcement.telemetry["safe_response"] = logic_result.safe_response
            anonymizer.clear(request_id=enforcement.correlation_id, session_id=enforcement.session_id)
            security_logger.log_event(
                "response_logic_blocked",
                {
                    "correlation_id": enforcement.correlation_id,
                    "session_id": enforcement.session_id,
                    "verdict": logic_result.verdict,
                    "risk_score": logic_result.risk_score,
                    "risk_level": logic_result.risk_level,
                    "violations": [violation.rule for violation in logic_result.violations],
                },
                correlation_id=enforcement.correlation_id,
            )
            return enforcement

        safe_output_text = anonymizer.deanonymize(
            logic_result.safe_response or output_text,
            request_id=enforcement.correlation_id,
            session_id=enforcement.session_id,
        )
        enforcement.telemetry["safe_response"] = safe_output_text
        anonymizer.clear(request_id=enforcement.correlation_id, session_id=enforcement.session_id)

        if not self.enable_output_scanner:
            return enforcement

        redacted_output, findings, action = scan_output_for_leaks(safe_output_text)
        enforcement.output_findings = findings
        if findings:
            security_metrics.increment("security.output.findings", len(findings))
            if action == EnforcementAction.BLOCK:
                enforcement.action = EnforcementAction.BLOCK
                enforcement.review_required = True
            elif action == EnforcementAction.REDACT and enforcement.action == EnforcementAction.ALLOW:
                enforcement.action = EnforcementAction.REDACT
            enforcement.telemetry["output_redacted_text"] = redacted_output

            security_audit_trail.append(
                event_type="security_output_scan",
                session_id=enforcement.session_id,
                correlation_id=enforcement.correlation_id,
                severity="MEDIUM",
                data={
                    "findings": [finding.finding_type for finding in findings],
                    "action": action.value,
                },
            )
            security_logger.log_event(
                "security_output_scan",
                {
                    "correlation_id": enforcement.correlation_id,
                    "finding_count": len(findings),
                    "action": action.value,
                },
                correlation_id=enforcement.correlation_id,
            )
        return enforcement

    @staticmethod
    def _build_explanation(result: SecurityEnforcementResult) -> str:
        details: list[str] = []
        if result.policy_matches:
            details.append("financial policy matched")
        if result.requires_2fa:
            details.append("2FA required")
        if bool(result.context_summary.get("hitl_bypass_attempt")):
            details.append("HITL bypass attempt detected")
        tool_firewall = result.context_summary.get("tool_context_firewall") if isinstance(result.context_summary, dict) else None
        if isinstance(tool_firewall, dict) and not bool(tool_firewall.get("allowed", True)):
            details.append("tool-context firewall blocked execution")
        if result.detections:
            details.append(f"{len(result.detections)} detector signals")
        if result.output_findings:
            details.append(f"{len(result.output_findings)} output leak findings")
        if result.context_summary.get("flags"):
            details.append("context monitor raised attack-chain flags")
        if not details:
            return "No security anomalies detected in enforcement layer."
        return " | ".join(details)


security_enforcement_layer = SecurityEnforcementLayer()
