from __future__ import annotations

import random

from app.question_engine.ylm.config import YLMConfig, enrich_config_with_lesson_rule
from app.question_engine.ylm.validators import (
    DIRECT_ADD_ALLOWED,
    DIRECT_SUB_ALLOWED,
    validate_question,
)

TEMPLATE_DIRECT = "DIRECT"
TEMPLATE_COMP5_ADD = "COMP5_ADD"
TEMPLATE_COMP5_SUB = "COMP5_SUB"
TEMPLATE_COMP10_ADD = "COMP10_ADD"
TEMPLATE_COMP10_SUB = "COMP10_SUB"
TEMPLATE_REVISION = "REVISION"


DIFFICULTY_STAGES: tuple[str, ...] = (
    "EASY",
    "EASY",
    "EASY_MEDIUM",
    "EASY_MEDIUM",
    "MEDIUM",
    "MEDIUM",
    "MEDIUM_HARD",
    "MEDIUM_HARD",
    "CHALLENGE",
    "CHALLENGE",
)

DIFFICULTY_ORDER: tuple[str, ...] = (
    "EASY",
    "EASY_MEDIUM",
    "MEDIUM",
    "MEDIUM_HARD",
    "CHALLENGE",
)

TEMPLATE_DIFFICULTY_WEIGHT: dict[str, int] = {
    TEMPLATE_DIRECT: 0,
    TEMPLATE_COMP5_ADD: 10,
    TEMPLATE_COMP5_SUB: 12,
    TEMPLATE_COMP10_ADD: 18,
    TEMPLATE_COMP10_SUB: 22,
}


def question_difficulty_stage(question_index: int) -> str:
    if question_index < 0:
        return "EASY"
    if question_index < len(DIFFICULTY_STAGES):
        return DIFFICULTY_STAGES[question_index]
    return "CHALLENGE"

# Phase B: revision worksheets must be concept-aware, not generic arithmetic.
# Each revision lesson uses a deterministic template rotation so every generated
# preview covers the intended taught families instead of accidentally clustering
# around one movement type.
REVISION_TEMPLATE_SCHEDULES: dict[int, tuple[str, ...]] = {
    # Direct + complement-of-5 addition revision.
    7: (
        TEMPLATE_DIRECT,
        TEMPLATE_COMP5_ADD,
        TEMPLATE_COMP5_ADD,
        TEMPLATE_DIRECT,
        TEMPLATE_COMP5_ADD,
    ),
    # Addition-focused complement-of-5 revision; direct rows only support fluency.
    12: (
        TEMPLATE_COMP5_ADD,
        TEMPLATE_COMP5_ADD,
        TEMPLATE_DIRECT,
        TEMPLATE_COMP5_ADD,
        TEMPLATE_COMP5_ADD,
    ),
    # Subtraction-focused complement-of-5 revision; direct rows only support fluency.
    13: (
        TEMPLATE_COMP5_SUB,
        TEMPLATE_COMP5_SUB,
        TEMPLATE_DIRECT,
        TEMPLATE_COMP5_SUB,
        TEMPLATE_COMP5_SUB,
    ),
    # Final YLM revision: all previously taught Golden Step families are represented.
    32: (
        TEMPLATE_DIRECT,
        TEMPLATE_COMP5_ADD,
        TEMPLATE_COMP5_SUB,
        TEMPLATE_COMP10_ADD,
        TEMPLATE_COMP10_SUB,
        TEMPLATE_COMP10_SUB,
        TEMPLATE_COMP10_ADD,
        TEMPLATE_COMP5_SUB,
        TEMPLATE_COMP5_ADD,
        TEMPLATE_DIRECT,
    ),
}


def _targets(config: YLMConfig, fallback: list[int]) -> list[int]:
    values = [abs(int(value)) for value in (config.target_numbers or []) if int(value) != 0]
    return values or fallback


def _direct_add_options(current: int) -> list[int]:
    return sorted(DIRECT_ADD_ALLOWED.get(current % 10, set()))


def _direct_sub_options(current: int) -> list[int]:
    return sorted(value for value in DIRECT_SUB_ALLOWED.get(current % 10, set()) if current - value >= 0)


def _direct_operands_for_focus(current: int, operation_focus: str) -> list[int]:
    operation_focus = (operation_focus or "ADD_LESS").upper()
    candidates: list[int] = []
    if operation_focus in {"ADD_LESS", "ADDITION"}:
        candidates.extend(_direct_add_options(current))
    if operation_focus in {"ADD_LESS", "SUBTRACTION"}:
        candidates.extend([-value for value in _direct_sub_options(current)])
    return [value for value in candidates if value != 0]


def _direct_bases(config: YLMConfig) -> list[int]:
    digit_pattern = (config.digit_pattern or "1D").upper()
    place_value = (config.place_value or "ONES").upper()
    if digit_pattern == "2D_TENS":
        return [10, 20, 30, 40, 50, 60, 70, 80, 90]
    if digit_pattern in {"2D", "1D_AND_2D"} or place_value in {"MIXED", "ONES_AND_TENS"}:
        return list(range(1, 10)) + [10, 20, 30, 40, 50, 60, 70, 80, 90]
    return list(range(1, 10))


def _safe_supports(current: int, template: str) -> list[int]:
    # Golden Step alignment rule:
    # - addition concept sheets receive only direct addition support rows
    # - subtraction concept sheets receive only direct subtraction support rows
    # - direct/revision direct templates may mix direct add-less rows
    if template in {TEMPLATE_COMP5_ADD, TEMPLATE_COMP10_ADD}:
        supports = _direct_operands_for_focus(current, "ADDITION")
    elif template in {TEMPLATE_COMP5_SUB, TEMPLATE_COMP10_SUB}:
        supports = _direct_operands_for_focus(current, "SUBTRACTION")
    else:
        supports = _direct_operands_for_focus(current, "ADD_LESS")
    if supports:
        return supports
    return _direct_operands_for_focus(current, "ADDITION") or _direct_operands_for_focus(current, "SUBTRACTION")


def _comp5_add_bases(target: int, config: YLMConfig) -> list[int]:
    ones = 5 - target
    tens_values = [0, 10, 20, 30, 40, 50, 60, 70, 80, 90]
    return [tens + ones for tens in tens_values if 0 < tens + ones <= 99]


def _comp5_sub_bases(target: int, config: YLMConfig) -> list[int]:
    ones_values = list(range(5, 5 + target))
    tens_values = [0, 10, 20, 30, 40, 50, 60, 70, 80, 90]
    return [tens + ones for tens in tens_values for ones in ones_values if 0 < tens + ones <= 99]


def _comp10_add_bases(target: int, config: YLMConfig) -> list[int]:
    # +target using complement of 10 must start from the exact trigger unit.
    # Example: +4 => 6 + 4, 16 + 4, 26 + 4. Not 38 + 4.
    ones = 10 - target
    tens_values = [0, 10, 20, 30, 40, 50, 60]
    return [tens + ones for tens in tens_values if tens + ones > 0]


def _comp10_sub_bases(target: int, config: YLMConfig) -> list[int]:
    # -target using complement of 10 must start from the exact borrow trigger range.
    # Example: -3 => 12 - 3, 22 - 3, 32 - 3. Not random two-digit subtraction.
    ones_values = list(range(0, target))
    tens_values = [10, 20, 30, 40, 50, 60, 70, 80, 90]
    return [tens + ones for tens in tens_values for ones in ones_values]


def _direct_stems(config: YLMConfig) -> list[tuple[int, int, str]]:
    stems: list[tuple[int, int, str]] = []
    for base in _direct_bases(config):
        for operand in _direct_operands_for_focus(base, config.operation_focus):
            stems.append((base, operand, TEMPLATE_DIRECT))
    return stems


def _template_stems(config: YLMConfig, template: str) -> list[tuple[int, int, str]]:
    template = (template or TEMPLATE_DIRECT).upper()
    stems: list[tuple[int, int, str]] = []
    if template == TEMPLATE_DIRECT:
        return _direct_stems(config)
    if template == TEMPLATE_COMP5_ADD:
        for target in _targets(config, [1, 2, 3, 4]):
            for base in _comp5_add_bases(target, config):
                stems.append((base, target, template))
    elif template == TEMPLATE_COMP5_SUB:
        for target in _targets(config, [1, 2, 3, 4]):
            for base in _comp5_sub_bases(target, config):
                stems.append((base, -target, template))
    elif template == TEMPLATE_COMP10_ADD:
        for target in _targets(config, [1, 2, 3, 4, 5, 6, 7, 8, 9]):
            for base in _comp10_add_bases(target, config):
                stems.append((base, target, template))
    elif template == TEMPLATE_COMP10_SUB:
        for target in _targets(config, [1, 2, 3, 4, 5, 6, 7, 8, 9]):
            for base in _comp10_sub_bases(target, config):
                stems.append((base, -target, template))
    return stems


def _lesson_templates(config: YLMConfig) -> tuple[str, ...]:
    template = (config.generation_template or TEMPLATE_DIRECT).upper()
    if template == TEMPLATE_REVISION:
        configured = tuple(value.upper() for value in (config.revision_templates or (TEMPLATE_DIRECT,)))
        schedule = REVISION_TEMPLATE_SCHEDULES.get(config.lesson_number)
        if schedule:
            # Keep the schedule strictly inside the lesson's configured taught families.
            allowed = set(configured)
            return tuple(value for value in schedule if value in allowed) or configured
        return configured
    return (template,)


def _template_for_question(config: YLMConfig, question_index: int) -> str | None:
    template = (config.generation_template or TEMPLATE_DIRECT).upper()
    if template != TEMPLATE_REVISION:
        return None
    templates = _lesson_templates(config)
    if not templates:
        return TEMPLATE_DIRECT
    return templates[question_index % len(templates)]


def _candidate_pool_for_templates(config: YLMConfig, templates: tuple[str, ...]) -> list[list[int]]:
    pool: list[list[int]] = []
    seen: set[tuple[int, ...]] = set()
    for template in templates:
        for base, primary, source_template in _template_stems(config, template):
            current = base + primary
            if current < 0:
                continue
            for support in _safe_supports(current, source_template):
                operands = [base, primary, support]
                key = tuple(operands)
                if key in seen:
                    continue
                if validate_question(config, operands, set()):
                    pool.append(operands)
                    seen.add(key)
    return pool


def build_candidate_pool(config: YLMConfig) -> list[list[int]]:
    config = enrich_config_with_lesson_rule(config)
    return _candidate_pool_for_templates(config, _lesson_templates(config))


def _operand_template_tag(operands: list[int]) -> str:
    if len(operands) < 2:
        return TEMPLATE_DIRECT
    primary = operands[1]
    if primary > 0 and abs(primary) in {1, 2, 3, 4}:
        base_ones = operands[0] % 10
        if base_ones == 5 - abs(primary):
            return TEMPLATE_COMP5_ADD
    if primary < 0 and abs(primary) in {1, 2, 3, 4}:
        base_ones = operands[0] % 10
        if 5 <= base_ones <= 4 + abs(primary):
            return TEMPLATE_COMP5_SUB
    if primary > 0 and abs(primary) in {1, 2, 3, 4, 5, 6, 7, 8, 9}:
        base_ones = operands[0] % 10
        if base_ones == 10 - abs(primary):
            return TEMPLATE_COMP10_ADD
    if primary < 0 and abs(primary) in {1, 2, 3, 4, 5, 6, 7, 8, 9}:
        base_ones = operands[0] % 10
        if 0 <= base_ones < abs(primary):
            return TEMPLATE_COMP10_SUB
    return TEMPLATE_DIRECT


def _difficulty_score(operands: list[int]) -> int:
    base = abs(operands[0]) if operands else 0
    answer = abs(sum(operands))
    support_count = max(0, len(operands) - 2)
    support_load = sum(abs(value) for value in operands[2:])
    primary_load = abs(operands[1]) if len(operands) > 1 else 0
    two_digit_bonus = 16 if max(base, answer) >= 10 else 0
    high_number_bonus = max(base, answer) // 10
    template_bonus = TEMPLATE_DIFFICULTY_WEIGHT.get(_operand_template_tag(operands), 0)
    direction_changes = 0
    previous_sign = 1 if operands[1] >= 0 else -1 if len(operands) > 1 else 0
    for value in operands[2:]:
        current_sign = 1 if value >= 0 else -1
        if previous_sign and current_sign != previous_sign:
            direction_changes += 1
        previous_sign = current_sign
    return (
        template_bonus
        + two_digit_bonus
        + high_number_bonus
        + primary_load
        + support_load
        + support_count * 3
        + direction_changes * 4
    )





def _max_question_value(operands: list[int]) -> int:
    running = operands[0] if operands else 0
    maximum = abs(running)
    for value in operands[1:]:
        running += value
        maximum = max(maximum, abs(running))
    return maximum


def _support_load(operands: list[int]) -> int:
    return sum(abs(value) for value in operands[2:]) if len(operands) > 2 else 0


def _support_direction_changes(operands: list[int]) -> int:
    if len(operands) < 3:
        return 0
    changes = 0
    previous = 1 if operands[1] >= 0 else -1
    for value in operands[2:]:
        current = 1 if value >= 0 else -1
        if current != previous:
            changes += 1
        previous = current
    return changes


def _absolute_stage_match(operands: list[int], target_stage: str) -> bool:
    """Absolute difficulty guard for YLM DPS ordering.

    Percentile buckets alone can make every question feel similar when a lesson has
    a narrow concept pool. This guard adds curriculum-friendly separation by using
    number size, support-row load, and direction changes while keeping the Golden
    Step concept unchanged.
    """
    max_value = _max_question_value(operands)
    support_load = _support_load(operands)
    changes = _support_direction_changes(operands)
    tag = _operand_template_tag(operands)

    # Direct beginner lessons live mostly inside one digit, so progression comes
    # from support load and direction changes rather than large place value.
    if tag == TEMPLATE_DIRECT and max_value < 10:
        if target_stage == "EASY":
            return support_load <= 4 and changes <= 1
        if target_stage == "EASY_MEDIUM":
            return support_load <= 5
        if target_stage == "MEDIUM":
            return support_load <= 6
        if target_stage == "MEDIUM_HARD":
            return support_load >= 4
        return support_load >= 5 or changes >= 1

    if target_stage == "EASY":
        return max_value <= 25 and support_load <= 4 and changes <= 1
    if target_stage == "EASY_MEDIUM":
        return max_value <= 45 and support_load <= 5
    if target_stage == "MEDIUM":
        return 20 <= max_value <= 70
    if target_stage == "MEDIUM_HARD":
        return max_value >= 35 and support_load >= 2
    if target_stage == "CHALLENGE":
        return max_value >= 55 or support_load >= 7 or changes >= 1
    return True


def _near_duplicate_key(operands: list[int]) -> tuple:
    """Stable shape key used to avoid repeated-looking DPS rows.

    Exact uniqueness is not enough for a premium worksheet. Questions such as
    36 + 4 + 2 and 36 + 4 + 3 are technically unique but feel repetitive. This
    key keeps the lesson concept intact while preferring different decades and
    support shapes across a 10-question DPS.
    """
    tag = _operand_template_tag(operands)
    base = operands[0] if operands else 0
    primary = operands[1] if len(operands) > 1 else 0
    support_signature = tuple((1 if value >= 0 else -1, abs(value)) for value in operands[2:])
    return (tag, primary, base // 10, support_signature)


def _near_duplicate_family(operands: list[int]) -> tuple:
    tag = _operand_template_tag(operands)
    base = operands[0] if operands else 0
    primary = operands[1] if len(operands) > 1 else 0
    return (tag, primary, base // 10)


def _without_near_duplicates(candidates: list[list[int]], seen: set[tuple[int, ...]]) -> list[list[int]]:
    if not candidates or not seen:
        return candidates
    seen_operands = [list(values) for values in seen]
    used_keys = {_near_duplicate_key(values) for values in seen_operands}
    strong = [operands for operands in candidates if _near_duplicate_key(operands) not in used_keys]
    if strong:
        return strong
    used_families = {_near_duplicate_family(values) for values in seen_operands}
    relaxed = [operands for operands in candidates if _near_duplicate_family(operands) not in used_families]
    return relaxed or candidates


def _bucketed_by_difficulty(pool: list[list[int]]) -> dict[str, list[list[int]]]:
    if not pool:
        return {stage: [] for stage in DIFFICULTY_ORDER}
    ordered = sorted(pool, key=lambda operands: (_difficulty_score(operands), tuple(operands)))
    bucketed: dict[str, list[list[int]]] = {stage: [] for stage in DIFFICULTY_ORDER}
    total = len(ordered)
    for index, operands in enumerate(ordered):
        bucket_index = min(len(DIFFICULTY_ORDER) - 1, (index * len(DIFFICULTY_ORDER)) // max(total, 1))
        bucketed[DIFFICULTY_ORDER[bucket_index]].append(operands)
    return bucketed


def _difficulty_candidates(pool: list[list[int]], target_stage: str) -> list[list[int]]:
    bucketed = _bucketed_by_difficulty(pool)
    target_stage = target_stage if target_stage in DIFFICULTY_ORDER else "MEDIUM"
    target_index = DIFFICULTY_ORDER.index(target_stage)

    stage_order = [target_stage]
    for distance in range(1, len(DIFFICULTY_ORDER)):
        lower = target_index - distance
        upper = target_index + distance
        if lower >= 0:
            stage_order.append(DIFFICULTY_ORDER[lower])
        if upper < len(DIFFICULTY_ORDER):
            stage_order.append(DIFFICULTY_ORDER[upper])

    for stage in stage_order:
        stage_pool = list(bucketed.get(stage, []))
        absolute_pool = [operands for operands in stage_pool if _absolute_stage_match(operands, target_stage)]
        if absolute_pool:
            return absolute_pool
        if stage_pool:
            return stage_pool

    absolute_all = [operands for operands in pool if _absolute_stage_match(operands, target_stage)]
    return absolute_all or list(pool)


def generate_unique_operands(config: YLMConfig, rng: random.Random, seen: set[tuple[int, ...]]) -> list[int]:
    config = enrich_config_with_lesson_rule(config)
    question_index = len(seen)
    preferred_template = _template_for_question(config, question_index)
    target_stage = question_difficulty_stage(question_index)

    if preferred_template:
        preferred_pool = _candidate_pool_for_templates(config, (preferred_template,))
        preferred_available = [operands for operands in preferred_pool if tuple(operands) not in seen]
        preferred_available = _without_near_duplicates(preferred_available, seen)
        available = _difficulty_candidates(preferred_available, target_stage)
        if available:
            return list(rng.choice(available))
        if preferred_pool:
            # If a narrow revision family runs out of unique combinations, reuse that
            # same valid family before moving to broader revision. Never use generic fallback.
            return list(rng.choice(_difficulty_candidates(preferred_pool, target_stage)))

    pool = build_candidate_pool(config)
    unique_pool = [operands for operands in pool if tuple(operands) not in seen]
    unique_pool = _without_near_duplicates(unique_pool, seen)
    available = _difficulty_candidates(unique_pool, target_stage)
    if not available:
        # Non-negotiable platform behavior: every YLM lesson must generate valid output.
        # Reuse the same valid lesson-template pool if the unique request exceeds the
        # available pattern count; never fall back to generic arithmetic.
        available = _difficulty_candidates(pool, target_stage)
    if not available:
        raise ValueError(f"YLM lesson {config.lesson_number} has no valid Golden Step generation pool")
    return list(rng.choice(available))


def generate_operands(config: YLMConfig, rng: random.Random) -> list[int]:
    return generate_unique_operands(config, rng, set())
