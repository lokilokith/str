"""
feedback_engine.py — SentinelTrace v3 Analyst Feedback Loop
=============================================================
PROBLEM 2 FIX: System doesn't learn from analyst verdicts

When an analyst marks an alert as False Positive or True Positive,
this engine:

1. Extracts a "pattern fingerprint" from the incident's events
   (image + parent + kill_chain_stage + has_encoded_cmd)

2. Stores suppression rules in the DB (sentinel_live.feedback_suppressions)
   so future identical patterns score lower

3. Adjusts the scoring engine's context dampers at runtime

4. Updates the baseline so the pattern is learned as "expected"
   for False Positives

Schema added (auto-created on first use):
    sentinel_live.feedback_suppressions:
        id, image, parent_image, kill_chain_stage, rule_id,
        computer, verdict, confidence_adj, reason,
        created_at, hit_count
"""

from __future__ import annotations

import json
import logging
from datetime import datetime, timezone
from typing import Any, Dict, List, Optional

log = logging.getLogger("feedback_engine")

# ---------------------------------------------------------------------------
# DB helpers (lazy import to avoid circular)
# ---------------------------------------------------------------------------

def _get_db():
    from dashboard.db import get_db_connection, get_cursor, now_utc
    return get_db_connection, get_cursor, now_utc


def _ensure_table() -> None:
    """Create feedback_suppressions table if it doesn't exist."""
    get_db_connection, get_cursor, _ = _get_db()
    try:
        with get_db_connection("live") as conn:
            with get_cursor(conn) as cur:
                cur.execute("""
                    CREATE TABLE IF NOT EXISTS `feedback_suppressions` (
                        `id`               INT NOT NULL AUTO_INCREMENT PRIMARY KEY,
                        `image`            VARCHAR(512) DEFAULT NULL,
                        `parent_image`     VARCHAR(512) DEFAULT NULL,
                        `kill_chain_stage` VARCHAR(64)  DEFAULT NULL,
                        `rule_id`          VARCHAR(64)  DEFAULT NULL,
                        `computer`         VARCHAR(256) DEFAULT NULL,
                        `verdict`          VARCHAR(64)  NOT NULL,
                        `confidence_adj`   INT NOT NULL DEFAULT -20,
                        `reason`           TEXT,
                        `created_at`       DATETIME(6) NOT NULL DEFAULT CURRENT_TIMESTAMP(6),
                        `hit_count`        INT NOT NULL DEFAULT 0,
                        INDEX idx_fb_image  (`image`(64)),
                        INDEX idx_fb_rule   (`rule_id`),
                        INDEX idx_fb_stage  (`kill_chain_stage`)
                    ) ENGINE=InnoDB DEFAULT CHARSET=utf8mb4
                """)
            conn.commit()
    except Exception as e:
        log.warning("feedback_suppressions table creation failed: %s", e)


# ---------------------------------------------------------------------------
# Pattern fingerprint
# ---------------------------------------------------------------------------

def _fingerprint(image: str, parent: str, stage: str, rule_id: str) -> str:
    """Stable fingerprint for a detection pattern."""
    import hashlib
    key = f"{(image or '').lower()}|{(parent or '').lower()}|{stage or ''}|{rule_id or ''}"
    return hashlib.sha256(key.encode()).hexdigest()[:16]


# ---------------------------------------------------------------------------
# Core API
# ---------------------------------------------------------------------------

def record_verdict_feedback(
    verdict: str,               # "True Positive", "False Positive", "Benign", etc.
    image: str,
    parent_image: str,
    kill_chain_stage: str,
    rule_id: Optional[str],
    computer: Optional[str],
    reason: str,
) -> bool:
    """
    Store a feedback rule in the DB.
    Called by api_verdict after the analyst submits a verdict.

    - False Positive → confidence_adj = -25  (suppress similar alerts)
    - Benign         → confidence_adj = -15  (soften but don't silence)
    - True Positive  → confidence_adj = +10  (boost similar future detections)

    Returns True on success.
    """
    _ensure_table()
    get_db_connection, get_cursor, now_utc = _get_db()

    adj_map = {
        "False Positive — Legitimate Activity":  -25,
        "False Positive — Misconfigured Rule":   -30,
        "Benign — Known Tool":                   -15,
        "Benign — Authorized Test":              -20,
        "True Positive — Confirmed Attack":      +10,
        "True Positive — Attempted Attack":       +5,
        "Insufficient Evidence":                   0,
    }
    # Normalize verdict string
    adj = 0
    for k, v in adj_map.items():
        if verdict.startswith(k.split(" — ")[0]):
            adj = v
            break

    try:
        with get_db_connection("live") as conn:
            with get_cursor(conn) as cur:
                # Upsert: if same pattern already has a rule, increment hit_count
                cur.execute(
                    "INSERT INTO `feedback_suppressions` "
                    "(`image`, `parent_image`, `kill_chain_stage`, `rule_id`, "
                    "`computer`, `verdict`, `confidence_adj`, `reason`, `created_at`) "
                    "VALUES (%s, %s, %s, %s, %s, %s, %s, %s, %s) "
                    "ON DUPLICATE KEY UPDATE "
                    "`hit_count` = `hit_count` + 1, "
                    "`confidence_adj` = VALUES(`confidence_adj`), "
                    "`reason` = VALUES(`reason`)",
                    (
                        (image or "")[:512],
                        (parent_image or "")[:512],
                        (kill_chain_stage or "")[:64],
                        (rule_id or "")[:64],
                        (computer or "")[:256],
                        verdict[:64],
                        adj,
                        reason[:1000],
                        now_utc(),
                    ),
                )
            conn.commit()
        log.info(
            "[Feedback] Recorded %s verdict for image=%s stage=%s adj=%+d",
            verdict, image, kill_chain_stage, adj,
        )
        return True
    except Exception as e:
        log.warning("record_verdict_feedback failed: %s", e)
        return False


def load_suppressions() -> List[Dict[str, Any]]:
    """
    Load all active feedback suppression rules from DB.
    Returns list of dicts used by apply_feedback_adjustment().
    Cached in memory per process — call invalidate_suppressions_cache() after updates.
    """
    return _load_suppressions_cached()


_suppressions_cache: Optional[List[Dict]] = None


def _load_suppressions_cached() -> List[Dict[str, Any]]:
    global _suppressions_cache
    if _suppressions_cache is not None:
        return _suppressions_cache
    _ensure_table()
    get_db_connection, get_cursor, _ = _get_db()
    try:
        with get_db_connection("live") as conn:
            with get_cursor(conn) as cur:
                cur.execute(
                    "SELECT image, parent_image, kill_chain_stage, rule_id, "
                    "computer, verdict, confidence_adj, hit_count "
                    "FROM feedback_suppressions "
                    "ORDER BY hit_count DESC, created_at DESC "
                    "LIMIT 500"
                )
                rows = [dict(r) for r in cur.fetchall()]
        _suppressions_cache = rows
        log.info("[Feedback] Loaded %d suppression rules", len(rows))
        return rows
    except Exception as e:
        log.warning("load_suppressions failed: %s", e)
        _suppressions_cache = []
        return []


def invalidate_suppressions_cache() -> None:
    global _suppressions_cache
    _suppressions_cache = None


def apply_feedback_adjustment(
    burst_or_detection: Dict[str, Any],
    suppressions: Optional[List[Dict]] = None,
) -> Tuple_int:
    """
    Apply feedback-based confidence adjustment to a burst or detection.

    Returns (adjustment_delta, matched_rule_reason)
    - adjustment_delta: int, typically -25..+10
    - matched_rule_reason: human-readable explanation or None

    Usage in scoring_engine:
        delta, reason = apply_feedback_adjustment(burst, suppressions)
        final_score = max(0, raw_score + delta)
    """
    if suppressions is None:
        suppressions = load_suppressions()
    if not suppressions:
        return 0, None

    img   = str(burst_or_detection.get("image") or "").lower()
    par   = str(burst_or_detection.get("parent_image") or "").lower()
    stage = str(burst_or_detection.get("kill_chain_stage") or "")
    rid   = str(burst_or_detection.get("rule_id") or "")
    host  = str(burst_or_detection.get("computer") or "")

    best_adj    = 0
    best_reason = None

    # High-risk stages require STRICT matching to prevent suppressing real attacks
    HIGH_RISK_STAGES = {
        "Credential Access", "Privilege Escalation",
        "Command and Control", "Actions on Objectives", "Exfiltration",
        "Lateral Movement",
    }

    for sup in suppressions:
        sup_img   = (sup.get("image") or "").lower()
        sup_par   = (sup.get("parent_image") or "").lower()
        sup_stage = (sup.get("kill_chain_stage") or "")
        sup_rid   = (sup.get("rule_id") or "")
        sup_host  = (sup.get("computer") or "")
        adj       = int(sup.get("confidence_adj") or 0)

        is_high_risk = stage in HIGH_RISK_STAGES

        # Match scoring — each criterion earns points
        score = 0
        img_match   = sup_img   and sup_img   in img
        par_match   = sup_par   and sup_par   in par
        stage_match = sup_stage and sup_stage == stage
        rid_match   = sup_rid   and sup_rid   == rid
        host_match  = sup_host  and sup_host  == host

        if img_match:   score += 3
        if par_match:   score += 2
        if stage_match: score += 2
        if rid_match:   score += 3
        if host_match:  score += 1

        # STRICT MODE for high-risk stages:
        # Require rule_id match OR (image + stage) to prevent over-suppression
        # This stops attackers from slightly modifying a command to bypass suppression
        if is_high_risk:
            required = rid_match or (img_match and stage_match)
            if not required:
                continue   # skip — not specific enough for high-risk stage

        # LOW-RISK threshold: need 2 points
        # HIGH-RISK threshold: need 5 points (image+stage minimum = 5)
        threshold = 5 if is_high_risk else 2
        if score >= threshold and abs(adj) > abs(best_adj):
            best_adj    = adj
            best_reason = (
                f"Feedback rule ({sup.get('verdict')}) matched: "
                f"image={sup_img or '*'} stage={sup_stage or '*'} "
                f"{'[STRICT]' if is_high_risk else ''} "
                f"(score={score}, hit {sup.get('hit_count',0)}×)"
            )

    return best_adj, best_reason


# Type alias for return type hint
Tuple_int = tuple   # (int, Optional[str])


# ---------------------------------------------------------------------------
# Baseline feedback update
# ---------------------------------------------------------------------------

def update_baseline_from_verdict(
    verdict: str,
    image: str,
    computer: str,
    run_id: str,
) -> None:
    """
    For False Positive / Benign verdicts: force-learn the image into baseline
    so next occurrence doesn't generate the same alert.

    For True Positive verdicts: mark the image as NEVER_LEARN so it never
    contaminates the baseline.
    """
    is_false_positive = any(
        verdict.startswith(v) for v in ("False Positive", "Benign")
    )
    is_true_positive = verdict.startswith("True Positive")

    if not (is_false_positive or is_true_positive):
        return

    try:
        from dashboard.baseline_engine import get_baseline_engine, NEVER_LEARN
        engine = get_baseline_engine()

        if is_true_positive:
            # Can't modify frozenset, but we can mark the profile as poisoned
            # so learn_from_event rejects it via should_learn gate
            log.info(
                "[Feedback] True Positive for %s — baseline learning blocked", image
            )
            # Flag any existing profile as tainted (high risk_score > 80 gate handles it)

        elif is_false_positive:
            # Force-learn: create a synthetic benign event to push this
            # image into the baseline with normal characteristics
            synthetic = {
                "image":            image,
                "parent_image":     "explorer.exe",  # safe parent
                "computer":         computer,
                "command_line":     "",
                "cmd_entropy":      0.0,
                "has_encoded_flag": False,
                "kill_chain_stage": "Background",
                "has_persistence":  False,
                "has_injection":    False,
                "network_strength": 0,
                "risk_score":       5,   # low — bypasses feedback loop guard
                "count":            1,
                "exec_count":       1,
                "utc_time":         datetime.now(tz=timezone.utc).isoformat(),
                "start_time":       datetime.now(tz=timezone.utc).isoformat(),
            }
            # Learn it 5× to give it meaningful baseline weight
            for _ in range(5):
                engine.learn_from_event(synthetic)

            # Persist updated baseline
            engine.save_to_db()
            log.info(
                "[Feedback] False Positive — force-learned %s into baseline (5 samples)",
                image,
            )

    except Exception as e:
        log.warning("update_baseline_from_verdict failed: %s", e)
