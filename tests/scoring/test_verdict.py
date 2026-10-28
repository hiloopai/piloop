"""The verdict rule on numbers alone: primary superiority by paired cluster bootstrap, guardrail non-inferiority.

Each verdict goes through the host's side of the contract (``ledger.decide``): the track of the
config become a ``Case`` of plain data, and the built-in rule's ``Judgement`` becomes the verdict of the database.
"""

import ast
import sys
from pathlib import Path

from inline_snapshot import snapshot
from piloop_min_gain import MinGain
from sqlalchemy import Enum

from piloop.actor import System
from piloop.config import CampaignConfig
from piloop.db.events import in_order
from piloop.db.models import Campaign
from piloop.db.session import Database
from piloop.plugins.campaign_type.kit.candidates.ids import Cause, Origin, Outcome
from piloop.plugins.campaign_type.kit.candidates.tables import Candidate
from piloop.plugins.campaign_type.kit.evaluation.config import Metric, MetricRole, Track, TrackConfig
from piloop.plugins.campaign_type.kit.evaluation.evaluate import Units
from piloop.plugins.campaign_type.kit.evaluation.ids import RungName, TrackName
from piloop.plugins.campaign_type.kit.verdicts import judge
from piloop.plugins.campaign_type.kit.verdicts.judge import criterion
from piloop.plugins.campaign_type.kit.verdicts.verdict import (
    PENDING,
    CandidateNoted,
    Refusal,
    daemon_owned,
    judgeable,
    label,
    note,
    noted_by,
    refusal,
    write,
)
from piloop.plugins.campaign_type.kit.verdicts.verdict_rule import bootstrap as verdict_module
from piloop.plugins.campaign_type.kit.verdicts.verdict_rule.bootstrap import Bootstrap, compare, lower_bound
from piloop.plugins.campaign_type.kit.verdicts.verdict_rule.contract import VERDICT_RULES, Side, Stopped, VerdictRule
from piloop.plugins.host import data_errors
from piloop.plugins.metric import Direction

BAR = 'candidate#73'


def decide(
    track: Track,
    confidence: float,
    mine: dict[str, float],
    theirs: dict[str, float],
    mine_units: Units,
    theirs_units: Units,
    *,
    bar: str,
) -> tuple[Outcome, str]:
    """The built-in rule's verdict on a candidate of ``track`` against ``bar``, as the daemon asks for it."""
    return judge.decide(
        Bootstrap(confidence=confidence), track, Side('candidate#74', mine, mine_units), Side(bar, theirs, theirs_units)
    )


def config(*guardrails: Metric, confidence: float = 0.95) -> CampaignConfig:
    return CampaignConfig(
        name='v',
        metrics=[Metric(name='accuracy', direction=Direction.HIGHER, role=MetricRole.PRIMARY), *guardrails],
        evaluate=['true'],
        plugins={'harness': {'pi': {'model': 'm'}}, 'verdict_rule': Bootstrap(confidence=confidence)},
    )


def rule(cfg: CampaignConfig) -> tuple[Track, float]:
    """What ``decide`` takes of a one-track config: its track and the confidence of its ``bootstrap``."""
    selected = VERDICT_RULES.selected(cfg.plugins)
    assert isinstance(selected, Bootstrap)
    return cfg.all_tracks[0], selected.confidence


def records(diffs: list[int], base: int = 1) -> tuple[dict[str, float], dict[str, float]]:
    """Per-record values of the bar and of a candidate that differs from it by ``diffs``."""
    theirs = {f'r{i:02}': float(base) for i in range(len(diffs))}
    mine = {f'r{i:02}': base + float(d) for i, d in enumerate(diffs)}
    return mine, theirs


def scored(mine: dict[str, float], theirs: dict[str, float]) -> tuple[dict[str, float], dict[str, float], Units, Units]:
    return (
        {'accuracy': sum(mine.values())},
        {'accuracy': sum(theirs.values())},
        {'accuracy': mine},
        {'accuracy': theirs},
    )


CONCENTRATED = [7, 6, 6] + [2] * 16 + [-2] * 14 + [1] + [0] * 35
"""A gain of +24 on 69 records: 19 of it from 3 records, and the other 5 left after gains and losses cancel out."""
BROAD = [2] * 16 + [1] * 4 + [-1] * 12 + [0] * 37
"""The same +24 on 69 records, spread over 20 of them."""


def test_a_gain_carried_by_three_units_is_interesting_not_keep() -> None:
    assert (len(CONCENTRATED), sum(CONCENTRATED), sum(CONCENTRATED[:3])) == (69, 24, 19)
    verdict, reason = decide(*rule(config()), *scored(*records(CONCENTRATED)), bar=BAR)
    assert verdict is Outcome.INTERESTING
    assert reason == snapshot(
        'against candidate#73: accuracy 93 vs 69 (+24; 95% worst case -1 over 69 units): the gain is not significant'
    )


def test_the_same_gain_spread_over_many_units_keeps() -> None:
    assert (len(BROAD), sum(BROAD)) == (69, 24)
    verdict, reason = decide(*rule(config()), *scored(*records(BROAD)), bar=BAR)
    assert verdict is Outcome.KEEP
    assert reason == snapshot('against candidate#73: accuracy 93 vs 69 (+24; 95% worst case +10 over 69 units)')


def test_the_bootstrap_is_seeded_so_a_verdict_is_reproducible() -> None:
    assert [lower_bound([float(d) for d in CONCENTRATED], 0.95) for _ in range(3)] == [-1.0, -1.0, -1.0]
    assert lower_bound([float(d) for d in CONCENTRATED], 0.80) > lower_bound([float(d) for d in CONCENTRATED], 0.95)
    verdict, _ = decide(*rule(config(confidence=0.8)), *scored(*records(CONCENTRATED)), bar=BAR)
    assert verdict is Outcome.KEEP, 'a laxer confidence admits the concentrated gain'


def test_without_units_the_aggregates_decide_and_the_reason_says_so() -> None:
    assert decide(*rule(config()), {'accuracy': 93}, {'accuracy': 69}, {}, {}, bar=BAR) == snapshot(
        (
            Outcome.KEEP,
            'against candidate#73: accuracy 93 vs 69 (+24; aggregate: no per-unit results)',
        )
    )
    mine, theirs = records(CONCENTRATED)
    assert decide(*rule(config()), {'accuracy': 93}, {'accuracy': 69}, {'accuracy': mine}, {}, bar=BAR)[1] == snapshot(
        'against candidate#73: accuracy 93 vs 69 (+24; aggregate: no per-unit results for the bar)'
    )
    assert decide(*rule(config()), {'accuracy': 93}, {'accuracy': 69}, {}, {'accuracy': theirs}, bar=BAR)[1] == (
        'against candidate#73: accuracy 93 vs 69 (+24; aggregate: no per-unit results for the candidate)'
    )
    del mine['r00']
    assert decide(
        *rule(config()), {'accuracy': 93}, {'accuracy': 69}, {'accuracy': mine}, {'accuracy': theirs}, bar=BAR
    )[1] == snapshot('against candidate#73: accuracy 93 vs 69 (+24; aggregate: the unit sets differ)')


def test_no_gain_or_a_loss_discards() -> None:
    assert decide(*rule(config()), {'accuracy': 69}, {'accuracy': 69}, {}, {}, bar=BAR) == snapshot(
        (Outcome.DISCARD, 'against candidate#73: accuracy 69 vs 69 (+0; aggregate: no per-unit results)')
    )
    assert decide(*rule(config()), *scored(*records([-1, 0, 0])), bar=BAR) == snapshot(
        (Outcome.DISCARD, 'against candidate#73: accuracy 2 vs 3 (-1; 95% worst case -2 over 3 units)')
    )


def test_a_crash_and_an_unscored_bar() -> None:
    assert decide(*rule(config()), {}, {'accuracy': 1}, {}, {}, bar=BAR) == (Outcome.CRASH, 'no successful measurement')
    assert decide(*rule(config()), {'accuracy': 1}, {}, {}, {}, bar=BAR) == snapshot(
        (Outcome.KEEP, 'candidate#73 has no score under the current evaluator')
    )


def test_a_climb_that_stopped_at_a_rung_is_a_discard_and_a_full_panel_outranks_it() -> None:
    track, confidence = rule(config())
    stopped = Stopped(RungName('screen'), 'accuracy 0.6 vs 0.7 (-0.1; margin 0.05)')
    bar = Side(BAR, {'accuracy': 0.7}, {})
    assert judge.decide(Bootstrap(confidence=confidence), track, Side('c', {}, {}, stopped=stopped), bar) == (
        Outcome.DISCARD,
        'stopped at screen: accuracy 0.6 vs 0.7 (-0.1; margin 0.05)',
    )
    remeasured = Side('c', {'accuracy': 0.6}, {}, stopped=stopped)
    assert judge.decide(Bootstrap(confidence=confidence), track, remeasured, bar)[0] is Outcome.DISCARD
    assert 'stopped' not in judge.decide(Bootstrap(confidence=confidence), track, remeasured, bar)[1]


COVERAGE = Metric(name='coverage', direction=Direction.HIGHER, role=MetricRole.GUARDRAIL, margin=10, floor=1000)
ERRORS = Metric(name='errors', direction=Direction.LOWER, role=MetricRole.GUARDRAIL, margin=50, floor=450)


def test_a_floor_breach_discards_whatever_the_primary_did() -> None:
    """A guardrail past its floor discards the candidate, even when the primary gained a lot."""
    mine = {'accuracy': 200.0, 'coverage': 990.0, 'errors': 745.0}
    theirs = {'accuracy': 80.0, 'coverage': 1000.0, 'errors': 300.0}
    assert decide(*rule(config(COVERAGE, ERRORS)), mine, theirs, {}, {}, bar=BAR) == snapshot(
        (Outcome.DISCARD, 'floor: coverage 990 past its floor 1000; errors 745 past its floor 450')
    )
    on_floor = {'accuracy': 200.0, 'coverage': 1000.0, 'errors': 450.0}
    assert decide(*rule(config(COVERAGE, ERRORS)), on_floor, {}, {}, {}, bar=BAR)[0] is Outcome.KEEP, (
        'the floor itself is allowed, and floors apply even against an unscored bar'
    )


def test_a_guardrail_regression_within_its_margin_keeps_beyond_it_is_interesting() -> None:
    theirs = {'accuracy': 80.0, 'coverage': 1020.0, 'errors': 300.0}
    within = {'accuracy': 90.0, 'coverage': 1010.0, 'errors': 350.0}
    assert decide(*rule(config(COVERAGE, ERRORS)), within, theirs, {}, {}, bar=BAR) == snapshot(
        (
            Outcome.KEEP,
            'against candidate#73: accuracy 90 vs 80 (+10; aggregate: no per-unit results); guardrails: coverage 1010 vs 1020 (-10; aggregate: no per-unit results) within its margin 10; errors 350 vs 300 (+50; aggregate: no per-unit results) within its margin 50',
        )
    )
    beyond = {'accuracy': 90.0, 'coverage': 1009.0, 'errors': 351.0}
    assert decide(*rule(config(COVERAGE, ERRORS)), beyond, theirs, {}, {}, bar=BAR) == snapshot(
        (
            Outcome.INTERESTING,
            'against candidate#73: accuracy 90 vs 80 (+10; aggregate: no per-unit results); guardrails: coverage 1009 vs 1020 (-11; aggregate: no per-unit results) beyond its margin 10; errors 351 vs 300 (+51; aggregate: no per-unit results) beyond its margin 50',
        )
    )


def test_a_guardrails_fraction_is_of_the_bars_value() -> None:
    """``fraction = 0.1`` on errors at 300 allows 30 more: the same rule as a margin of 30, whatever the scale."""
    relative = Metric(name='errors', direction=Direction.LOWER, role=MetricRole.GUARDRAIL, fraction=0.1)
    theirs = {'accuracy': 80.0, 'errors': 300.0}
    assert decide(*rule(config(relative)), {'accuracy': 90.0, 'errors': 330.0}, theirs, {}, {}, bar=BAR) == snapshot(
        (
            Outcome.KEEP,
            'against candidate#73: accuracy 90 vs 80 (+10; aggregate: no per-unit results); guardrails: errors 330 vs 300 (+30; aggregate: no per-unit results) within its fraction 0.1',
        )
    )
    assert decide(*rule(config(relative)), {'accuracy': 90.0, 'errors': 331.0}, theirs, {}, {}, bar=BAR)[0] is (
        Outcome.INTERESTING
    )


def test_a_guardrail_with_units_is_tested_on_its_bootstrap_worst_case() -> None:
    """The point regression is inside the margin, but one unit carries it all: the worst case is beyond."""
    loose = Metric(name='errors', direction=Direction.LOWER, role=MetricRole.GUARDRAIL, margin=6)
    mine_accuracy, theirs_accuracy = records([1] * 20)
    mine_errors = {f'r{i:02}': (5.0 if i == 0 else 0.0) for i in range(20)}
    theirs_errors = {f'r{i:02}': 0.0 for i in range(20)}
    verdict, reason = decide(
        *rule(config(loose)),
        {'accuracy': 40, 'errors': 5},
        {'accuracy': 20, 'errors': 0},
        {'accuracy': mine_accuracy, 'errors': mine_errors},
        {'accuracy': theirs_accuracy, 'errors': theirs_errors},
        bar=BAR,
    )
    assert verdict is Outcome.INTERESTING
    assert reason == snapshot(
        'against candidate#73: accuracy 40 vs 20 (+20; 95% worst case +20 over 20 units); guardrails: errors 5 vs 0 (+5; 95% worst case +15 over 20 units) beyond its margin 6'
    )
    untouched = decide(
        *rule(config(loose)),
        {'accuracy': 40, 'errors': 0},
        {'accuracy': 20, 'errors': 0},
        {'accuracy': mine_accuracy, 'errors': theirs_errors},
        {'accuracy': theirs_accuracy, 'errors': theirs_errors},
        bar=BAR,
    )
    assert untouched[0] is Outcome.KEEP, 'paired: units that did not move add no noise'


SECONDS = Metric(name='seconds', direction=Direction.LOWER, role=MetricRole.GUARDRAIL, margin=1)


def test_pairs_judge_a_metric_without_units_on_the_worst_case_of_the_mean_pair_difference() -> None:
    """The bar was measured long ago on a quiet host, the candidate under load: their means say nothing.

    The pairs ran next to each other, so the load hit both sides alike.
    """
    stale = ({'accuracy': 2, 'seconds': 24.5}, {'accuracy': 1, 'seconds': 5.6})
    pairs = (
        {'accuracy': [2.0, 2.0, 2.0], 'seconds': [6.5, 6.4, 6.6]},
        {'accuracy': [1.0, 1.0, 1.0], 'seconds': [6.5, 5.5, 6.4]},
    )
    track, confidence = rule(config(SECONDS))
    unpaired = judge.decide(
        Bootstrap(confidence=confidence), track, Side('candidate#74', stale[0], {}), Side(BAR, stale[1], {})
    )
    assert unpaired[0] is Outcome.INTERESTING
    paired = judge.decide(
        Bootstrap(confidence=confidence),
        track,
        Side('candidate#74', stale[0], {}, pairs[0]),
        Side(BAR, stale[1], {}, pairs[1]),
    )
    assert paired == snapshot(
        (
            Outcome.KEEP,
            'against candidate#73: accuracy 2 vs 1 (+1; 95% worst case +1 over 3 pairs); guardrails: seconds 6.5 vs 6.133 (+0.3667; 95% worst case +0.6667 over 3 pairs) within its margin 1',
        )
    )


def test_units_decide_a_metric_that_has_them_also_when_it_has_pairs() -> None:
    """Pairs of a deterministic metric differ by the same amount each time: they say nothing of the spread of the
    units, so a gain that three units carry is still not significant."""
    mine, theirs, mine_units, theirs_units = scored(*records(CONCENTRATED))
    samples = ({'accuracy': [mine['accuracy']] * 3}, {'accuracy': [theirs['accuracy']] * 3})
    verdict, reason = judge.decide(
        Bootstrap(),
        rule(config())[0],
        Side('candidate#74', mine, mine_units, samples[0]),
        Side(BAR, theirs, theirs_units, samples[1]),
    )
    assert (verdict, reason) == snapshot(
        (
            Outcome.INTERESTING,
            'against candidate#73: accuracy 93 vs 69 (+24; 95% worst case -1 over 69 units): the gain is not significant',
        )
    )


def test_samples_of_one_side_only_are_no_pairs() -> None:
    track, confidence = rule(config())
    only = judge.decide(
        Bootstrap(confidence=confidence),
        track,
        Side('candidate#74', {'accuracy': 2}, {}, {'accuracy': [2.0, 2.0]}),
        Side(BAR, {'accuracy': 1}, {}),
    )
    assert only == snapshot(
        (Outcome.KEEP, 'against candidate#73: accuracy 2 vs 1 (+1; aggregate: no per-unit results)')
    )


def test_a_guardrail_neither_side_measured_holds_the_keep_back() -> None:
    assert decide(*rule(config(ERRORS)), {'accuracy': 2}, {'accuracy': 1}, {}, {}, bar=BAR) == snapshot(
        (
            Outcome.INTERESTING,
            'against candidate#73: accuracy 2 vs 1 (+1; aggregate: no per-unit results); guardrails: errors unmeasured',
        )
    )


def test_a_lower_is_better_primary_reads_in_its_own_direction() -> None:
    cfg = CampaignConfig(
        name='v',
        metrics=[Metric(name='loss', direction=Direction.LOWER, role=MetricRole.PRIMARY)],
        evaluate=['true'],
        plugins={'harness': {'pi': {'model': 'm'}}},
    )
    theirs = {f'u{i}': 1.0 for i in range(30)}
    mine = {f'u{i}': 0.5 for i in range(30)}
    assert decide(*rule(cfg), {'loss': 15}, {'loss': 30}, {'loss': mine}, {'loss': theirs}, bar=BAR) == snapshot(
        (Outcome.KEEP, 'against candidate#73: loss 15 vs 30 (-15; 95% worst case -15 over 30 units)')
    )
    assert compare(criterion(cfg.all_tracks[0].primary), 15, 30, mine, theirs, 0.95).gain == 15


def test_a_lower_is_better_metric_that_did_not_move_reads_plus_zero() -> None:
    loss = Metric(name='loss', direction=Direction.LOWER, role=MetricRole.GUARDRAIL, margin=1)
    same_units = {f'u{i}': 1.0 for i in range(3)}
    assert (
        compare(criterion(loss), 3, 3, None, None, 0.95).text(0.95)
        == 'loss 3 vs 3 (+0; aggregate: no per-unit results)'
    )
    assert compare(criterion(loss), 3, 3, same_units, same_units, 0.95).text(0.95) == (
        'loss 3 vs 3 (+0; 95% worst case +0 over 3 units)'
    )


def same(track: Track, mine: dict[str, float], parent: dict[str, float]) -> bool:
    """Whether the built-in rule's reason says that the candidate is a no-op on its ``parent``, the bar too here."""
    sides = Side('candidate#74', mine, {}), Side(BAR, parent, {})
    reason = judge.decide(Bootstrap(), track, *sides, parent=Side('candidate#70', parent, {}))[1]
    return reason.startswith('no-op: ')


def test_same_means_every_deciding_metric_equal_and_ignores_watch_metrics() -> None:
    """Only the primary and the guardrails decide: a watch metric such as ``eval_seconds`` can differ."""
    guard = Metric(name='errors', direction=Direction.LOWER, role=MetricRole.GUARDRAIL, margin=1)
    watch = Metric(name='eval_seconds', direction=Direction.LOWER, role=MetricRole.WATCH)
    cfg = config(guard, watch)
    parent = {'accuracy': 10.0, 'errors': 2.0, 'eval_seconds': 63.1}
    assert same(cfg.all_tracks[0], {'accuracy': 10.0, 'errors': 2.0, 'eval_seconds': 613.1}, parent)
    assert not same(cfg.all_tracks[0], {'accuracy': 10.0, 'errors': 3.0, 'eval_seconds': 63.1}, parent), (
        'a guardrail moved'
    )
    assert not same(cfg.all_tracks[0], {'accuracy': 11.0, 'errors': 2.0}, parent), 'the primary moved'
    assert not same(cfg.all_tracks[0], {}, {}), 'nothing measured is no no-op: it is a crash or a skip'


def test_every_other_track_primary_is_a_guardrail_with_its_margin_and_floor() -> None:
    """A serving candidate must hold accuracy within its margin and above its floor; accuracy must hold cost too."""
    cfg = CampaignConfig(
        name='v',
        metrics=[
            Metric(
                name='acc', direction=Direction.HIGHER, role=MetricRole.PRIMARY, track='accuracy', margin=2, floor=90
            ),
            Metric(name='cost', direction=Direction.LOWER, role=MetricRole.PRIMARY, track='serving', margin=1),
            ERRORS,
        ],
        tracks={TrackName('accuracy'): TrackConfig(share=0.75), TrackName('serving'): TrackConfig(share=0.25)},
        evaluate=['true'],
        plugins={'harness': {'pi': {'model': 'm'}}},
    )
    serving, accuracy = cfg.track(TrackName('serving')), cfg.track(TrackName('accuracy'))
    assert ([m.name for m in serving.guardrails], [m.name for m in accuracy.guardrails]) == (
        ['errors', 'acc'],
        ['errors', 'cost'],
    ), 'the campaign guardrails first, then the other tracks primaries'
    theirs = {'acc': 95.0, 'cost': 10.0, 'errors': 300.0}
    neutral = {'acc': 94.0, 'cost': 8.0, 'errors': 300.0}
    assert decide(serving, 0.95, neutral, theirs, {}, {}, bar=BAR) == snapshot(
        (
            Outcome.KEEP,
            'against candidate#73: cost 8 vs 10 (-2; aggregate: no per-unit results); guardrails: errors 300 vs 300 (+0; aggregate: no per-unit results) within its margin 50; acc 94 vs 95 (-1; aggregate: no per-unit results) within its margin 2',
        )
    )
    costly = {'acc': 92.0, 'cost': 8.0, 'errors': 300.0}
    assert decide(serving, 0.95, costly, theirs, {}, {}, bar=BAR)[0] is Outcome.INTERESTING, 'accuracy beyond margin'
    floored = {'acc': 89.0, 'cost': 1.0, 'errors': 300.0}
    assert decide(serving, 0.95, floored, {**theirs, 'acc': 89.5}, {}, {}, bar=BAR) == snapshot(
        (Outcome.DISCARD, 'floor: acc 89 past its floor 90')
    )
    pricier = {'acc': 99.0, 'cost': 11.5, 'errors': 300.0}
    assert decide(accuracy, 0.95, pricier, theirs, {}, {}, bar=BAR)[0] is Outcome.INTERESTING, 'cost beyond margin'
    assert decide(accuracy, 0.95, {**pricier, 'cost': 10.5}, theirs, {}, {}, bar=BAR)[0] is Outcome.KEEP
    assert same(serving, {**theirs, 'eval_seconds': 3.0}, theirs)
    assert not same(serving, {**theirs, 'acc': 96.0}, theirs), "another track's primary decides too"


def test_every_guardrail_past_its_margin_is_in_the_reason_whatever_the_primary_did() -> None:
    """A flat primary, a gain that is not significant or a floor discard still names each guardrail past its margin.

    Otherwise the reason of a discard or an ``interesting`` hides a large regression of another metric.
    """
    cfg = config(COVERAGE, ERRORS)
    theirs = {'accuracy': 80.0, 'coverage': 1020.0, 'errors': 300.0}
    flat = {'accuracy': 80.0, 'coverage': 1005.0, 'errors': 420.0}
    assert decide(*rule(cfg), flat, theirs, {}, {}, bar=BAR) == snapshot(
        (
            Outcome.DISCARD,
            'against candidate#73: accuracy 80 vs 80 (+0; aggregate: no per-unit results); guardrails past their margin: coverage 1005 vs 1020 (-15; aggregate: no per-unit results) beyond its margin 10; errors 420 vs 300 (+120; aggregate: no per-unit results) beyond its margin 50',
        )
    )
    mine_accuracy, theirs_accuracy = records(CONCENTRATED)
    noisy = decide(
        *rule(cfg),
        {'accuracy': 93.0, 'coverage': 1020.0, 'errors': 420.0},
        {'accuracy': 69.0, 'coverage': 1020.0, 'errors': 300.0},
        {'accuracy': mine_accuracy},
        {'accuracy': theirs_accuracy},
        bar=BAR,
    )
    assert noisy == snapshot(
        (
            Outcome.INTERESTING,
            'against candidate#73: accuracy 93 vs 69 (+24; 95% worst case -1 over 69 units): the gain is not significant; guardrails past their margin: errors 420 vs 300 (+120; aggregate: no per-unit results) beyond its margin 50',
        )
    )
    floored = {'accuracy': 90.0, 'coverage': 990.0, 'errors': 420.0}
    assert decide(*rule(cfg), floored, theirs, {}, {}, bar=BAR) == snapshot(
        (
            Outcome.DISCARD,
            'floor: coverage 990 past its floor 1000; guardrails past their margin: errors 420 vs 300 (+120; aggregate: no per-unit results) beyond its margin 50',
        )
    )
    assert decide(*rule(cfg), floored, {}, {}, {}, bar=BAR) == snapshot(
        (Outcome.DISCARD, 'floor: coverage 990 past its floor 1000')
    ), 'an unscored bar has no margins to compare'
    within = {'accuracy': 80.0, 'coverage': 1015.0, 'errors': 320.0}
    assert decide(*rule(cfg), within, theirs, {}, {}, bar=BAR)[1] == snapshot(
        'against candidate#73: accuracy 80 vs 80 (+0; aggregate: no per-unit results)'
    ), 'a guardrail within its margin adds nothing to a discard'


def test_the_contract_of_a_rule_is_data_in_data_out_and_its_verdicts_are_verdicts() -> None:
    """A rule can move out of process or to a Wasm component: nothing live crosses its contract."""
    assert data_errors(VerdictRule) == []
    column = Candidate.__table__.c.verdict.type
    assert isinstance(column, Enum) and column.enum_class is Outcome, 'a candidate holds what a rule gives'


def test_the_built_in_rule_imports_only_the_standard_library_pydantic_its_contract_and_the_metric_types() -> None:
    """``bootstrap`` is a pure provider like a plugin's: it reads nothing of piloop's state. pydantic declares its
    parameters."""
    tree = ast.parse(Path(verdict_module.__file__).read_text())
    imported = {a.name for n in ast.walk(tree) if isinstance(n, ast.Import) for a in n.names} | {
        n.module for n in ast.walk(tree) if isinstance(n, ast.ImportFrom) and n.module is not None
    }
    outside = {m for m in imported if m.split('.')[0] not in sys.stdlib_module_names}
    assert outside == {
        'piloop.plugins.campaign_type.kit.verdicts.verdict_rule.contract',
        'piloop.plugins.metric',
        'pydantic',
    }


def test_the_example_rule_min_gain_delegates_to_bootstrap_and_holds_back_a_small_gain() -> None:
    """``examples/plugins/min-gain``: it calls the built-in rule and changes one thing, through the host's contract."""
    track = rule(config(COVERAGE))[0]

    def judged(mine: dict[str, float], theirs: dict[str, float], with_rule: VerdictRule) -> tuple[Outcome, str]:
        return judge.decide(with_rule, track, Side('candidate#74', mine, {}), Side(BAR, theirs, {}))

    bar = {'accuracy': 10.0, 'coverage': 1000.0}
    for mine, theirs in [
        ({'accuracy': 12.0, 'coverage': 1000.0}, bar),
        ({'accuracy': 9.0, 'coverage': 1000.0}, bar),
        ({'accuracy': 99.0, 'coverage': 990.0}, bar),
        ({'accuracy': 1.0}, {}),
        ({}, bar),
    ]:
        assert judged(mine, theirs, MinGain(min_gain=2)) == judged(mine, theirs, Bootstrap()), (
            'the built-in verdict stays'
        )
    assert judged({'accuracy': 11.0, 'coverage': 1000.0}, bar, MinGain(min_gain=2)) == (
        Outcome.INTERESTING,
        'against candidate#73: accuracy 11 vs 10 (+1; aggregate: no per-unit results); guardrails: coverage 1000 vs'
        ' 1000 (+0; aggregate: no per-unit results) within its margin 10; the gain is below min_gain 2',
    )


def test_only_a_judgement_is_overridden_and_a_note_needs_a_regressed_result() -> None:
    """``refusal`` is the one table of who may set which verdict by hand."""

    def of(origin: Origin, verdict: Outcome | None) -> Candidate:
        return Candidate(campaign_id=1, tree_sha='t', revision='c', origin=origin, verdict=verdict)

    note = Cause.NOTE
    assert [
        refusal(of(Origin.RUN, None), Outcome.KEEP, None),
        refusal(of(Origin.BASELINE, None), Outcome.KEEP, note),
        *(refusal(of(o, None), Outcome.KEEP, None) for o in (Origin.RECOVERED, Origin.SKIPPED)),
        *(refusal(of(Origin.REFERENCE, None), to, None) for to in (Outcome.INTERESTING, Outcome.DISCARD)),
        refusal(of(Origin.REFERENCE, None), Outcome.INTERESTING, note),
        refusal(of(Origin.RUN, Outcome.KEEP), Outcome.KEEP, None),
        refusal(of(Origin.RUN, Outcome.KEEP), Outcome.INTERESTING, note),
        refusal(of(Origin.RUN, Outcome.CRASH), Outcome.INTERESTING, note),
    ] == [
        Refusal.PENDING,
        Refusal.PENDING,
        Refusal.NOT_JUDGED,
        Refusal.NOT_JUDGED,
        Refusal.NOT_JUDGED,
        Refusal.NOT_JUDGED,
        Refusal.NOT_JUDGED,
        Refusal.SAME,
        Refusal.NO_RESULT,
        Refusal.NO_RESULT,
    ]
    assert refusal(of(Origin.RUN, Outcome.DISCARD), Outcome.INTERESTING, note) is None
    assert refusal(of(Origin.RUN, Outcome.INTERESTING), Outcome.INTERESTING, note) is None, 'a second note'
    assert refusal(of(Origin.BASELINE, Outcome.KEEP), Outcome.DISCARD, None) is None
    assert refusal(of(Origin.REFERENCE, None), Outcome.KEEP, None) is None, 'a reference is only kept by hand'
    assert refusal(of(Origin.REFERENCE, Outcome.KEEP), Outcome.INTERESTING, None) is None, 'then it is a judgement'


def test_a_note_never_re_signs_a_verdict_and_is_signed_in_its_own_event(db: Database, campaign: Campaign) -> None:
    """``verdict_by`` changes only with the verdict. A note on an ``interesting`` candidate keeps who judged it, and the
    daemon never judges a noted lead again. A note that turns a discard into a lead changes the verdict, so it signs it.
    """
    with db.session() as s:
        lead, worse = (
            Candidate(
                campaign_id=campaign.id,
                tree_sha=tree,
                revision=tree,
                origin=Origin.RUN,
                verdict=verdict,
                verdict_by='daemon',
                verdict_reason='against candidate#1: 2 vs 3',
            )
            for tree, verdict in (('lead', Outcome.INTERESTING), ('worse', Outcome.DISCARD))
        )
        s.add_all([lead, worse])
        s.flush()
        assert judgeable(lead)
        note(s, lead, 'a lead', by=System.ORCHESTRATOR)
        note(s, worse, 'worth a look', by=System.HUMAN)
        s.commit()
        assert (lead.verdict, lead.cause, lead.verdict_by, lead.verdict_reason) == (
            Outcome.INTERESTING,
            Cause.NOTE,
            'daemon',
            'a lead; against candidate#1: 2 vs 3',
        )
        assert not judgeable(lead), 'the daemon never judges a noted lead again'
        assert noted_by(s, lead) == 'orchestrator'
        assert (worse.verdict, worse.cause, worse.verdict_by) == (Outcome.INTERESTING, Cause.NOTE, 'human')
        assert [(e.actor, e.target_id, n.reason) for e, n in in_order(s, CandidateNoted)] == [
            ('orchestrator', lead.id, 'a lead'),
            ('human', worse.id, 'worth a look'),
        ]


def test_a_judged_skip_is_a_runs() -> None:
    skipped = Candidate(origin=Origin.SKIPPED)
    assert label(skipped) == 'skipped'
    write(skipped, Outcome.KEEP, cause=None, reason='measured at last', by=System.DAEMON)
    assert (skipped.origin, label(skipped), daemon_owned(skipped)) == (Origin.RUN, 'keep', True)
    assert label(Candidate(origin=Origin.BASELINE)) == PENDING


def test_the_daemon_judges_what_has_no_verdict_or_its_own_changeable_one_but_never_a_reference() -> None:
    def of(origin: Origin, verdict: Outcome | None, by: str | None) -> Candidate:
        return Candidate(origin=origin, verdict=verdict, verdict_by=by)

    assert [
        judgeable(of(Origin.RUN, None, None)),
        judgeable(of(Origin.SKIPPED, None, None)),
        judgeable(of(Origin.RUN, Outcome.DISCARD, 'daemon')),
        judgeable(of(Origin.RUN, Outcome.KEEP, 'daemon')),
        judgeable(of(Origin.RUN, Outcome.DISCARD, 'human')),
        judgeable(of(Origin.REFERENCE, None, None)),
    ] == [True, True, True, False, False, False], "a keep stays, and so does anyone else's verdict"
