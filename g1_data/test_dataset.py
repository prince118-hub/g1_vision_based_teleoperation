"""What the dataset loader must REFUSE, proved by building bad datasets on purpose.

The three refusals are the ones that would otherwise produce a result that looks
fine and is wrong: mixed SPEC_VERSIONs (the arrays stop meaning the same thing),
mixed contact contracts (D18 - half the episodes lived in different physics), and
a held-out spawn in the training set (the Objective 4 guarantee). Each RAISES.
A warning here would be read once, on the day it was written, and never again.

    python g1_data/test_dataset.py
"""
from __future__ import annotations

import json
import os
import shutil
import subprocess
import sys
import tempfile

import numpy as np

sys.path.insert(0, os.path.dirname(os.path.dirname(os.path.abspath(__file__))))

from g1_data import dataset as DS
from g1_data import spec


def _raises(exc, fn, *a, **k):
    try:
        fn(*a, **k)
    except exc as e:
        return e
    raise AssertionError("%s did not raise %s" % (getattr(fn, "__name__", fn),
                                                  exc.__name__))


def _ep(seed, version=spec.SPEC_VERSION, contract="bprime", spawn=(1.50, -0.10)):
    """An Episode with only the metadata the checks read - no arrays needed."""
    return DS.Episode("mem://seed%d.npz" % seed,
                      dict(seed=seed, spec_version=version,
                           contact_contract=contract, box_spawn_xy=list(spawn)))


def _fake_episode_files(n):
    """(tmpdir, [Episode]) - `n` real staged episodes copied under fresh seeds.

    Real files, because `fit_norm_stats` loads the arrays: the metadata-only
    `_ep` above is enough for the refusal checks and not for this one. Returns
    None when nothing is staged, so the caller can skip rather than fail.
    """
    src = sorted(p for p in DS._npz(DS.SYNTHETIC))
    if len(src) < n:
        return None
    tmp = tempfile.mkdtemp()
    eps = []
    for i, p in enumerate(src[:n]):
        dst = os.path.join(tmp, "ep%d.npz" % i)
        shutil.copy2(p, dst)
        eps.append(DS.Episode(dst, DS.read_meta(dst)))
    return tmp, eps


def test_uniform_dataset_passes():
    DS.assert_uniform([_ep(0), _ep(1), _ep(2)])


def test_mixed_spec_version_raises():
    e = _raises(DS.DatasetError, DS.assert_uniform,
                [_ep(0), _ep(1, version="g1-spec-1.0.0")])
    assert "SPEC_VERSION" in str(e)
    assert "g1-spec-1.0.0" in str(e) and spec.SPEC_VERSION in str(e)


def test_uniform_but_wrong_spec_version_raises():
    # All agree with each other and all disagree with the code: still refused.
    _raises(AssertionError, DS.assert_uniform,
            [_ep(0, version="g1-spec-1.0.0"), _ep(1, version="g1-spec-1.0.0")])


def test_mixed_contact_contract_raises():
    e = _raises(DS.DatasetError, DS.assert_uniform,
                [_ep(0, contract="bprime"), _ep(1, contract="full")])
    assert "contact contract" in str(e) and "D18" in str(e)


def test_missing_contract_counts_as_a_different_contract():
    a, b = _ep(0), _ep(1)
    b.meta.pop("contact_contract")
    _raises(DS.DatasetError, DS.assert_uniform, [a, b])


def _ep_demo(seed, demonstrator):
    e = _ep(seed)
    if demonstrator is not None:
        e.meta["demonstrator"] = dict(demonstrator)
    return e


def test_uniform_demonstrator_settings_pass():
    A = dict(hold_max=0.80, reposition_s=0.5)
    DS.assert_uniform_demonstrator([_ep_demo(0, A), _ep_demo(1, A)])
    # No demonstrator at all (teleop, or recorded before the field): uniform.
    DS.assert_uniform_demonstrator([_ep_demo(0, None), _ep_demo(1, None)])


def test_mixed_demonstrator_settings_raise():
    e = _raises(DS.DatasetError, DS.assert_uniform_demonstrator,
                [_ep_demo(0, dict(hold_max=0.80, reposition_s=0.5)),
                 _ep_demo(1, dict(hold_max=0.40, reposition_s=0.5))])
    assert "0.8" in str(e) and "0.4" in str(e)


def test_partial_demonstrator_settings_raise():
    """Some episodes say which settings produced them and some cannot."""
    e = _raises(DS.DatasetError, DS.assert_uniform_demonstrator,
                [_ep_demo(0, dict(hold_max=0.80, reposition_s=0.5)),
                 _ep_demo(1, None)])
    assert "NO demonstrator settings" in str(e)


ROOT = os.path.dirname(os.path.dirname(os.path.abspath(__file__)))


def _good_episode_file():
    src = sorted(DS._npz(DS.SYNTHETIC))
    return src[0] if src else None


def failed_copy(good, dst):
    """A FAILED episode, made from a good one: what seed 25 was on 2026-10-17
    (demonstrator ok=False, placement 0.1087 m). The real file
    (recordings/scripted_v1_rejected/ep_seed0025.npz) is spec 1.1.0 and this
    build refuses it before any success check could run, so the failure is
    reproduced in BOTH places the checks read: the demonstrator's verdict in
    the metadata, and the trajectory (final box 0.35 m off the goal)."""
    from g1_data import success as SU
    with np.load(good, allow_pickle=False) as z:
        arrays = {k: z[k] for k in z.files if k != "meta"}
        meta = json.loads(str(z["meta"]))
    arrays, meta = SU.sabotage(arrays, meta, "placement_out")
    meta["outcome"] = dict(meta.get("outcome") or {}, ok=False, fail_phase="PLACE(upright)",
                           placement_error=0.1087)
    meta["seed"] = 25
    np.savez_compressed(dst, meta=np.array(json.dumps(meta)), **arrays)
    return dst


def _copy_with_meta(src, dst, drop=(), **meta_updates):
    """Copy an episode, rewriting only its metadata."""
    with np.load(src, allow_pickle=False) as z:
        arrays = {k: z[k] for k in z.files if k != "meta"}
        meta = json.loads(str(z["meta"]))
    for k in drop:
        meta.pop(k, None)
    meta.update(meta_updates)
    np.savez_compressed(dst, meta=np.array(json.dumps(meta)), **arrays)
    return DS.Episode(dst, meta)


def test_failed_scripted_episode_is_refused_by_name():
    """Seed 25 (demonstrator FAIL, placement 0.1087 m) was accepted by mistake
    on 2026-10-17. A copy of it must be refused, named, and a good episode
    beside it must not be blamed."""
    good = _good_episode_file()
    if not good:
        print("      (skipped: needs a staged episode)")
        return
    tmp = tempfile.mkdtemp()
    try:
        failed_copy(good, os.path.join(tmp, "ep_seed0025.npz"))
        _copy_with_meta(good, os.path.join(tmp, "ep_seed0100.npz"), seed=100)
        eps = [DS.Episode(p, DS.read_meta(p)) for p in sorted(DS._npz(tmp))]
        e = _raises(DS.DatasetError, DS.assert_successful, eps)
        assert "ep_seed0025.npz" in str(e) and "ep_seed0100.npz" not in str(e)
        assert "demonstrator ok=False" in str(e) and "0.1087" in str(e)
        # And build_dataset split refuses it, writing no split file.
        out = os.path.join(tmp, "splits.json")
        r = subprocess.run([sys.executable, os.path.join(ROOT, "tools", "build_dataset.py"),
                            "split", "--episodes", tmp, "--splits", out],
                           capture_output=True, text=True)
        assert r.returncode != 0 and "ep_seed0025.npz" in (r.stdout + r.stderr)
        assert not os.path.exists(out)
    finally:
        shutil.rmtree(tmp, ignore_errors=True)


def test_human_episode_success_is_computed_from_the_trajectory():
    """A non-scripted episode stores no verdict; success.evaluate decides."""
    good = _good_episode_file()
    if not good:
        print("      (skipped: needs a staged episode)")
        return
    from g1_data import recorder as REC
    tmp = tempfile.mkdtemp()
    try:
        bad = _copy_with_meta(failed_copy(good, os.path.join(tmp, "f.npz")),
                              os.path.join(tmp, "ep_seed0025.npz"),
                              drop=("outcome",), source=REC.SOURCE_TELEOP_FIXTURE)
        ok = _copy_with_meta(good, os.path.join(tmp, "ep_seed0100.npz"),
                             drop=("outcome",), source=REC.SOURCE_TELEOP_FIXTURE)
        assert DS.episode_success(ok)[0], DS.episode_success(ok)
        e = _raises(DS.DatasetError, DS.assert_successful, [ok, bad])
        assert "ep_seed0025.npz" in str(e) and "success criteria failed" in str(e)
    finally:
        shutil.rmtree(tmp, ignore_errors=True)


def test_scripted_episode_without_an_outcome_is_refused():
    from g1_data import recorder as REC
    e = _ep(7)
    e.meta["source"] = REC.SOURCE_SCRIPTED
    ok, why = DS.episode_success(e)
    assert not ok and "no demonstrator outcome" in why


def test_heldout_spawn_in_training_raises():
    from g1_teleop.config import TeleopConfig
    cfg = TeleopConfig().box
    inside = (float(np.mean(cfg.heldout_x)), float(np.mean(cfg.heldout_y)))
    e = _raises(DS.DatasetError, DS.assert_no_leak, [_ep(0), _ep(7, spawn=inside)])
    assert "HELD-OUT" in str(e) and "7" in str(e)


def test_clean_training_set_passes_the_leak_check():
    DS.assert_no_leak([_ep(0), _ep(1, spawn=(1.46, -0.18))])


def test_raw_heldout_directory_must_be_empty():
    """The emptiness of data/raw/heldout IS the leak check, so a file in it fails."""
    real = DS.RAW_HELDOUT
    tmp = tempfile.mkdtemp()
    try:
        DS.RAW_HELDOUT = tmp
        DS.assert_no_leak([_ep(0)])                    # empty: passes
        np.savez(os.path.join(tmp, "leaked.npz"), x=np.zeros(1))
        e = _raises(DS.DatasetError, DS.assert_no_leak, [_ep(0)])
        assert "not empty" in str(e)
    finally:
        DS.RAW_HELDOUT = real
        shutil.rmtree(tmp, ignore_errors=True)


def test_partition_streams_are_disjoint_and_correctly_sided():
    from g1_teleop.box_reset import in_heldout, sample_box_pose
    from g1_teleop.config import TeleopConfig
    cfg = TeleopConfig().box
    p = DS.partition_seeds(n_train=30, n_exp1=10, n_exp2=10, n_select=5, n_train_ext=7)
    tr, e1, e2, sel = set(p["train"]), set(p["exp1"]), set(p["exp2"]), set(p["select"])
    assert len(tr) == 37 and len(e1) == 10 and len(e2) == 10 and len(sel) == 5
    # open item 38: selection overlaps nothing, and comes AFTER the three streams
    assert not (sel & (tr | e1 | e2)), "checkpoint selection must use its own seeds"
    assert min(sel) >= p["original_end"] and min(p["train"][30:]) > max(sel)
    for s in sel:
        assert not in_heldout(sample_box_pose(cfg, s)[0][:2], cfg)
    # extending changes nothing already issued
    q = DS.partition_seeds(n_train=30, n_exp1=10, n_exp2=10, n_select=0, n_train_ext=0)
    assert q["train"] == p["train"][:30] and q["exp1"] == p["exp1"] and q["exp2"] == p["exp2"]
    assert not (tr & e2), "collection stream overlaps the held-out patch"
    assert not (tr & e1), "D16: Exp 1 seeds must be FRESH, not collection spawns"
    assert not (e1 & e2)
    for s in tr | e1:
        assert not in_heldout(sample_box_pose(cfg, s)[0][:2], cfg)
    for s in e2:
        assert in_heldout(sample_box_pose(cfg, s)[0][:2], cfg)


def test_seed_files_on_disk_are_the_partition():
    """data/eval/*.json are exactly `partition_seeds()`: the first 200 training
    seeds, exp1 and exp2 are the streams issued since 2026-09-11, and the 20
    selection seeds sit above 678, in no other stream (open item 38)."""
    p = DS.partition_seeds()
    for key in ("train", "exp1", "exp2", "select"):
        assert DS.load_seed_file(os.path.join(DS.EVAL, "%s_seeds.json" % key)) == p[key], key
    assert p["train"][:200] == list(DS.partition_seeds(n_select=0, n_train_ext=0)["train"])
    assert min(p["select"]) > 678 and len(p["select"]) == 20 and len(p["train"]) == 300
    assert DS.SELECT_SEEDS.endswith("select_seeds.json")


def test_grip_label_guard():
    """Open item 29: a dataset of unlabelled episodes, or of mixed labels, is
    refused, naming the groups; a uniformly labelled one passes."""
    def lab(seed, label):
        e = _ep(seed)
        if label is not None:
            e.meta["grip_label"] = label
        return e
    DS.assert_uniform_grip_label([lab(0, spec.GRIP_LABEL), lab(1, spec.GRIP_LABEL)])
    e = _raises(DS.DatasetError, DS.assert_uniform_grip_label, [lab(0, None), lab(1, None)])
    assert "NO grip_label" in str(e) and "convert_grip_label" in str(e)
    e = _raises(DS.DatasetError, DS.assert_uniform_grip_label,
                [lab(0, spec.GRIP_LABEL), lab(1, None)])
    assert "NO grip_label" in str(e) and spec.GRIP_LABEL in str(e)
    _raises(DS.DatasetError, DS.assert_uniform_grip_label,
            [lab(0, spec.GRIP_LABEL), lab(1, "some_other_v9")])


def test_grip_label_guard_is_wired_into_split_norm_and_the_loader():
    import inspect
    sys.path.insert(0, os.path.join(ROOT, "tools"))
    import build_dataset as BD
    from g1_model.loader import ChunkDataset
    for fn in (BD.cmd_split, BD.cmd_norm, ChunkDataset.__init__):
        assert "assert_uniform_grip_label" in inspect.getsource(fn), fn.__qualname__


def test_split_is_exactly_80_20_and_covers_every_bin():
    eps = []
    for i in range(150):                       # the planned collection size
        x = 1.44 + 0.12 * ((i % 10) / 9.0)
        y = -0.21 + 0.42 * (((i // 10) % 15) / 14.0)
        eps.append(_ep(i, spawn=(x, y)))
    sp = DS.stratified_split(eps)
    assert len(sp["train"]) + len(sp["val"]) == 150
    assert len(sp["val"]) == 30, sp["val"]      # exactly 20%, not 4% (the carry)
    assert not set(sp["train"]) & set(sp["val"])
    assert len(sp["bins"]) == 9 and not sp["bins_without_val"]


def _grid_eps(n):
    return [_ep(i, spawn=(1.44 + 0.12 * ((i % 10) / 9.0),
                          -0.21 + 0.42 * (((i // 10) % 20) / 19.0))) for i in range(n)]


def test_nested_split_is_a_stratified_subset_with_the_same_val():
    """`nested_split`: exactly n_train seeds, all from the parent's train, the
    parent's val untouched, every bin represented in proportion (within 1),
    deterministic, and nested again it stays inside the first subset."""
    eps = _grid_eps(200)
    parent = DS.stratified_split(eps)
    assert len(parent["train"]) == 160 and len(parent["val"]) == 40
    sub = DS.nested_split(parent, eps, 40, parent_path="p.json")
    assert len(sub["train"]) == 40 == len(set(sub["train"]))
    assert set(sub["train"]) <= set(parent["train"])
    assert sub["val"] == parent["val"] and not set(sub["train"]) & set(sub["val"])
    assert sub["nested_from"] == dict(path="p.json", n_train=160,
                                      spec_version=spec.SPEC_VERSION)
    ptrain = set(parent["train"])
    for cell, seeds in parent["bins"].items():
        n_parent = len([s for s in seeds if s in ptrain])
        assert abs(len(sub["bins"].get(cell, [])) - n_parent * 40 / 160.0) <= 1.0, cell
    assert DS.nested_split(parent, list(reversed(eps)), 40) == DS.nested_split(parent, eps, 40)
    mid = DS.nested_split(parent, eps, 80)
    inner = DS.nested_split(mid, eps, 40)
    assert set(inner["train"]) <= set(mid["train"]) <= ptrain and inner["val"] == parent["val"]


def test_nested_split_refuses_a_bad_size_or_missing_episodes():
    eps = _grid_eps(50)
    parent = DS.stratified_split(eps)
    _raises(DS.DatasetError, DS.nested_split, parent, eps, 0)
    _raises(DS.DatasetError, DS.nested_split, parent, eps, len(parent["train"]))
    e = _raises(DS.DatasetError, DS.nested_split, parent, eps[:30], 10)
    assert "not among the episodes" in str(e)


def test_split_is_deterministic():
    eps = [_ep(i, spawn=(1.44 + 0.012 * (i % 10), -0.2 + 0.04 * (i // 10)))
           for i in range(40)]
    assert DS.stratified_split(eps) == DS.stratified_split(list(reversed(eps)))


def test_norm_stats_refuse_synthetic_by_default():
    """Fitting statistics on the demonstrator has to be a deliberate act."""
    e = _ep(0)
    e.meta["source"] = "scripted_demo"
    err = _raises(DS.DatasetError, DS.fit_norm_stats, [e], "train")
    assert "scripted" in str(err) or "synthetic" in str(err)
    _raises(DS.DatasetError, DS.fit_norm_stats, [], "train")


def test_norm_stats_split_must_be_stated():
    """A3: `split` was the literal "train" regardless of what was handed in, so
    a normalizer fitted on everything in a directory came out labelled "train"
    and nothing could tell. It is now the caller's explicit claim."""
    import inspect
    sig = inspect.signature(DS.fit_norm_stats).parameters["split"]
    assert sig.default is inspect.Parameter.empty, "split must have no default"
    e = _ep(0)
    e.meta["source"] = "scripted_demo"
    for bad in ("", None):
        err = _raises(DS.DatasetError, DS.fit_norm_stats, [e], bad)
        assert "split" in str(err).lower()


def test_norm_stats_carry_seed_provenance_and_it_is_checked():
    """A3: seeds, date and commit are written, and a normalizer fitted on a
    DIFFERENT episode set is refused rather than loaded silently."""
    eps = _fake_episode_files(3)
    if eps is None:
        print("      (skipped: nothing staged in data/synthetic)")
        return
    tmp, eps = eps
    try:
        st, ac, rep = DS.fit_norm_stats(eps, "train", allow_synthetic=True)
        assert rep["seeds"] == sorted(e.seed for e in eps)
        assert rep["split"] == "train" and st.split == "train"
        path = os.path.join(tmp, "norm.npz")
        DS.save_norm_stats(st, ac, path=path, source=rep["source"],
                           n_episodes=rep["n_episodes"], seeds=rep["seeds"],
                           split=rep["split"])
        _, _, meta = DS.load_norm_stats(path)
        for field in ("seeds", "fitted_utc", "git_commit", "split", "source"):
            assert field in meta, field
        assert meta["seeds"] == sorted(e.seed for e in eps)
        # matching set: silent
        DS.assert_norm_stats_match(meta, eps)
        # one episode short, and one episode extra: both refused, by SEED
        err = _raises(DS.DatasetError, DS.assert_norm_stats_match, meta, eps[:-1])
        assert "NOT in the dataset" in str(err)
        err = _raises(DS.DatasetError, DS.assert_norm_stats_match,
                      meta, list(eps) + [_ep(999)])
        assert "999" in str(err)
        # stats predating the provenance fields are refused, not waved through
        old = {k: v for k, v in meta.items() if k != "seeds"}
        err = _raises(DS.DatasetError, DS.assert_norm_stats_match, old, eps)
        assert "provenance" in str(err)
    finally:
        shutil.rmtree(tmp, ignore_errors=True)


def _rewrite_norm_meta(path, **changes):
    """Rewrite a stats file's metadata; a value of None removes the key."""
    with np.load(path, allow_pickle=False) as z:
        arrays = {k: z[k] for k in z.files if k != "meta"}
        meta = json.loads(str(z["meta"]))
    for k, v in changes.items():
        if v is None:
            meta.pop(k, None)
        else:
            meta[k] = v
    np.savez(path, meta=np.array(json.dumps(meta)), **arrays)


def test_norm_stats_store_the_std_floor_and_refuse_a_different_one():
    """O33 (2026-10-17): the floor changed without a SPEC_VERSION bump, so the
    file carries it and loading checks it. Missing or different: refused."""
    eps = _fake_episode_files(3)
    if eps is None:
        print("      (skipped: nothing staged in data/synthetic)")
        return
    tmp, eps = eps
    try:
        st, ac, rep = DS.fit_norm_stats(eps, "train", allow_synthetic=True)
        path = os.path.join(tmp, "norm.npz")
        DS.save_norm_stats(st, ac, path=path, source=rep["source"],
                           n_episodes=rep["n_episodes"], seeds=rep["seeds"],
                           split=rep["split"])
        _, _, meta = DS.load_norm_stats(path)
        assert meta["std_floor"] == spec.NormStats.STD_FLOOR == 1e-2
        _rewrite_norm_meta(path, std_floor=1e-6)            # fitted under the old floor
        e = _raises(DS.DatasetError, DS.load_norm_stats, path)
        assert "1e-06" in str(e) and "0.01" in str(e)
        _rewrite_norm_meta(path, std_floor=None)            # predates the field
        e = _raises(DS.DatasetError, DS.load_norm_stats, path)
        assert "std_floor" in str(e)
    finally:
        shutil.rmtree(tmp, ignore_errors=True)


def test_repo_relpath_survives_a_cross_drive_path():
    """A1: `os.path.relpath` raises across Windows drive letters, and the fix had
    been written three times separately. One helper, and a test that proves it is
    exercising the guarded branch rather than passing because the branch is never
    reached: the raw call on the SAME inputs must raise where the helper does not.

    No second physical drive needed - relpath is string arithmetic and neither
    path has to exist.
    """
    from g1_data.paths import ROOT, repo_relpath
    other = "Z:\\scratch\\ep_seed0000.npz" if os.name == "nt" \
        else "/mnt/other/ep_seed0000.npz"

    got = repo_relpath(other)
    assert isinstance(got, str) and got, got

    if os.name != "nt":
        # POSIX has no drive letters: relpath cannot raise, and a path outside
        # the repo legitimately comes back as "../..". What must hold there is
        # that it still names the same file.
        assert os.path.normpath(os.path.join(ROOT, got)) == os.path.abspath(other), got
    else:
        assert os.path.isabs(got) or not got.startswith(".."), got
    if os.name == "nt":
        # the guarded branch is real on this platform, and IS the branch taken
        _raises(ValueError, os.path.relpath, other, ROOT)   # relpath-ok: the point
        assert got == os.path.abspath(other)
    # a same-drive path still comes back short and relative, as every caller wants
    inside = os.path.join(ROOT, "data", "synthetic", "ep_seed0000.npz")
    assert repo_relpath(inside) == os.path.join("data", "synthetic",
                                                "ep_seed0000.npz")
    # total: no input raises
    for p in ("", ".", "relative/bit", ROOT, other):
        assert isinstance(repo_relpath(p), str)


def test_every_relpath_call_site_goes_through_the_helper():
    """A1: three copies of one fix is this repo's characteristic bug, so the
    next site reaching for the raw call is visible here rather than in a
    crash report months later.

    Parsed, not grepped: this file and `paths.py` both DISCUSS the raw call in
    prose, and a text scan cannot tell a docstring from a use - the same false
    positive the loader's B7 test hit.
    """
    import ast
    import g1_data.paths as PATHS
    from g1_data.paths import repo_relpath
    root = os.path.dirname(os.path.dirname(os.path.abspath(__file__)))
    offenders = []
    for base, dirs, files in os.walk(root):
        dirs[:] = [d for d in dirs
                   if d not in ("__pycache__", ".git", "unitree_rl_gym",
                                "venv", ".venv", "build", "dist")]
        for fn in files:
            if not fn.endswith(".py"):
                continue
            p = os.path.join(base, fn)
            if os.path.abspath(p) == os.path.abspath(PATHS.__file__):
                continue                       # the one legitimate home
            src = open(p, encoding="utf-8", errors="replace").read()
            try:
                tree = ast.parse(src)
            except SyntaxError:
                continue                       # not importable anyway
            lines = src.splitlines()
            for node in ast.walk(tree):
                # os.path.relpath(...) is Attribute(Attribute(Name(os),path),relpath)
                if not (isinstance(node, ast.Attribute)
                        and node.attr == "relpath"):
                    continue
                v = node.value
                if not (isinstance(v, ast.Attribute) and v.attr == "path"
                        and isinstance(v.value, ast.Name) and v.value.id == "os"):
                    continue
                line = lines[node.lineno - 1] if node.lineno <= len(lines) else ""
                # `# relpath-ok: <why>` is the deliberate-use escape hatch: a
                # site that really does want the raw call says so where a reader
                # sees it, rather than the whole file being exempted and the
                # next unguarded call in it going unnoticed.
                if "relpath-ok" in line:
                    continue
                offenders.append("%s:%d" % (repo_relpath(p, root), node.lineno))
    assert not offenders, (
        "these call the raw relpath directly instead of "
        "`g1_data.paths.repo_relpath`, and will crash across drive letters: %s"
        % offenders)


def test_per_tick_arrays_must_agree_on_length():
    """A1: equal lengths were guaranteed by construction in EpisodeBuffer and
    checked nowhere, so a file from an older or external path could pair
    state[t] with action[t+1] and nothing would say so."""
    from g1_data import recorder as REC
    base = dict(states=np.zeros((5, 47)), actions=np.zeros((5, 22)),
                phase_labels=np.zeros(5, dtype=np.int8),
                gait_phase=np.zeros((5, 2)), qpos=np.zeros((5, 45)),
                qvel=np.zeros((5, 43)), step_index=np.arange(5) * 20)
    assert REC.assert_tick_lengths(base, dict(n_ticks=5)) == 5

    short = dict(base, actions=np.zeros((4, 22)))
    e = _raises(REC.EpisodeLengthError, REC.assert_tick_lengths, short,
                dict(n_ticks=5))
    assert "actions" in str(e) and "4" in str(e) and "5" in str(e)

    e = _raises(REC.EpisodeLengthError, REC.assert_tick_lengths, base,
                dict(n_ticks=9))
    assert "9" in str(e) and "5" in str(e)

    _raises(REC.EpisodeLengthError, REC.assert_tick_lengths, base, dict())

    missing = {k: v for k, v in base.items() if k != "qvel"}
    e = _raises(REC.EpisodeLengthError, REC.assert_tick_lengths, missing,
                dict(n_ticks=5))
    assert "qvel" in str(e)

    # tracking_ok is optional, but checked when present
    REC.assert_tick_lengths(dict(base, tracking_ok=np.ones(5, dtype=np.uint8)),
                            dict(n_ticks=5))
    e = _raises(REC.EpisodeLengthError, REC.assert_tick_lengths,
                dict(base, tracking_ok=np.ones(3, dtype=np.uint8)),
                dict(n_ticks=5))
    assert "tracking_ok" in str(e)


def test_length_check_runs_on_load_not_just_on_demand():
    """A1 is only worth having if it fires on the path episodes arrive by."""
    from g1_data import recorder as REC
    src = sorted(p for p in DS._npz(DS.SYNTHETIC))
    if not src:
        print("      (skipped: nothing staged in data/synthetic)")
        return
    tmp = tempfile.mkdtemp()
    try:
        dst = os.path.join(tmp, "truncated.npz")
        with np.load(src[0], allow_pickle=False) as z:
            arrays = {k: z[k] for k in z.files}
        REC.load_episode(src[0])                            # intact: loads
        arrays["actions"] = arrays["actions"][:-1]          # drop one tick
        np.savez(dst, **arrays)
        e = _raises(REC.EpisodeLengthError, REC.load_episode, dst)
        assert "actions" in str(e) and "truncated.npz" in str(e)
    finally:
        shutil.rmtree(tmp, ignore_errors=True)


def test_staged_episodes_all_pass_the_length_check():
    """The guard must be a no-op on all 40 episodes already collected."""
    from g1_data import recorder as REC
    eps = DS.scan(DS.SYNTHETIC)
    if not eps:
        print("      (skipped: nothing staged in data/synthetic)")
        return
    for e in eps:
        arrays, meta = e.load()                             # raises on mismatch
        n = REC.assert_tick_lengths(arrays, meta,
                                    where=os.path.basename(e.path))
        assert n == int(meta["n_ticks"])
        assert REC.tracking_measured(arrays) is False       # all on the default


def test_real_files_on_disk_are_refused_when_mixed():
    """The same two refusals, end to end through `scan`, on real episode files.

    The in-memory tests above call the checks directly; this one goes through the
    path a collection run actually takes - read the .npz, parse its metadata,
    scan the directory - so a refusal that only works on hand-built dicts would
    show up here.
    """
    src = sorted(p for p in DS._npz(DS.SYNTHETIC))
    if len(src) < 2:
        print("      (skipped: needs 2 staged episodes in data/synthetic)")
        return
    tmp = tempfile.mkdtemp()
    try:
        good = []
        for i, p in enumerate(src[:2]):
            dst = os.path.join(tmp, "ep%d.npz" % i)
            shutil.copy2(p, dst)
            good.append(dst)
        assert len(DS.scan(tmp)) == 2                       # uniform: accepted

        def _patch(path, **fields):
            with np.load(path, allow_pickle=False) as z:
                arrays = {k: z[k] for k in z.files}
            meta = json.loads(str(arrays["meta"]))
            meta.update(fields)
            arrays["meta"] = np.asarray(json.dumps(meta))
            np.savez(path, **arrays)

        _patch(good[1], spec_version="g1-spec-1.0.0")
        e = _raises(DS.DatasetError, DS.scan, tmp)
        assert "SPEC_VERSION" in str(e)

        _patch(good[1], spec_version=spec.SPEC_VERSION,
               contact_contract="full-contact-no-bprime")
        e = _raises(DS.DatasetError, DS.scan, tmp)
        assert "contact contract" in str(e)
    finally:
        shutil.rmtree(tmp, ignore_errors=True)


# ─── the provenance and velocity guards (decision audit, 2026-09-16) ──────────
def test_every_registered_source_declares_whether_it_is_real():
    from g1_data import recorder as REC
    assert REC.SOURCES, "the registry must not be empty"
    for src, info in REC.SOURCES.items():
        assert isinstance(src, str) and src
        assert set(info) == {"label", "real"}, info
        assert isinstance(info["real"], bool)
    # Exactly ONE source produces real demonstrations: the live recorder with
    # the camera (tools/record_teleop_live.py, 2026-10-22). Its fake-camera mode
    # is a separate, non-real source, so a dry run can never route into training.
    real = sorted(s for s, i in REC.SOURCES.items() if i["real"])
    assert real == [REC.SOURCE_TELEOP_LIVE], real
    assert REC.SOURCES[REC.SOURCE_TELEOP_LIVE_FAKE]["real"] is False


def test_unknown_source_is_refused_not_guessed():
    from g1_data import recorder as REC
    e = _raises(REC.UnknownSource, REC.source_info, "brand_new_tool.py",
                where="ep_seed0007.npz")
    assert "brand_new_tool.py" in str(e) and "ep_seed0007.npz" in str(e)
    _raises(REC.UnknownSource, REC.source_info, None)
    _raises(REC.UnknownSource, REC.label_of, "")


def test_label_is_derived_from_source():
    from g1_data import recorder as REC
    assert REC.label_of(REC.SOURCE_SCRIPTED) == "scripted"
    assert REC.label_of(REC.SOURCE_TELEOP_FIXTURE) == "teleop-fixture"


def test_velocity_guard_refuses_an_out_of_clip_command():
    """The D15 guard the recorder now calls on every tick."""
    rail = np.array([0.80, 0.80, 0.60], dtype=np.float32).astype(np.float64)
    spec.assert_velocity_within_clip(rail)                    # must not raise
    for dim, over in ((0, [0.81, 0.0, 0.0]), (1, [0.0, 0.81, 0.0]),
                      (2, [0.0, 0.0, 0.61])):
        e = _raises(AssertionError, spec.assert_velocity_within_clip,
                    np.asarray(over), where="tick 42")
        assert "tick 42" in str(e)


def test_staged_episodes_all_pass_both_guards():
    """The guards must be no-ops on the data already collected."""
    from g1_data import recorder as REC
    eps = DS.scan(DS.SYNTHETIC)
    if not eps:
        print("      (skipped: nothing staged in data/synthetic)")
        return
    for e in eps:
        REC.source_info(e.meta.get("source"), where=os.path.basename(e.path))
        arrays, _ = e.load()
        spec.assert_velocity_within_clip(
            np.asarray(arrays["actions"][:, spec.VEL_A], dtype=np.float64),
            where=os.path.basename(e.path))


def test_namespaces_are_separate_and_each_owns_its_ledger():
    from g1_data import recorder as REC
    assert REC.NS_SCRIPTED != REC.NS_COLLECTION
    assert REC.NAMESPACES[REC.NS_SCRIPTED]["real"] is False
    assert REC.NAMESPACES[REC.NS_COLLECTION]["real"] is True
    # The ledger is derived from the directory, so the two can never be paired
    # wrongly - that pairing is what silently skipped 40 of 200 training seeds.
    assert REC.ledger_for(REC.NS_SCRIPTED) != REC.ledger_for(REC.NS_COLLECTION)
    for ns in (REC.NS_SCRIPTED, REC.NS_COLLECTION):
        assert os.path.dirname(REC.ledger_for(ns)) == os.path.abspath(ns)


def test_scripted_source_refused_in_the_collection_namespace():
    from g1_data import recorder as REC
    e = _raises(REC.NamespaceMismatch, REC.assert_namespace,
                REC.NS_COLLECTION, REC.SOURCE_SCRIPTED)
    assert "demonstrations" in str(e) and REC.SOURCE_SCRIPTED in str(e)
    # and the reverse: a real demonstration may not land in the scripted tree
    REC.SOURCES["__test_real__"] = dict(label="test-real", real=True)
    try:
        e = _raises(REC.NamespaceMismatch, REC.assert_namespace,
                    REC.NS_SCRIPTED, "__test_real__")
        assert "episodes" in str(e)
    finally:
        del REC.SOURCES["__test_real__"]


def test_unregistered_directory_is_allowed():
    """Ad-hoc output dirs are fine: staging routes on source, so an
    unregistered directory cannot smuggle anything into a training split."""
    from g1_data import recorder as REC
    assert REC.namespace_info(tempfile.gettempdir()) is None
    REC.assert_namespace(tempfile.gettempdir(), REC.SOURCE_SCRIPTED)


def test_collection_ledger_does_not_inherit_the_scripted_accepts():
    """The A4 failure case, as a test."""
    from g1_data.ledger import EpisodeLedger
    tmp = tempfile.mkdtemp()
    try:
        old = EpisodeLedger(os.path.join(tmp, "scripted", "ledger.jsonl"))
        for seed in range(5):
            old.append("accept", seed=seed, path="x.npz", heldout=False,
                       label="scripted", checks={}, placement_error=0.0)
        new = EpisodeLedger(os.path.join(tmp, "demonstrations", "ledger.jsonl"))
        stream = list(range(8))
        assert old.pending(stream) == [5, 6, 7], "shared ledger skips 0-4"
        assert new.pending(stream) == stream, "separate ledger issues every seed"
    finally:
        shutil.rmtree(tmp, ignore_errors=True)


def _tests():
    return [(n, f) for n, f in sorted(globals().items())
            if n.startswith("test_") and callable(f)]


if __name__ == "__main__":
    failed = 0
    for name, fn in _tests():
        try:
            fn()
        except Exception as e:                              # noqa: BLE001
            failed += 1
            print("FAIL  %s\n        %s: %s" % (name, type(e).__name__, e))
        else:
            print("ok    %s" % name)
    print("\n%d/%d passed" % (len(_tests()) - failed, len(_tests())))
    raise SystemExit(1 if failed else 0)
