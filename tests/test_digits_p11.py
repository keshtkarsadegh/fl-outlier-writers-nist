"""
P11: the aggregation screen, and the selection that follows it.

The screen is 845 runs whose only purpose is to rank, so the tests here are
about the two ways a rank can be wrong without looking wrong: a line that does
not run the protocol it claims to, and a selection whose output does not match
the array written to consume it.
"""

from __future__ import annotations

import json
import shlex
import sys
from pathlib import Path

import pytest

from federated_outlier_adaptation.training import agg_cells
from federated_outlier_adaptation.training import study_lines as SL
from federated_outlier_adaptation.training.study_config import (
    DIGITS_STUDY01,
    STUDIES,
    config,
)

TOOLS = str(Path(__file__).resolve().parents[1] / "tools")


@pytest.fixture(autouse=True)
def _shipped_baselines(tmp_path):
    """
    Every synthetic study root carries g-0's own two accuracies.

    Selection is measured against them - what a run ADDED on the new clients,
    less the source knowledge it SPENT - so a root without them is not a study
    root, and the emitters refuse it rather than guess. The real programme
    writes these in the selection stage, one record per fold.
    """
    for name, accuracy in (("g0_perfold_evaluations.json", 0.8225),
                           ("g0_evaluations.json", 0.9986)):
        (tmp_path / name).write_text(json.dumps({
            str(fold): {"fold": fold, "part": "test", "accuracy": accuracy}
            for fold in (1, 2, 3, 4, 5)
        }))
    return tmp_path


@pytest.fixture()
def tools_path():
    if TOOLS not in sys.path:
        sys.path.insert(0, TOOLS)
    return TOOLS


@pytest.fixture()
def p11(tools_path):
    import make_digits_p11

    return make_digits_p11


@pytest.fixture()
def emit(tools_path):
    import study_emit

    return study_emit


@pytest.fixture()
def parsed(p11):
    from federated_outlier_adaptation.cli import build_parser

    parser = build_parser()
    # the screen FILE, not the whole table: the boundary extension was appended
    # to the table afterwards and is submitted as its own file.
    return [
        parser.parse_args(shlex.split(line)[1:]) for line in p11.screened_lines()
    ]


# --------------------------------------------------------------------------- #
# the revived configuration, and nothing else
# --------------------------------------------------------------------------- #


def test_no_two_studies_can_collide_in_one_root():
    """
    Different tags and different seed bases, so a folder or a sampler seed can
    never be claimed by two studies at once. Holds for one study and for five;
    the registry gains and loses them as the programme moves.
    """
    tags = {cfg.tag for cfg in STUDIES.values()}
    bases = {cfg.seed_base for cfg in STUDIES.values()}
    assert len(tags) == len(bases) == len(STUDIES)
    spacings = [abs(a - b) for a in bases for b in bases if a != b]
    if spacings:
        # Far enough apart that no stage's offset reaches the next study's block.
        assert min(spacings) >= 50_000


def test_the_study_is_the_digit_design_point():
    cfg = DIGITS_STUDY01
    assert cfg.classes == "digits"
    assert (cfg.cohort_size, cfg.old_size, cfg.clients_per_round) == (10, 200, 9)
    assert cfg.dropout == pytest.approx(0.1)
    assert cfg.cohort_file_name == "cohort_worst10.json"
    assert cfg.cohort_book_name == "cohort10"


def test_the_seed_base_is_clear_of_every_earlier_stage(p11):
    """
    P09's seeds run 30001-30505, and the earlier stages' are hand-written.

    Two lines drawing the same participation pattern would be a coincidence
    nobody would notice and nobody could undo.
    """
    assert DIGITS_STUDY01.seed_base >= 700000
    first = DIGITS_STUDY01.seed_base + p11.SEED_OFFSET
    assert first > 100000


def test_the_dataset_flags_follow_the_configuration():
    assert SL.setting(DIGITS_STUDY01) == "--resolution 28 --classes digits"


# --------------------------------------------------------------------------- #
# the table and the grouping
# --------------------------------------------------------------------------- #
def test_the_screen_is_the_same_cell_table_as_always(p11):
    """
    The table is 171 now; the screen that ran is still its first 169.

    The two extra cells are the trim row's boundary extension, appended after
    the fact - see the extension tests below.
    """
    assert len(agg_cells.screen_cells()) == 96
    assert p11.SCREENED_CELLS == 96
    assert len(p11.screened_lines()) == 480
    assert SL.counts(DIGITS_STUDY01)["agg_screen"] == 480


def test_the_methods_are_the_seventeen():
    """
    A weighting rule is not a coefficient of another weighting rule, and a
    control with the oracle stop rule armed is not a setting of the one without.
    """
    methods = {method for _, method in SL.AGG_METHODS}
    assert len(SL.AGG_METHODS) == 17
    # The weighting is one method swept over an exponent, not four methods:
    # its cells differ in a coefficient, the way the eta row's do.
    for name in ("weight_q", "eta", "anchor", "trimmed", "seq_mix",
                 "control_fedavg", "control_fedavg_earlystop"):
        assert name in methods, name
    assert SL.counts(DIGITS_STUDY01)["agg_full"] == 85


def test_every_cell_belongs_to_exactly_one_method():
    from collections import Counter

    counted = Counter(
        (cell["path"], SL.agg_method_of(cell)) for cell in agg_cells.screen_cells()
    )
    assert set(counted) == set(SL.AGG_METHODS)
    assert sum(counted.values()) == 96
    # a wider row is not a new method
    assert counted[("concurrent", "trimmed")] == 3


# --------------------------------------------------------------------------- #
# the 845 lines
# --------------------------------------------------------------------------- #
def test_the_screen_is_every_cell_at_every_fold(p11, parsed):
    assert len(parsed) == 480
    cells = {c["id"] for c in agg_cells.screen_cells()[:p11.SCREENED_CELLS]}
    seen = {
        (a.parent[len("d01_agg_"):].rsplit("_fold", 1)[0], a.fold) for a in parsed
    }
    assert len(seen) == 480
    assert {c for c, _ in seen} == cells


def test_every_line_draws_the_search_rate(parsed):
    # search_clients_per_round, not the study's own clients_per_round: a grid is
    # searched once at the harder rate and the winners are carried to the rest.
    for args in parsed:
        assert args.clients_per_round == DIGITS_STUDY01.search_clients_per_round == 8
        assert args.clients_per_round != DIGITS_STUDY01.clients_per_round
        assert args.policy == "uniform"


def test_a_search_rate_its_cohort_cannot_hold_is_refused(emit):
    """
    The constant is written for ten clients, and it is not carried down.

    A five-client study inherits ``search_clients_per_round`` unchanged, so a
    grid stage emitted for it would ask eight of five; an eight-client one would
    get full participation from a constant whose whole purpose is to be harder
    than that. Both have to stop before a task file exists.
    """
    import dataclasses

    for cohort in (5, 8):
        small = dataclasses.replace(
            DIGITS_STUDY01, name="smaller", cohort_size=cohort,
            clients_per_round=cohort - 1,
        )
        with pytest.raises(SystemExit) as raised:
            emit.searched_at(small)
        assert f"8 of {cohort}" in str(raised.value)


def test_every_line_is_the_digit_task_at_the_screening_horizon(parsed):
    for args in parsed:
        assert args.classes == "digits" and args.resolution == 28
        assert args.rounds == SL.SCREEN_ROUNDS == 25
        assert (args.epochs, args.batch_size) == (5, 64)
        assert args.trainer == "BaseTrainer"


def test_every_line_reads_the_cohort_and_the_old_book(parsed):
    for args in parsed:
        assert args.outliers_file.endswith("outliers/cohort_worst10.json")
        assert args.fold_book.endswith("fold_books/cohort10.foldbook.npz")
        assert args.old_book.endswith("fold_books/old_data.foldbook.npz")
        assert args.old_clients_file.endswith("outliers/old_data.json")


def test_every_line_starts_from_g0_and_keeps_its_model(parsed):
    for args in parsed:
        assert args.init == "global" and args.global_name == "g0"
        assert args.save_final_model and args.track_clients


def test_preservation_is_five_folds_on_every_line(parsed):
    """Five independent re-draws of one population are what the error bar is made of."""
    for args in parsed:
        assert args.old_fold == "all"


def test_no_line_touches_an_archived_or_foreign_artefact(p11, parsed):
    text = "\n".join(p11.lines())
    # "T1_" alone would be a false positive on a KD-style cell id; match the
    # retired STUDY names rather than the letter.
    for dead in ("v1_superseded", "main_v6", "studies/T", "T1_20outliers",
                 "T1_10outliers", "T2_20outliers", "T2_10outliers",
                 "T3_20normals", "T3_10normals", "all_writers_digits"):
        assert dead not in text, dead
    for args in parsed:
        for attr in ("results_dir", "outliers_file", "fold_book", "old_book",
                     "old_clients_file"):
            value = getattr(args, attr, None)
            if isinstance(value, str):
                assert value.startswith("$FOA_STUDY_DIR"), (attr, value)


def test_the_lines_are_480_distinct_cells_with_480_distinct_seeds(parsed):
    assert len({a.parent for a in parsed}) == 480
    assert len({a.sampler_seed for a in parsed}) == 480


def test_no_seed_collides_with_the_federated_stage(parsed):
    """P09 used 30001-30505; a shared seed would repeat a draw silently."""
    p09 = set(range(30001, 30506))
    assert not {a.sampler_seed for a in parsed} & p09


def test_each_named_rule_resolves_to_its_own_family(parsed):
    """
    A named rule runs one family; only the controls span two, by definition.

    A cell resolving to the wrong schedule would be a different experiment under
    the same name.
    """
    from federated_outlier_adaptation.aggregation.selector import (
        AGG_VARIANTS,
        SKIP_FAMILY,
        resolve_aggregation,
    )

    cells = {c["id"]: c for c in agg_cells.screen_cells()}
    variants = 0
    for args in parsed:
        cell = cells[args.parent[len("d01_agg_"):].rsplit("_fold", 1)[0]]
        if args.aggregation in AGG_VARIANTS:
            assert cell["path"] == "control"
            variants += 1
            continue
        families = [
            (scenario, metadata)
            for scenario in ("concurrent", "sequential")
            for metadata in ("weights", "delta")
            if resolve_aggregation(scenario, metadata, args.aggregation,
                                   extended=True) != SKIP_FAMILY
        ]
        assert len(families) == 1, (cell["id"], families)
        assert families[0][0] == cell["path"]
    # the two control cells, five folds each
    assert variants == 10


def test_the_coefficients_round_trip_exactly(parsed, p11):
    """A label may round; a coefficient may not."""
    from federated_outlier_adaptation.cli import _server_kwargs

    cells = {c["id"]: c for c in agg_cells.screen_cells()}
    for args in parsed:
        cell = cells[args.parent[len("d01_agg_"):].rsplit("_fold", 1)[0]]
        kwargs = _server_kwargs(args)
        flags = cell["flags"]
        if "server_anchor" in flags:
            assert kwargs["anchor_lambda"] == flags["server_anchor"]
        if "server_lr" in flags:
            assert kwargs["server_lr"] == flags["server_lr"]
        if "server_tau" in flags:
            assert kwargs["tau"] == flags["server_tau"]
        if "server_eta" in flags:
            assert args.server_eta == flags["server_eta"]
        if "seq_mix_alpha" in flags:
            assert args.seq_mix_alpha == flags["seq_mix_alpha"]


# --------------------------------------------------------------------------- #
# the selection
# --------------------------------------------------------------------------- #
def _result(root: Path, prefix: str, cell_id: str, fold: int, adaptation: float,
            preservation: float = 0.9):
    run = (root / f"{prefix}{cell_id}_fold{fold}_x_grid_search" / "fold1_seed_1"
           / "concurrent_delta" / "base_agg_x")
    run.mkdir(parents=True, exist_ok=True)
    (run / "accuracies_0.json").write_text(json.dumps({
        "scenario": "concurrent",
        "accuracies": [[adaptation, 0.5]] * 25,
        "pool_val_accuracies": [adaptation] * 25,
        "final_evaluation": {
            "clients": {"accuracy": adaptation - 0.01},
            "old": {"mean": preservation, "sd": 0.0},
        },
    }))


def test_the_selection_keeps_every_method(emit, tmp_path):
    """
    No method filtering: eighteen methods, eighteen winners.

    Selecting one overall winner would leave the full stage comparing it against
    nothing.
    """
    cells = agg_cells.screen_cells()
    for index, cell in enumerate(cells):
        for fold in (1, 2):
            _result(tmp_path, "d01_agg_", cell["id"], fold, 0.5 + index * 1e-4)

    out = tmp_path / "p12.txt"
    expect = SL.counts(DIGITS_STUDY01)["agg_full"]
    assert emit.agg_full(DIGITS_STUDY01, tmp_path, out, expect) == 0

    lines = [l for l in out.read_text().splitlines() if l and not l.startswith("#")]
    assert len(lines) == expect == 85
    record = json.loads(
        (tmp_path / "tables" / "p11_agg_method_winners.json").read_text()
    )
    assert len(record) == 17 and all(e["measured"] for e in record.values())


def test_a_miscount_halts_rather_than_mismatching_the_array(emit, tmp_path):
    for cell in agg_cells.screen_cells():
        _result(tmp_path, "d01_agg_", cell["id"], 1, 0.5)
    assert emit.agg_full(DIGITS_STUDY01, tmp_path, tmp_path / "p12.txt", 999) == 1


def test_the_emitted_p12_file_says_it_is_not_authorised(emit, tmp_path):
    """It exists so the file is ready for review, not so it can be submitted."""
    for cell in agg_cells.screen_cells():
        _result(tmp_path, "d01_agg_", cell["id"], 1, 0.5)
    out = tmp_path / "p12.txt"
    emit.agg_full(DIGITS_STUDY01, tmp_path, out, 90)
    text = out.read_text()
    assert "NOT YET AUTHORISED" in text
    assert "gated separately" in text


def test_the_emitted_p12_lines_are_the_full_horizon(emit, tmp_path):
    from federated_outlier_adaptation.cli import build_parser

    for cell in agg_cells.screen_cells():
        _result(tmp_path, "d01_agg_", cell["id"], 1, 0.5)
    out = tmp_path / "p12.txt"
    # 85, which is what the emitter writes: an expect it cannot meet makes the
    # emitter halt, and an unchecked return code let this test go on reading an
    # empty file and passing on nothing at all
    assert emit.agg_full(DIGITS_STUDY01, tmp_path, out, 85) == 0

    parser = build_parser()
    lines = [l for l in out.read_text().splitlines() if l and not l.startswith("#")]
    for line in lines:
        args = parser.parse_args(shlex.split(line)[1:])
        assert args.rounds == SL.FULL_ROUNDS == 100
        # the finals must match the screen they were selected from, so they
        # take search_clients_per_round too
        assert args.clients_per_round == 8 and args.classes == "digits"
        assert args.old_fold == "all"
    assert len({shlex.split(l)[shlex.split(l).index("--parent") + 1] for l in lines}) == 85


def test_grid_edge_winners_are_flagged_and_do_not_halt(emit, tmp_path):
    """
    A winner at the end of its row means the optimum may be outside the range.

    Worth reporting; not a reason to stop, because the run is still the best of
    what was tried.
    """
    for cell in agg_cells.screen_cells():
        score = 0.9 if cell["id"] == "eta_0p1" else 0.4
        for fold in (1, 2):
            _result(tmp_path, "d01_agg_", cell["id"], fold, score)
    assert emit.agg_full(DIGITS_STUDY01, tmp_path, tmp_path / "p12.txt", 85) == 0
    hits = (tmp_path / "tables" / "BOUNDARY_HITS.txt").read_text()
    assert "eta_0p1" in hits and "LOW end" in hits


def test_the_selector_is_still_parameterised_by_prefix(emit):
    """One selection rule, addressed at whichever study is being read."""
    prefixes = emit.prefixes(DIGITS_STUDY01)
    assert prefixes["agg_screen"] == "d01_agg_"
    assert prefixes["agg_full"] == "d01_aggfull_"
    # the regularisation path was added later and shares the same mechanism
    assert set(prefixes) >= {"agg_screen", "agg_full"}
    assert all(value.startswith(DIGITS_STUDY01.tag) for value in prefixes.values())


def test_the_readme_gives_the_exact_selection_command(p11):
    text = p11.readme(p11.lines())
    assert "tools/study_emit.py" in text and "agg-full" in text
    assert "--expect 85" in text
    assert "NOT AUTHORISED" in text


# the boundary extension of the trim row
# --------------------------------------------------------------------------- #


def test_the_extension_runs_the_screen_s_protocol(p11):
    from federated_outlier_adaptation.cli import build_parser

    parser = build_parser()
    for line in p11.ext_lines():
        args = parser.parse_args(shlex.split(line)[1:])
        assert args.classes == "digits" and args.rounds == 25
        assert args.clients_per_round == 9 and args.policy == "uniform"
        assert args.init == "global" and args.global_name == "g0"
        assert args.old_fold == "all"
        assert args.aggregation == "con_delta_trimmed_mean"
        assert args.outliers_file.endswith("cohort_worst10.json")
        assert args.fold_book.endswith("cohort10.foldbook.npz")


# --------------------------------------------------------------------------- #
# what the trimmed mean actually does at nine clients
# --------------------------------------------------------------------------- #
@pytest.mark.parametrize("fraction,survivors", [(0.1, 9), (0.2, 7), (0.3, 5), (0.4, 3)])
def test_how_many_updates_survive_each_trim_fraction(fraction, survivors):
    """
    ``trim = int(f * K)``, and the rule only bites when that is at least one.

    At nine clients ``int(0.1 * 9)`` is ZERO, so trim_frac=0.1 is not a trimmed
    mean at all - it is the plain coordinate-wise mean. The row the boundary
    rule saw was effectively [no trimming, drop one].
    """
    import torch

    from federated_outlier_adaptation.aggregation.concurrent_methods import (
        ServerState,
        con_delta_trimmed_mean,
    )

    K = 9
    assert K - 2 * int(fraction * K) == survivors or int(fraction * K) == 0
    if int(fraction * K) == 0:
        assert survivors == K

    # a coordinate whose extremes are outliers: the surviving count decides the mean
    values = [-100.0] + [1.0] * 7 + [100.0]
    globals_ = {"w": torch.zeros(1)}
    clients = [{"w": torch.tensor([v])} for v in values]
    state = ServerState(eta=1.0, trim_fraction=fraction)
    result = con_delta_trimmed_mean(globals_, clients, [1] * K, server_state=state)
    trim = int(fraction * K)
    kept = sorted(values)[trim: K - trim] if trim else sorted(values)
    assert len(kept) == survivors
    assert result["w"].item() == pytest.approx(sum(kept) / len(kept), abs=1e-4)


def test_a_half_fraction_is_not_reachable():
    """int(0.5 * 9) = 4 would leave one update, which is not a mean of anything."""
    from federated_outlier_adaptation.aggregation.concurrent_methods import ServerState

    with pytest.raises(ValueError, match=r"trim_fraction must lie in \[0, 0.5\)"):
        ServerState(trim_fraction=0.5)


def test_the_documented_survivor_counts_match_the_implementation(p11):
    assert p11.TRIM_SURVIVORS == {0.1: 9, 0.2: 7, 0.3: 5, 0.4: 3}
    assert p11.CLIENTS == DIGITS_STUDY01.clients_per_round == 9
    text = p11.ext_readme(p11.ext_lines())
    assert "is not a trimmed mean" in text
    assert "0.4 is the top of the row that can exist here" in text


# --------------------------------------------------------------------------- #
# the patch
# --------------------------------------------------------------------------- #
def _trim_results(root: Path, best: str):
    """Screen results where ``best`` is the strongest trimmed cell."""
    for cell in agg_cells.screen_cells():
        score = 0.9 if cell["id"] == best else 0.4
        for fold in (1, 2):
            _result(root, "d01_agg_", cell["id"], fold, score)


def test_the_patch_is_five_lines_not_ninety(emit, tmp_path):
    """
    One row widened, so at most one method's winner can move.

    Re-running the other seventeen would spend GPU time reproducing results
    whose inputs did not change.
    """
    _trim_results(tmp_path, "trimmed_t2")
    out = tmp_path / "patch.txt"
    assert emit.agg_trimmed_patch(DIGITS_STUDY01, tmp_path, out, 5) == 0
    lines = [l for l in out.read_text().splitlines() if l and not l.startswith("#")]
    assert len(lines) == 5
    assert all("trimmed_t2" in l for l in lines)


def test_the_patch_lines_are_the_full_horizon_with_p12_seeds(emit, tmp_path):
    """The patched lines and the ones they replace must be the same runs."""
    from federated_outlier_adaptation.cli import build_parser

    _trim_results(tmp_path, "trimmed_t3")
    out = tmp_path / "patch.txt"
    emit.agg_trimmed_patch(DIGITS_STUDY01, tmp_path, out, 5)

    full = tmp_path / "p12.txt"
    emit.agg_full(DIGITS_STUDY01, tmp_path, full, 90)

    parser = build_parser()
    patch = [
        parser.parse_args(shlex.split(l)[1:])
        for l in out.read_text().splitlines() if l and not l.startswith("#")
    ]
    p12 = [
        parser.parse_args(shlex.split(l)[1:])
        for l in full.read_text().splitlines() if l and not l.startswith("#")
    ]
    trimmed_in_p12 = [a for a in p12 if "trimmed_" in a.parent]
    assert len(patch) == len(trimmed_in_p12) == 5
    assert {a.rounds for a in patch} == {100}
    assert {a.sampler_seed for a in patch} == {a.sampler_seed for a in trimmed_in_p12}
    assert {a.fold for a in patch} == {1, 2, 3, 4, 5}


def test_the_patch_says_whether_the_winner_moved(emit, tmp_path, capsys):
    _trim_results(tmp_path, "trimmed_t1")
    emit.agg_full(DIGITS_STUDY01, tmp_path, tmp_path / "p12.txt", 85)
    capsys.readouterr()

    emit.agg_trimmed_patch(DIGITS_STUDY01, tmp_path, tmp_path / "patch.txt", 5)
    out = capsys.readouterr().out
    assert "UNCHANGED" in out
    record = json.loads(
        (tmp_path / "tables" / "p11ext_trimmed_reselection.json").read_text()
    )
    assert record["changed"] is False
    assert record["winner"] == record["previous_winner"] == "trimmed_t1"
    # The trim row is a row of counts now, not of fractions.
    assert record["row"] == [1, 2, 3]


def test_the_patch_reports_a_moved_winner(emit, tmp_path, capsys):
    """The first selection saw only the short row; the extension changes it."""
    for cell in agg_cells.screen_cells():
        if cell["id"].startswith("trimmed_t2") or cell["id"].startswith("trimmed_t3"):
            continue
        score = 0.9 if cell["id"] == "trimmed_t1" else 0.4
        for fold in (1, 2):
            _result(tmp_path, "d01_agg_", cell["id"], fold, score)
    emit.agg_full(DIGITS_STUDY01, tmp_path, tmp_path / "p12.txt", 85)
    capsys.readouterr()

    # now the extension lands, and 0.4 wins
    for fold in (1, 2):
        _result(tmp_path, "d01_agg_", "trimmed_t3", fold, 0.99)
    emit.agg_trimmed_patch(DIGITS_STUDY01, tmp_path, tmp_path / "patch.txt", 5)

    out = capsys.readouterr().out
    assert "CHANGED" in out
    record = json.loads(
        (tmp_path / "tables" / "p11ext_trimmed_reselection.json").read_text()
    )
    assert record["previous_winner"] == "trimmed_t1"
    assert record["winner"] == "trimmed_t3" and record["changed"] is True
    # 0.4 is the high edge of the widened row - a genuine finding, still flagged
    assert any("HIGH end" in h for h in record["boundary_hits"])


def test_the_patch_is_stamped_unauthorised(emit, tmp_path):
    _trim_results(tmp_path, "trimmed_t2")
    out = tmp_path / "patch.txt"
    emit.agg_trimmed_patch(DIGITS_STUDY01, tmp_path, out, 5)
    assert "NOT AUTHORISED" in out.read_text()


def test_a_patch_miscount_halts(emit, tmp_path):
    _trim_results(tmp_path, "trimmed_t2")
    assert emit.agg_trimmed_patch(
        DIGITS_STUDY01, tmp_path, tmp_path / "patch.txt", 90
    ) == 1


