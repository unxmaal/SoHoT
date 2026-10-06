"""Issue #61: read a candidate's source before downloading its weights."""
import pytest

from harness import inspect as ins


def tree(tmp_path, files: dict):
    for rel, text in files.items():
        p = tmp_path / rel
        p.parent.mkdir(parents=True, exist_ok=True)
        p.write_text(text, encoding="utf-8")
    return tmp_path


# ---- what the source says --------------------------------------------------

def test_a_declared_cuda_dependency_is_found(tmp_path):
    t = tree(tmp_path, {"requirements.txt": "torch\nflash_attn==2.5\n"})
    assert "flash_attn" in ins.scan(t)["cuda"]


def test_cuda_in_code_is_recorded_but_not_as_a_dependency(tmp_path):
    """apple/coreai-models mentions torch.cuda in one export recipe and is an
    Apple on-device repo. Calling that "needs CUDA" threw away the most
    relevant candidate in the sweep."""
    t = tree(tmp_path, {"export.py": "if torch.cuda.is_available():\n    pass\n"})
    found = ins.scan(t)
    assert found["cuda"] == []
    assert "torch.cuda" in found["cuda_mentioned"]


def test_mlx_native_is_distinguished_from_a_torch_mps_fallback(tmp_path):
    native = ins.scan(tree(tmp_path / "a", {"m.py": "import mlx.core as mx\n"}))
    fallback = ins.scan(tree(tmp_path / "b", {"m.py": 'device = "mps"\n'}))
    assert native["mlx"] and not native["mps"]
    assert fallback["mps"] and not fallback["mlx"]


def test_model_ids_are_read_out_of_code(tmp_path):
    t = tree(tmp_path, {"g.py": 'load("Lightricks/LTX-2")\nx = "google/umt5-xxl"\n'})
    assert set(ins.scan(t)["hf_ids"]) == {"Lightricks/LTX-2", "google/umt5-xxl"}


def test_infrastructure_ids_are_not_weights(tmp_path):
    t = tree(tmp_path, {"w.yaml": 'uses: "actions/checkout"\n'})
    assert ins.scan(t)["hf_ids"] == []


def test_dot_directories_are_not_the_project(tmp_path):
    """An agent skills folder full of helper scripts was being read as the
    project's own entry points."""
    t = tree(tmp_path, {".claude/skills/helper.py": 'if __name__ == "__main__": pass'})
    assert ins.scan(t)["entry_points"] == []


def test_an_entry_point_is_found(tmp_path):
    t = tree(tmp_path, {"pyproject.toml": "[project.scripts]\nx = 'a:b'\n"})
    assert ins.scan(t)["entry_points"] == ["pyproject scripts"]


# ---- the verdict -----------------------------------------------------------

def fit(machine=None, **kw):
    """A verdict for one candidate. `machine` pins which machine is deciding;
    left out, the local one answers, which is right for the checks that do not
    depend on a runtime and wrong for the ones that do."""
    return ins.decide(ins.Fit(repo="a/b", entry_points=["main.py"], **kw),
                      machine=machine)


def test_a_declared_cuda_dependency_outranks_everything(tmp_path):
    """Absolute on a machine without CUDA: a repo that cannot run at any size
    is not a size question.

    Pinned to a Mac rather than left to whatever runs the suite. Unpinned, this
    asserted the local machine's answer, which is the confusion the runtime
    verdicts exist to remove: on a card the same repo correctly fits."""
    assert fit(cuda=["flash_attn"], smallest=1,
               machine=_APPLE).verdict == "needs-cuda"


def test_the_smallest_weight_decides_not_the_largest():
    """Measured the hard way. Blaizzy/nativ names a 1774 GiB model and was
    reported as too big for this machine; it is a Mac app with a CATALOGUE of
    models it can serve. Source cannot tell a requirement from an option, so
    the honest question is whether ANYTHING it names could run here."""
    got = fit(smallest=2 * ins.GIB, largest=1774 * ins.GIB)
    assert got.verdict == "fits"


def test_a_model_that_cannot_fit_at_all_is_refused():
    assert fit(smallest=90 * ins.GIB, largest=90 * ins.GIB).verdict == "too-big"


def test_weights_that_could_not_be_sized_are_unknown_not_fitting():
    """An unknown size reported as zero reads as "small enough", which is the
    opposite of what is known. HuggingFace 429s this endpoint under a sweep."""
    got = fit(unsized=["org/a", "org/b"])
    assert got.verdict == "unknown" and "not known" in got.why


def test_naming_no_weights_at_all_is_not_the_same_as_unknown():
    got = fit()
    assert got.verdict == "fits" and "no weights named" in got.why


def test_a_repo_nobody_has_touched_in_years_is_dead():
    assert fit(last_commit="2019-01-01T00:00:00+00:00").verdict == "dead"


def test_nothing_to_call_is_not_a_candidate():
    assert ins.decide(ins.Fit(repo="a/b")).verdict == "no-entry-point"


def test_an_unparseable_commit_date_does_not_decide_anything():
    got = fit(last_commit="whenever")
    assert got.verdict == "fits"


# ---- guards ----------------------------------------------------------------

def test_a_repo_carrying_weights_in_git_is_refused_before_cloning(tmp_path):
    """Cloning it IS the download this tier exists to avoid."""
    got = ins.inspect("a/b", tmp_path, meta={"size": 900_000},
                      run=lambda *a, **k: pytest.fail("must not clone"))
    assert got.verdict == "too-big" and "weights in git" in got.why


def test_the_clone_is_shallow_and_single_branch(tmp_path):
    seen = []

    def run(argv, cwd=None, timeout=180.0):
        seen.append(argv)
        (tmp_path / "a__b").mkdir(exist_ok=True)
        return "2026-01-01T00:00:00+00:00"

    ins.inspect("a/b", tmp_path, meta={"size": 10}, run=run,
                sizer=lambda m: -1)
    assert "--depth" in seen[0] and "1" in seen[0]
    assert "--single-branch" in seen[0] and "--no-tags" in seen[0]


def test_an_unreachable_registry_sizes_nothing_rather_than_zero():
    assert ins.hf_size("org/x", fetch=lambda url: (_ for _ in ()).throw(
        RuntimeError("429"))) == -1


def test_a_registry_reply_with_no_files_is_unknown_not_zero():
    assert ins.hf_size("org/x", fetch=lambda url: '{"siblings": []}') == -1


def test_sizes_are_summed_across_the_repo():
    reply = '{"siblings": [{"size": 100}, {"size": 250}]}'
    assert ins.hf_size("org/x", fetch=lambda url: reply) == 350


# ---- the tier has to stay cheap --------------------------------------------

def test_only_a_bounded_number_of_weights_is_sized(tmp_path):
    """A repo listing a hundred models is showing a CATALOGUE. Sizing all of
    them turned a seconds-long tier into hours: the registry 429s under a
    sweep, and retrying at the feed cadence costs 80s per id."""
    asked = []

    def run(argv, cwd=None, timeout=180.0):
        d = tmp_path / "a__b"
        d.mkdir(exist_ok=True)
        (d / "m.py").write_text("\n".join(
            f'load("org/model-{i:03d}")' for i in range(60)), encoding="utf-8")
        return "2026-01-01T00:00:00+00:00"

    def sizer(model_id, cache=None):
        asked.append(model_id)
        return -1

    got = ins.inspect("a/b", tmp_path, meta={"size": 10}, run=run, sizer=sizer)
    assert 0 < len(asked) <= ins.SIZE_LIMIT
    assert len(got.unsized) == 60


def test_the_sizing_retry_is_short_not_the_feed_cadence():
    """20s between four tries is right for a feed nobody is waiting on, and
    wrong for a tier justified by costing seconds."""
    assert ins.SIZE_RETRIES <= 1 and ins.SIZE_DELAY <= 5


def test_a_known_size_is_answered_from_cache_without_asking():
    calls = []

    def fetch(url):
        calls.append(url)
        return '{"siblings": [{"size": 5}]}'

    cache = {"org/x": {"size": 4242, "lane": "stt"}}
    assert ins.hf_size("org/x", fetch=fetch, cache=cache) == 4242
    assert calls == []


def test_a_rate_limit_is_not_cached_as_a_permanent_unknown():
    """Caching -1 would freeze one bad afternoon into a fact."""
    cache = {}
    ins.hf_size("org/x", fetch=lambda url: (_ for _ in ()).throw(RuntimeError()),
                cache=cache)
    assert cache == {}


def test_a_real_size_is_kept_so_the_next_sweep_is_free():
    """Size and lane come out of ONE registry call and are cached together:
    the registry rate-limits, so asking twice for one model is a request spent
    on nothing."""
    cache = {}
    ins.hf_size("org/x", fetch=lambda url: '{"siblings": [{"size": 7}]}',
                cache=cache)
    assert cache == {"org/x": {"size": 7, "lane": ""}}


def test_an_older_size_only_cache_entry_is_upgraded_not_trusted():
    """Trusting it reported every already-sized model as unmeasurable: the
    first real run showed 0 queued and 14 orphans, several plainly STT and
    image models. A size-only entry predates lanes, so it is refetched."""
    got = ins.hf_facts("org/x", cache={"org/x": 99},
                       fetch=lambda url: '{"siblings": [{"size": 99}],'
                                         ' "pipeline_tag": "text-to-speech"}')
    assert got == {"size": 99, "lane": "tts"}


def test_an_mlx_project_is_not_disqualified_by_an_optional_cuda_build(tmp_path):
    """ml-explore/mlx itself came back needs-cuda. Its setup.py adds nvidia-*
    inside `if toolkit == 12:`, a branch this machine never takes, and an
    `import mlx` is positive proof the project runs on Apple Silicon."""
    got = ins.decide(ins.Fit(repo="ml-explore/mlx", entry_points=["setup.py"],
                             mlx=True, cuda=["nvidia-cublas"]),
                     machine=_APPLE)
    assert got.verdict == "fits"
    assert "nvidia-cublas" in got.cuda_mentioned


def test_a_non_mlx_project_is_still_disqualified_by_a_cuda_dependency():
    got = ins.decide(ins.Fit(repo="a/b", entry_points=["setup.py"], mlx=False,
                             cuda=["nvidia-resiliency-ext"]),
                     machine=_APPLE)
    assert got.verdict == "needs-cuda"


def test_awq_is_a_quantisation_format_not_a_cuda_requirement(tmp_path):
    """mlx-lm was flagged on an entry point named `mlx_lm.awq`, and mlx-lm
    implements AWQ natively."""
    t = tree(tmp_path, {"setup.py": '"mlx_lm.awq = mlx_lm.quant.awq:main"'})
    assert ins.scan(t)["cuda"] == []


def test_too_big_is_not_claimed_from_a_truncated_size_scan():
    """The smallest of twelve sized ids out of three hundred named is an upper
    bound on the floor, not the floor. mlx-video was refused on exactly this."""
    got = ins.decide(ins.Fit(repo="a/b", entry_points=["m.py"],
                             weights={"org/x": 90 * ins.GIB},
                             smallest=90 * ins.GIB, largest=90 * ins.GIB,
                             unsized=["org/%d" % i for i in range(50)]))
    assert got.verdict == "unknown" and "never sized" in got.why


def test_too_big_still_holds_when_the_scan_was_complete():
    got = ins.decide(ins.Fit(repo="a/b", entry_points=["m.py"],
                             weights={"org/x": 90 * ins.GIB},
                             smallest=90 * ins.GIB, largest=90 * ins.GIB))
    assert got.verdict == "too-big"


# ---- issue #68: which weight is the repo actually FOR ----------------------

def test_a_model_named_in_the_readme_outranks_one_buried_in_code():
    """The first queue built from "smallest named weight" filled with
    tokenizers and a 0.6B somebody used in a test."""
    got = ins.headline("org/thing", ["org/buried", "org/introduced"],
                       {"org/buried": 1, "org/introduced": 1},
                       ["org/introduced"])
    assert got[0] == "org/introduced"


def test_a_model_named_repeatedly_outranks_one_named_once():
    """The model a repo is ABOUT gets named again and again; a helper appears
    once."""
    got = ins.headline("org/thing", ["org/once", "org/everywhere"],
                       {"org/once": 1, "org/everywhere": 9}, [])
    assert got[0] == "org/everywhere"


def test_a_model_whose_name_echoes_the_repo_outranks_a_stranger():
    """mlx-video naming Lightricks/LTX-2 beats it naming google/umt5-xxl."""
    got = ins.headline("Blaizzy/mlx-video", ["google/umt5-xxl", "org/mlx-video-base"],
                       {}, [])
    assert got[0] == "org/mlx-video-base"


def test_the_ranking_keeps_everything(tmp_path):
    """A ranking, not a filter: a weak signal is not evidence of irrelevance."""
    ids = ["org/a", "org/b", "org/c"]
    assert sorted(ins.headline("x/y", ids, {}, [])) == sorted(ids)


def test_both_the_smallest_and_the_headline_get_sized(tmp_path):
    """They are rarely the same models, and they answer different questions:
    can anything here run, and what is worth downloading."""
    asked = []

    def run(argv, cwd=None, timeout=180.0):
        d = tmp_path / "a__thing"
        d.mkdir(exist_ok=True)
        (d / "README.md").write_text('see "org/the-headline-model-with-long-name"', encoding="utf-8")
        (d / "m.py").write_text("\n".join(
            f'load("org/helper-{i:02d}")' for i in range(30)), encoding="utf-8")
        return "2026-01-01T00:00:00+00:00"

    def sizer(model_id, cache=None):
        asked.append(model_id)
        return 2 * ins.GIB

    ins.inspect("a/thing", tmp_path, meta={"size": 10}, run=run, sizer=sizer)
    assert "org/the-headline-model-with-long-name" in asked
    assert any(i.startswith("org/helper-") for i in asked)


def test_the_fit_carries_the_repo_description(tmp_path):
    """_judge_fits reads it to show the judge prose AND source facts together.
    It shipped reading a field Fit did not have, and the whole suite passed
    because nothing exercised that path."""
    def run(argv, cwd=None, timeout=180.0):
        (tmp_path / "a__b").mkdir(exist_ok=True)
        return "2026-01-01T00:00:00+00:00"

    got = ins.inspect("a/b", tmp_path, meta={"size": 10, "description": "a tool"},
                      run=run, sizer=lambda m, cache=None: -1)
    assert got.description == "a tool"


# ---- issue #81: a weight no lane can test ---------------------------------

def test_the_registrys_own_task_label_names_the_lane():
    assert ins.lane_for({"pipeline_tag": "automatic-speech-recognition"}) == "stt"
    assert ins.lane_for({"pipeline_tag": "text-to-audio"}) == "tts"


def test_free_text_tags_are_read_when_the_task_label_is_missing():
    """pipeline_tag was absent on three of six real models checked."""
    assert ins.lane_for({"pipeline_tag": None, "tags": ["mlx", "asr"]}) == "stt"


def test_a_model_nothing_here_can_measure_has_no_lane():
    """silero-vad and MossFormer2 are both good models and neither can be
    scored by anything in this repo. Empty is a fact about the harness, not a
    rejection of the model."""
    assert ins.lane_for({"pipeline_tag": "audio-classification",
                         "tags": ["mlx", "vad"]}) == ""
    assert ins.lane_for({}) == ""


def test_the_lane_travels_with_the_weight(tmp_path):
    def run(argv, cwd=None, timeout=180.0):
        d = tmp_path / "a__b"
        d.mkdir(exist_ok=True)
        (d / "m.py").write_text('load("org/ears")', encoding="utf-8")
        return "2026-01-01T00:00:00+00:00"

    got = ins.inspect("a/b", tmp_path, meta={"size": 10}, run=run,
                      facts=lambda m, cache=None: {"size": 2 * ins.GIB,
                                                   "lane": "stt"})
    assert got.lanes["org/ears"] == "stt"


# ---- a training extra is not a runtime requirement -------------------------

def test_an_optional_extra_is_not_a_runtime_dependency(tmp_path):
    """Reading a pyproject wholesale called starvector CUDA-dependent partly on
    `deepspeed`, which sits in `[project.optional-dependencies] train`. The
    verdict was right for another reason, which is worse than being wrong: it
    hid the defect."""
    t = tree(tmp_path, {"pyproject.toml": (
        '[project]\ndependencies = ["torch", "numpy"]\n\n'
        '[project.optional-dependencies]\ntrain = ["deepspeed", "ninja"]\n')})
    found = ins.scan(t)
    assert found["cuda"] == []
    assert "deepspeed" in found["cuda_mentioned"]


def test_a_runtime_dependency_before_the_extras_still_disqualifies(tmp_path):
    """starvector really does pin flash_attn==2.7.3 inside `dependencies`, so
    the verdict stands -- for the right reason this time."""
    t = tree(tmp_path, {"pyproject.toml": (
        '[project]\ndependencies = ["torch", "flash_attn==2.7.3"]\n\n'
        '[project.optional-dependencies]\ntrain = ["deepspeed"]\n')})
    assert "flash_attn" in ins.scan(t)["cuda"]


def test_poetry_dev_groups_are_optional_too(tmp_path):
    t = tree(tmp_path, {"pyproject.toml": (
        '[project]\ndependencies = ["torch"]\n\n'
        '[tool.poetry.group.dev.dependencies]\ntriton = "*"\n')})
    assert ins.scan(t)["cuda"] == []


def test_a_dev_requirements_file_is_not_a_runtime_requirement():
    """It is read to decide whether a thing can RUN here."""
    assert "requirements-dev.txt" not in ins.DEPENDENCY_FILES


def _clone_pushed(tmp_path, when: str):
    """A fake checkout with one entry point, last touched at `when`."""
    def run(argv, cwd=None, timeout=180.0):
        tree = tmp_path / "a__b"
        tree.mkdir(exist_ok=True)
        (tree / "main.py").write_text("if __name__ == '__main__':\n    pass\n", encoding="utf-8")
        return when
    return run


def test_inspect_passes_dead_days_through_to_decide(tmp_path):
    """It accepted a ceiling override and not this one, so the abandonment
    threshold was reachable only as decide()'s captured default and no caller
    could vary it. Issue #103."""
    run = _clone_pushed(tmp_path, "2024-01-01T00:00:00+00:00")
    lenient = ins.inspect("a/b", tmp_path, meta={"size": 10}, run=run,
                          sizer=lambda m: -1, dead_days=100_000)
    assert lenient.verdict != "dead"

    strict = ins.inspect("a/b", tmp_path, meta={"size": 10}, run=run,
                         sizer=lambda m: -1, dead_days=1)
    assert strict.verdict == "dead"


def test_inspect_still_defaults_to_the_module_threshold(tmp_path):
    run = _clone_pushed(tmp_path, "2019-01-01T00:00:00+00:00")
    got = ins.inspect("a/b", tmp_path, meta={"size": 10}, run=run,
                      sizer=lambda m: -1)
    assert got.verdict == "dead"

# ---- capacity gating ------------------------------------------------------
# The ceiling was a constant describing ONE machine. Two Windows boxes differ
# from each other as much as either differs from the Apple Silicon machine, so what a candidate
# is measured against has to be read off the machine running the sweep.


def test_the_ceiling_is_read_off_the_accelerator_not_a_constant():
    from harness import memory
    discrete = memory.Accelerator("discrete", 12.0, 10.5)
    big_card = memory.Accelerator("discrete", 24.0, 22.0)
    assert ins.ceiling_bytes(discrete) < ins.ceiling_bytes(big_card)
    assert ins.ceiling_bytes(discrete) <= 12 * ins.GIB


def test_a_weight_over_the_cards_vram_is_too_big_for_that_card():
    """Qwen3-30B-A3B at 4-bit is ~17 GB: it fits a 24 GB card and does not fit
    a 12 GB one. The same candidate, two verdicts, two machines."""
    from harness import memory
    small = ins.decide(ins.Fit(repo="x/y", weights=["w"], smallest=17 * ins.GIB,
                                 entry_points=["run.py"]),
                        ceiling=ins.ceiling_bytes(
                            memory.Accelerator("discrete", 12.0, 10.5)))
    roomy = ins.decide(ins.Fit(repo="x/y", weights=["w"], smallest=17 * ins.GIB,
                                 entry_points=["run.py"]),
                        ceiling=ins.ceiling_bytes(
                            memory.Accelerator("discrete", 24.0, 22.0)))
    assert small.verdict == "too-big"
    assert roomy.verdict != "too-big"


# ---- which runtime a candidate needs --------------------------------------
# The verdict names the RUNTIME, not the platform. "CUDA is absolute on this
# machine" was true of the Mac it was written on and made every CUDA candidate
# a rejection on a box bought to run them, while an MLX repo that cannot start
# there passed the same gate.

from harness import machine as mach  # noqa: E402
from harness.memory import Accelerator  # noqa: E402

_APPLE = mach.Machine(frozenset({"mlx", "cpu"}),
                      Accelerator("unified", 32.0, 25.0, "Mac16,1"))
_CARD = mach.Machine(frozenset({"cuda", "cpu"}),
                     Accelerator("discrete", 12.0, 10.5, "RTX 4070"))
_LINUX_CARD = mach.Machine(frozenset({"cuda", "cpu"}),
                           Accelerator("discrete", 12.0, 10.5, "RTX 4070"))


def _fit(**kw):
    base = dict(repo="x/y", weights=["w"], smallest=1 * ins.GIB,
                entry_points=["run.py"])
    base.update(kw)
    return ins.Fit(**base)


def test_a_cuda_repo_runs_on_a_card_and_not_on_a_mac():
    assert ins.decide(_fit(cuda=["torch.cuda"]), machine=_CARD).verdict != "needs-cuda"
    assert ins.decide(_fit(cuda=["torch.cuda"]), machine=_APPLE).verdict == "needs-cuda"


def test_an_mlx_repo_runs_on_a_mac_and_not_on_a_card():
    """The half that was missing. An MLX-only repo was accepted on a machine
    with no MLX, so a sweep queued weights that cannot load."""
    assert ins.decide(_fit(mlx=True), machine=_APPLE).verdict != "needs-mlx"
    assert ins.decide(_fit(mlx=True), machine=_CARD).verdict == "needs-mlx"


def test_a_repo_offering_both_runs_on_either():
    """An MLX import beside a CUDA pin is a project with two paths, and both
    machines have one of them. This is the case the old rule got right."""
    # A FRESH Fit per machine: decide() mutates what it is given, moving a
    # satisfied cuda dependency into cuda_mentioned, so a shared one arrives at
    # the second machine already altered.
    for m in (_APPLE, _CARD):
        both = _fit(mlx=True, cuda=["torch.cuda"])
        assert ins.decide(both, machine=m).verdict not in ("needs-cuda", "needs-mlx")


def test_a_repo_needing_neither_runs_anywhere():
    """Pure python has no runtime requirement, so no machine refuses it."""
    for m in (_APPLE, _CARD):
        assert ins.decide(_fit(), machine=m).verdict not in ("needs-cuda", "needs-mlx")



def test_linux_and_windows_with_the_same_card_reach_the_same_verdict():
    """Nothing in decide() may consult the platform."""
    for kw in ({"cuda": ["torch.cuda"]}, {"mlx": True}, {}):
        # Fresh Fits for the same reason as above.
        assert (ins.decide(_fit(**kw), machine=_CARD).verdict
                == ins.decide(_fit(**kw), machine=_LINUX_CARD).verdict)


def test_a_repo_offering_two_runtimes_on_a_machine_with_neither_names_both():
    """It reported `needs-mlx` beside a reason listing CUDA packages, because
    the verdict took whichever runtime sorted first. Verdicts are recorded as
    terminal in the store, so a wrong reason there is durable."""
    from harness import machine as mach
    from harness.memory import Accelerator
    bare = mach.Machine(frozenset({"cpu"}),
                        Accelerator("discrete", 12.0, 10.0, "RTX"))
    fit = ins.Fit(repo="a/b", mlx=True, cuda=["flash_attn"],
                  entry_points=["main.py"])
    got = ins.decide(fit, ceiling=99 << 30, machine=bare)
    assert got.verdict.startswith("needs-")
    assert "mlx" in got.why and "cuda" in got.why


def test_one_missing_runtime_is_still_named_singly():
    from harness import machine as mach
    from harness.memory import Accelerator
    mac = mach.Machine(frozenset({"mlx", "cpu"}),
                       Accelerator("unified", 32.0, 25.0, "arm64"))
    fit = ins.Fit(repo="a/b", cuda=["flash_attn"], entry_points=["main.py"])
    got = ins.decide(fit, ceiling=99 << 30, machine=mac)
    assert got.verdict == "needs-cuda"
    assert "none of" not in got.why


def test_the_verdict_list_is_derived_rather_than_written_down():
    """A hand-written tuple said needs-cuda long after decide() had learned to
    say needs-mlx and needs-rocm."""
    got = ins.verdicts()
    assert "needs-mlx" in got and "needs-cuda" in got and "needs-rocm" in got
    assert "fits" in got


# ---- a clone that did not finish (issue #181) ------------------------------

def test_a_finished_clone_is_recognised(tmp_path):
    (tmp_path / ".git").mkdir()
    (tmp_path / "README.md").write_text("hi", encoding="utf-8")
    assert ins.cloned(tmp_path)


def test_a_killed_clone_leaves_a_git_dir_and_no_worktree(tmp_path):
    """What AdaptiveMotorControlLab/AmadeusGPT left behind after 180s."""
    (tmp_path / ".git").mkdir()
    assert not ins.cloned(tmp_path)


def test_a_half_clone_is_removed_rather_than_scanned(tmp_path):
    dest = tmp_path / "half"
    dest.mkdir()
    (dest / ".git").mkdir()
    calls = []

    def run(argv, **kw):
        calls.append(argv)
        dest.mkdir(parents=True, exist_ok=True)
        (dest / ".git").mkdir(exist_ok=True)
        (dest / "setup.py").write_text("", encoding="utf-8")
        return ""

    ins.clone("org/repo", dest, run=run)
    assert calls, "a half-clone must be re-cloned, not returned as it stands"
    assert ins.files(dest), "and the retry must leave a readable tree"


def test_a_finished_clone_is_not_fetched_again(tmp_path):
    dest = tmp_path / "whole"
    dest.mkdir()
    (dest / ".git").mkdir()
    (dest / "setup.py").write_text("", encoding="utf-8")

    def run(argv, **kw):
        raise AssertionError("re-cloned a tree that was already complete")

    assert ins.clone("org/repo", dest, run=run) == dest


def test_a_failed_clone_leaves_nothing_behind(tmp_path):
    dest = tmp_path / "doomed"

    def run(argv, **kw):
        dest.mkdir(parents=True, exist_ok=True)
        (dest / ".git").mkdir()
        raise ins.InspectError("git: no answer in 180s")

    with pytest.raises(ins.InspectError):
        ins.clone("org/repo", dest, run=run)
    assert not dest.exists()


def test_a_clone_timeout_is_an_inspect_error(monkeypatch):
    """TimeoutExpired is not an InspectError, so it escaped the per-candidate
    guard in _report_inspect and took the whole batch down. Issue #181."""
    import subprocess

    def boom(*a, **kw):
        raise subprocess.TimeoutExpired(cmd=["git"], timeout=180.0)

    monkeypatch.setattr(subprocess, "run", boom)
    with pytest.raises(ins.InspectError) as exc:
        ins._run(["git", "clone", "x"])
    assert "180s" in str(exc.value)


def test_a_nonzero_exit_is_still_an_inspect_error(monkeypatch):
    import subprocess

    monkeypatch.setattr(subprocess, "run", lambda *a, **kw: subprocess.CompletedProcess(
        args=a, returncode=128, stdout="", stderr="repository not found"))
    with pytest.raises(ins.InspectError) as exc:
        ins._run(["git", "clone", "x"])
    assert "repository not found" in str(exc.value)


@pytest.mark.parametrize("tag,tags,lane", [
    # Qwen-Image-Bench: a VLM judge tagged text-to-image, screened as an image
    # generator. What it produces is text.
    ("image-text-to-text", ["text-to-image"], "code"),
    ("image-text-to-text", [], "code"),
    ("image-text-to-image", [], "image"),
    ("image-text-to-video", ["text-to-image"], "video"),
    ("image-to-3d", ["diffusion"], ""),
    ("text-classification", [], ""),
    ("any-to-any", ["text-to-image"], "image"),
])
def test_an_unlisted_task_is_filed_by_what_it_produces(tag, tags, lane):
    """#379."""
    assert ins.lane_for({"pipeline_tag": tag, "tags": tags}) == lane


def test_tags_still_decide_when_the_publisher_named_no_task():
    """Negative control for #379."""
    assert ins.lane_for({"pipeline_tag": "", "tags": ["text-to-image"]}) == "image"


#: Every HuggingFace pipeline task, from huggingface.js packages/tasks/src/
#: pipelines.ts (57 on 2026-10-05). #383 class 2: an unlisted task fails here.
HF_TASKS = (
    "text-classification token-classification table-question-answering "
    "question-answering zero-shot-classification translation summarization "
    "feature-extraction text-generation fill-mask sentence-similarity "
    "text-to-speech text-to-audio automatic-speech-recognition audio-to-audio "
    "audio-classification audio-text-to-text voice-activity-detection "
    "depth-estimation image-classification object-detection image-segmentation "
    "text-to-image image-to-text image-to-image image-to-video "
    "unconditional-image-generation video-classification reinforcement-learning "
    "robotics tabular-classification tabular-regression tabular-to-text "
    "table-to-text multiple-choice text-ranking text-retrieval "
    "time-series-forecasting text-to-video image-text-to-text image-text-to-image "
    "image-text-to-video visual-question-answering document-question-answering "
    "zero-shot-image-classification graph-ml mask-generation "
    "zero-shot-object-detection text-to-3d image-to-3d image-feature-extraction "
    "video-text-to-text keypoint-detection visual-document-retrieval any-to-any "
    "video-to-video other").split()

#: The deliberate answer: a lane whose cases the task can take, else "".
TASK_LANES = {
    "text-generation": "code", "image-text-to-text": "code",
    "audio-text-to-text": "code", "video-text-to-text": "code",
    "text-to-image": "image", "text-to-video": "video",
    "image-to-video": "video", "image-text-to-video": "video",
    "text-to-speech": "tts", "automatic-speech-recognition": "stt",
    **{t: "" for t in (
        "text-classification", "token-classification",
        "table-question-answering", "question-answering",
        "zero-shot-classification", "translation", "summarization",
        "feature-extraction", "fill-mask", "sentence-similarity",
        "audio-to-audio", "audio-classification", "voice-activity-detection",
        "depth-estimation", "image-classification", "object-detection",
        "image-segmentation", "unconditional-image-generation",
        "video-classification", "reinforcement-learning", "robotics",
        "tabular-classification", "tabular-regression", "multiple-choice",
        "text-ranking", "text-retrieval", "time-series-forecasting",
        "visual-question-answering", "document-question-answering",
        "zero-shot-image-classification", "graph-ml", "mask-generation",
        "zero-shot-object-detection", "text-to-3d", "image-to-3d",
        "image-feature-extraction", "keypoint-detection",
        "visual-document-retrieval", "any-to-any", "other")},
}

#: Answered today but the answer looks wrong; not pinned until #387 decides.
QUESTIONED = {"text-to-audio", "image-to-text", "table-to-text",
              "tabular-to-text", "image-to-image", "image-text-to-image",
              "video-to-video"}


def test_every_huggingface_task_has_a_deliberate_lane():
    assert len(HF_TASKS) == len(set(HF_TASKS))
    assert not set(TASK_LANES) & QUESTIONED
    assert set(TASK_LANES) | QUESTIONED == set(HF_TASKS)


@pytest.mark.parametrize("task", sorted(TASK_LANES))
def test_each_huggingface_task_lands_where_it_was_decided(task):
    assert ins.lane_for({"pipeline_tag": task, "tags": []}) == TASK_LANES[task]
