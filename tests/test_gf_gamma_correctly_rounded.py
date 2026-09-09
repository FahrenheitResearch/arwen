"""The gamma gate, after the LGPL transcription was removed.

WHAT CHANGED, AND WHY THIS FILE EXISTS.  Through ArWen 2.6.5 ``gfk_tgamma``
was a line-for-line transcription of glibc's ``e_gammaf_r.c`` and
``gamma_productf.c``, and it was graded against
``gpuwm/data/gf/oracle/gf-libm-tgammaf.csv`` -- a recording of what glibc
2.39 returns.  Both glibc files are FSF-copyright and LGPL-2.1-or-later with
no permissive upstream (``gamma_productf.c`` was created from nothing by
glibc commit ``d8cd06db62d9``), so an Apache-2.0 distribution cannot carry
them.  They are gone.

The kernel now computes the CORRECTLY ROUNDED float32 gamma, so "matches one
binary" no longer describes the contract and grading against it would be
grading against a bug.  This file grades the contract that replaced it:
**the mathematically correct answer**, from a 113-bit oracle.  That is a
strictly stronger check -- any reviewer with any arbitrary-precision library
can regenerate the reference, whereas ``gf-libm-tgammaf.csv`` can only be
regenerated on x86-64 glibc 2.39.

It also PINS THE DIVERGENCE.  gfortran binds WRF's F2008 ``gamma()``
intrinsic to glibc's ``tgammaf``, so ArWen no longer reproduces WRF's ``fzu``
bit for bit.  ``docs/gf_gamma_known_delta.md`` is the record; the tests below
are what stop it drifting.

HOW A REVIEWER RUNS IT
----------------------
Everything except the two ``@pytest.mark.gpu`` tests runs with no GPU, no
CuPy and no compiler::

    pytest tests/test_gf_gamma_correctly_rounded.py -v

The host-compiled kernel arm builds its own copy of the harness when one
is not already built, so it needs a C++ toolchain but no manual step.  To
build the harness by hand anyway -- which is what the parity tool loads::

    cd tools/gf_wrf461_oracle && bash build.sh          # or, minimally:
    g++ -O2 -std=c++17 -ffp-contract=off -fno-unsafe-math-optimizations \
        -I ../../gpuwm/core/kernels -shared -fPIC gf_host_harness.cpp \
        -o gf_host_harness.so -lm

To regenerate the reference fixtures from scratch (glibc-independent)::

    gcc -O2 -o /tmp/crg tools/gf_wrf461_oracle/gf_crgamma_dump.c -lm -lquadmath
    cut -d, -f1 gpuwm/data/gf/oracle/gf-libm-tgammaf.csv | /tmp/crg /dev/stdin
"""

from __future__ import annotations

import math
import os
import struct

import numpy as np
import pytest

from gpuwm.verify.gf_oracle import GF_ORACLE_DIR

_ROOT = os.path.dirname(os.path.dirname(os.path.abspath(__file__)))

# The interval gfk_tgamma is claimed correctly rounded over, and the interval
# the scheme can reach: alpha in [1.075, 28], beta in {1.3, 2.5, 4.0}, so
# alpha+beta in [2.375, 32].  0.25 and 36 are the committed probe bounds.
_LO_WORD = 0x3E800000   # 0.25f
_HI_WORD = 0x42100000   # 36.0f


def _words(name):
    """(argument words, answer words) from a two-column hex CSV."""
    xs, ys = [], []
    with (GF_ORACLE_DIR / name).open(encoding="ascii") as fh:
        for line in fh:
            a, b = line.strip().split(",")
            xs.append(int(a, 16))
            ys.append(int(b, 16))
    return np.array(xs, dtype=np.uint32), np.array(ys, dtype=np.uint32)


def _f32(word):
    return np.frombuffer(struct.pack("<I", int(word)), dtype=np.float32)[0]


def _word(x):
    return struct.unpack("<I", struct.pack("<f", np.float32(x)))[0]


# ==========================================================================
# 1. the reference fixture is correct MATHEMATICS, checked without trusting
#    any float32 gamma -- not glibc's, not ours, not the generator's
# ==========================================================================
def test_the_correctly_rounded_fixture_is_actually_correctly_rounded():
    """Re-derive every answer word from an independent double-precision
    gamma AND prove the rounding is forced, so the check does not inherit
    that gamma's last bits.

    ``gf-crgamma-tgammaf.csv`` was written by libquadmath's 113-bit
    ``tgammaq`` (tools/gf_wrf461_oracle/gf_crgamma_dump.c).  This test does
    not take that on trust.  For each row it computes Gamma in binary64 with
    ``math.gamma`` -- a different routine at a different precision -- and
    then checks the answer is not merely the nearest float32 to that double,
    but that the double is FURTHER THAN ANY PLAUSIBLE ERROR from the float32
    rounding boundary.  A float32 ULP is 2**29 double ULPs, so requiring
    2**10 double ULPs of clearance leaves 19 binary orders of margin over
    ``tgamma``'s own sub-ULP error.  If a row ever fails the clearance check
    it is reported rather than silently passed: that row would need the
    113-bit value to adjudicate.
    """
    xs, want = _words("gf-crgamma-tgammaf.csv")
    margin = 2.0 ** 10
    tight = []
    for xw, ww in zip(xs.tolist(), want.tolist()):
        x = float(_f32(xw))
        g = math.gamma(x)                      # binary64, independent routine
        with np.errstate(over="ignore"):       # Gamma -> +inf near 35.04
            v = np.float32(g)
        assert _word(v) == ww, (
            f"x=0x{xw:08X}: float64 gamma rounds to 0x{_word(v):08X}, "
            f"fixture says 0x{ww:08X}")
        # distance from g to the float32 rounding boundary, in double ULPs
        nxt = np.nextafter(v, np.float32(np.inf) if g > float(v)
                           else np.float32(-np.inf))
        mid = (float(v) + float(nxt)) / 2.0
        if math.isfinite(mid) and mid != 0.0:
            clear = abs(g - mid) / math.ulp(g) if math.ulp(g) else float("inf")
            if clear < margin:
                tight.append((xw, clear))
    assert not tight, (
        f"{len(tight)} rows sit within {margin} double ULPs of a float32 "
        f"rounding boundary, so the float64 cross-check cannot adjudicate "
        f"them: first 0x{tight[0][0]:08X} at {tight[0][1]:.1f} ULPs")


def test_the_fixture_covers_the_whole_reachable_interval():
    xs, _ = _words("gf-crgamma-tgammaf.csv")
    assert xs.min() == _LO_WORD and xs.max() <= _HI_WORD
    assert np.all(np.diff(xs.astype(np.int64)) > 0), "arguments must ascend"
    assert xs.size == 65638


# ==========================================================================
# 2. the divergence, pinned.  This is the known delta, not a regression.
# ==========================================================================
def test_glibc_is_the_one_that_is_wrong_and_by_how_much():
    """MEASURED, and the reason the transcription was not worth keeping.

    Both fixtures carry the same 65,638 arguments in the same order, so the
    subtraction below is exact and needs no interpolation.  Numbers here are
    the committed statement of ``docs/gf_gamma_known_delta.md``; a change in
    either direction should be understood before it is accepted.
    """
    xg, wg = _words("gf-libm-tgammaf.csv")      # what glibc 2.39 returns
    xc, wc = _words("gf-crgamma-tgammaf.csv")   # what is correct
    assert np.array_equal(xg, xc), "the two gamma fixtures must be row-aligned"
    d = wc.astype(np.int64) - wg.astype(np.int64)
    ndiff = int(np.count_nonzero(d))
    assert ndiff == 25713, ndiff                    # 39.17 per cent of rows
    assert int(np.abs(d).max()) == 4, int(np.abs(d).max())
    # The full shape, so a change is legible rather than just red.  (The
    # worst case over the WHOLE interval is 6 ULP; this strided grid of
    # 65,638 arguments reaches 4.)
    hist = {int(k): int(v) for k, v in
            zip(*np.unique(d, return_counts=True))}
    assert hist == {-4: 17, -3: 282, -2: 2558, -1: 12942, 0: 39925,
                    1: 8947, 2: 915, 3: 51, 4: 1}, hist
    # ... and the error is two-sided, which is what a rounding error looks
    # like.  A one-sided histogram would mean an implementation difference.
    assert int((d > 0).sum()) > 0 and int((d < 0).sum()) > 0


def test_the_two_fixtures_are_different_objects():
    """Negative control for the gate swap: if these ever agree, the new
    oracle has been regenerated from glibc and the gate is grading the bug
    it was built to stop grading."""
    _, wg = _words("gf-libm-tgammaf.csv")
    _, wc = _words("gf-crgamma-tgammaf.csv")
    assert not np.array_equal(wg, wc)


def test_tgammaf_of_four_is_the_headline_case():
    """glibc returns 6.00000048 for Gamma(4); the answer is 6."""
    xs, wc = _words("gf-crgamma-tgammaf.csv")
    _, wg = _words("gf-libm-tgammaf.csv")
    # 4.0f is not on the swept grid, so assert the property that put it there
    assert _word(np.float32(6.0)) == 0x40C00000
    # and the swept grid must contain arguments where glibc is a full ULP out
    d = wc.astype(np.int64) - wg.astype(np.int64)
    assert int(np.count_nonzero(np.abs(d) >= 1)) == 25713


# ==========================================================================
# 3. fzu -- what the divergence actually costs the physics
# ==========================================================================
def _fzu_rows():
    rows = []
    with (GF_ORACLE_DIR / "gf-crgamma-fzu.csv").open(encoding="ascii") as fh:
        for line in fh:
            a, b, f = line.strip().split(",")
            rows.append((int(a, 16), int(b, 16), int(f, 16)))
    return rows


def test_fzu_reference_is_spelled_as_the_scheme_spells_it():
    """``fzu = gamma(a+b)/(gamma(a)*gamma(b))``, one float32 rounding per
    operation, recomputed here from the gamma fixture's own answers rather
    than from any gamma implementation."""
    xs, wc = _words("gf-crgamma-tgammaf.csv")
    table = dict(zip(xs.tolist(), wc.tolist()))
    checked = 0
    for aw, bw, fw in _fzu_rows():
        a, b = _f32(aw), _f32(bw)
        ab = np.float32(a + b)
        if not all(w in table for w in (aw, bw, _word(ab))):
            continue                     # argument off the swept grid
        ga, gb, gab = (_f32(table[w]) for w in (aw, bw, _word(ab)))
        want = np.float32(np.float32(gab) / np.float32(ga * gb))
        assert _word(want) == fw, f"alpha=0x{aw:08X} beta=0x{bw:08X}"
        checked += 1
    assert checked > 0, "no fzu row was checkable against the gamma fixture"


def test_fzu_divergence_from_wrf_stays_inside_the_cpu_suites_budget():
    """The number the forecast impact hangs on.

    ``tests/test_gf_deep_parity.py::test_fzu_is_the_one_measured_divergence``
    has asserted a 4-ULP ``fzu`` budget for the float32 CPU authority since
    the port landed, and ``xmb`` moves by up to 7.3 per cent inside it
    (``test_a_one_ulp_massflux_shape_perturbation_moves_xmb_by_seven_percent``).
    The CUDA kernel now lands in the same place instead of being exactly
    WRF's.  MEASURED over the 26 (alpha, beta) pairs the committed 216-column
    fixture actually reaches: 21 differ, worst 4 ULP.  If this widens, the
    xmb statement in docs/gf_gamma_known_delta.md is no longer covered by the
    CPU suite's measurement and must be re-measured.
    """
    surf = GF_ORACLE_DIR / "gf-deep-surface.csv"
    import csv as _csv
    reach = set()
    with surf.open(encoding="ascii") as fh:
        for r in _csv.DictReader(fh):
            for al, be in (("up_alpha", "up_beta"), ("dn_alpha", "dn_beta")):
                a, b = np.float32(float(r[al])), np.float32(float(r[be]))
                if a > 0 and b > 0:
                    reach.add((_word(a), _word(b)))
    sh = GF_ORACLE_DIR / "gf-shallow-surface.csv"
    with sh.open(encoding="ascii") as fh:
        for r in _csv.DictReader(fh):
            a, b = np.float32(float(r["sh_alpha"])), np.float32(float(r["sh_beta"]))
            if a > 0 and b > 0:
                reach.add((_word(a), _word(b)))
    assert len(reach) == 26, len(reach)

    ours = {(a, b): f for a, b, f in _fzu_rows()}
    missing = reach - set(ours)
    assert not missing, f"{len(missing)} reachable pairs missing from the fzu fixture"

    # WRF's own captured fzu for the same pairs
    wrf = {}
    with surf.open(encoding="ascii") as fh:
        for r in _csv.DictReader(fh):
            for al, be, fz in (("up_alpha", "up_beta", "up_fzu"),
                               ("dn_alpha", "dn_beta", "dn_fzu")):
                a, b = np.float32(float(r[al])), np.float32(float(r[be]))
                if a > 0 and b > 0:
                    wrf[(_word(a), _word(b))] = _word(np.float32(float(r[fz])))
    with sh.open(encoding="ascii") as fh:
        for r in _csv.DictReader(fh):
            a, b = np.float32(float(r["sh_alpha"])), np.float32(float(r["sh_beta"]))
            if a > 0 and b > 0:
                wrf[(_word(a), _word(b))] = _word(np.float32(float(r["sh_fzu"])))

    d = [abs(int(ours[k]) - int(wrf[k])) for k in reach if k in wrf]
    assert len(d) == 26, len(d)
    assert sum(1 for v in d if v) == 21, sum(1 for v in d if v)
    assert max(d) == 4, max(d)


# ==========================================================================
# 4. the LGPL code is actually gone
# ==========================================================================
@pytest.mark.parametrize("symbol", ["gfk_gamma_product", "gfk_gammaf_positive",
                                    "GAM_SQRT12", "GAM_TWOPI", "__gamma_productf"])
def test_the_lgpl_gamma_symbols_are_absent_from_the_shipped_kernels(symbol):
    """The licence half of this change, gated.  These are the identifiers of
    glibc's ``e_gammaf_r.c`` / ``gamma_productf.c``; the wheel ships
    ``*.cu``/``*.cuh`` as source (pyproject package-data), so their absence
    from the tree is their absence from the distribution."""
    kdir = os.path.join(_ROOT, "gpuwm", "core", "kernels")
    hits = []
    for fn in sorted(os.listdir(kdir)):
        if not fn.endswith((".cu", ".cuh")):
            continue
        text = open(os.path.join(kdir, fn), encoding="utf-8").read()
        for i, line in enumerate(text.splitlines(), 1):
            if symbol in line and not line.lstrip().startswith("//"):
                hits.append(f"{fn}:{i}")
    assert not hits, f"{symbol} still present as code at {hits}"


def test_the_known_delta_note_exists_and_the_kernel_cites_it():
    note = os.path.join(_ROOT, "docs", "gf_gamma_known_delta.md")
    assert os.path.exists(note), "docs/gf_gamma_known_delta.md is missing"
    body = open(note, encoding="utf-8").read()
    for token in ("7.3", "correctly rounded", "fzu_override", "LGPL"):
        assert token in body, f"the known-delta note must discuss {token!r}"
    for src in ("gf.cu", "glibc_flt32.cuh"):
        text = open(os.path.join(_ROOT, "gpuwm", "core", "kernels", src),
                    encoding="utf-8").read()
        assert "docs/gf_gamma_known_delta.md" in text, f"{src} must cite the note"


# ==========================================================================
# 5. the kernel itself -- host build (no GPU) and device build
# ==========================================================================
#: Built once per session into a temporary directory, or ``None`` when this
#: box has no working C++ toolchain at all.
_BUILT_HARNESS: list = []


def _host_harness(tmp_dir):
    """The shipped kernel, compiled.  BUILT HERE if it is not already built.

    It used to ``pytest.skip`` when ``gf_host_harness.so`` was absent, which
    made the no-GPU arm of this file an option rather than a gate: on a
    GPU-less box with no harness built, a bare ``pytest tests/`` ran every
    test in this module WITHOUT EVER EXECUTING THE KERNEL.  The fixture data
    was checked against itself and nothing checked the code.  So the build is
    done here, with the same recipe ``tools/gf_wrf461_oracle/gf_host_parity.py``
    uses and the same builder discrimination ``tests/test_gf_workspace.py``
    applies -- a toolchain must first compile a trivial translation unit, so a
    half-installed compiler cannot turn a broken kernel into a skip.

    A pre-built ``gf_host_harness.so`` beside the harness source is still used
    when present, because that is what a reviewer following the module
    docstring produces.  Only "no toolchain anywhere" skips now.
    """
    so = os.path.join(_ROOT, "tools", "gf_wrf461_oracle", "gf_host_harness.so")
    if not os.path.exists(so):
        if not _BUILT_HARNESS:
            _BUILT_HARNESS.append(_build_host_harness(tmp_dir))
        so = _BUILT_HARNESS[0]
        if so is None:
            pytest.skip("no working C++17 toolchain to build gf_host_harness")
    import ctypes
    return ctypes.CDLL(so)


def _build_host_harness(tmp_dir):
    """``str`` path to a freshly built ``.so``, or ``None`` if impossible."""
    import importlib.util
    import shutil
    import subprocess

    spec = importlib.util.spec_from_file_location(
        "gf_workspace_builders",
        os.path.join(os.path.dirname(os.path.abspath(__file__)),
                     "test_gf_workspace.py"))
    workspace = importlib.util.module_from_spec(spec)
    spec.loader.exec_module(workspace)

    probe = os.path.join(str(tmp_dir), "trivial.cpp")
    with open(probe, "w", encoding="ascii", newline="\n") as handle:
        handle.write(workspace._TRIVIAL)
    candidates = list(workspace._native_builders())
    wsl = workspace._wsl_builder()
    if wsl is not None:
        candidates.append(wsl)
    for build, _label in candidates:
        if build(probe, os.path.join(str(tmp_dir), "trivial.out"),
                 str(tmp_dir))[0] != 0:
            continue
        out = os.path.join(str(tmp_dir), "gf_host_harness.so")
        code, text = build(workspace._HARNESS, out, workspace._KERNEL_DIR)
        assert code == 0, (
            "a working C++ toolchain could not build "
            "tools/gf_wrf461_oracle/gf_host_harness.cpp, so the no-GPU gamma "
            "gate cannot run:\n" + text)
        return out
    return None


def test_host_compiled_gfk_tgamma_is_correctly_rounded(tmp_path_factory):
    """The same gate as the device one, with no GPU involved: x86-64 SSE
    evaluates the same __fadd_rn/__dmul_rn/... operations with the same
    IEEE-754 semantics when built with contraction off, which is the whole
    premise of tools/gf_wrf461_oracle/gf_host_parity.py.

    Since 2.7.0 this builds the harness itself rather than skipping without
    one -- see :func:`_host_harness`."""
    lib = _host_harness(tmp_path_factory.mktemp("gf-host-harness"))
    assert hasattr(lib, "gf_host_tgamma"), (
        "gf_host_harness exports no gf_host_tgamma; a stale prebuilt .so "
        "beside the harness source will do this -- delete it and let this "
        "test build its own")
    import ctypes
    lib.gf_host_tgamma.restype = ctypes.c_float
    lib.gf_host_tgamma.argtypes = [ctypes.c_float]
    xs, want = _words("gf-crgamma-tgammaf.csv")
    bad = 0
    first = None
    for xw, ww in zip(xs.tolist(), want.tolist()):
        got = _word(lib.gf_host_tgamma(ctypes.c_float(float(_f32(xw)))))
        if got != ww:
            bad += 1
            first = first or (xw, got, ww)
    assert bad == 0, (
        f"gfk_tgamma: {bad}/{xs.size} words differ; first "
        f"x=0x{first[0]:08X} got=0x{first[1]:08X} want=0x{first[2]:08X}")


@pytest.mark.gpu
def test_device_gfk_tgamma_is_correctly_rounded():
    """max_ulp 0 against the 113-bit oracle over all 65,638 sweep arguments.

    This is the gate that replaced ``test_device_libm_matches_live_glibc``
    for tgammaf.  It is stronger: it asserts the answer is RIGHT, not that it
    matches a particular binary.
    """
    cp = pytest.importorskip("cupy")
    from gpuwm.core.kernels import load_module
    module = load_module("gf")
    xs, want = _words("gf-crgamma-tgammaf.csv")
    x = xs.view(np.float32)
    n = x.size
    d_x = cp.asarray(np.ascontiguousarray(x))
    d_out = cp.zeros(4 * n, dtype=cp.float32)
    fn = module.get_function("gf_libm_unary_probe")
    fn(((n + 255) // 256,), (256,), (d_x, d_out, np.int32(n)))
    got = cp.asnumpy(d_out).reshape(n, 4)[:, 0].copy().view(np.uint32)
    bad = np.flatnonzero(got != want)
    assert bad.size == 0, (
        f"gfk_tgamma: {bad.size}/{n} words differ; first "
        f"x=0x{int(xs[bad[0]]):08X} got=0x{int(got[bad[0]]):08X} "
        f"want=0x{int(want[bad[0]]):08X}")
    # negative control: CUDA's builtin tgammaf is a third function again and
    # is NOT correctly rounded either.  If this stops firing, re-measure.
    builtin = cp.asnumpy(d_out).reshape(n, 4)[:, 1].copy().view(np.uint32)
    assert int(np.count_nonzero(builtin != want)) > 0, (
        "CUDA's builtin tgammaf matched the correctly rounded reference on "
        "every argument -- the negative control no longer fires")


@pytest.mark.gpu
def test_device_fzu_matches_the_correctly_rounded_reference():
    cp = pytest.importorskip("cupy")
    from gpuwm.core.kernels import load_module
    module = load_module("gf")
    rows = _fzu_rows()
    a = np.array([_f32(r[0]) for r in rows], dtype=np.float32)
    b = np.array([_f32(r[1]) for r in rows], dtype=np.float32)
    want = np.array([r[2] for r in rows], dtype=np.uint32)
    n = a.size
    d_out = cp.zeros(n, dtype=cp.float32)
    fn = module.get_function("gf_fzu_probe")
    fn(((n + 255) // 256,), (256,), (cp.asarray(a), cp.asarray(b),
                                     d_out, np.int32(n)))
    got = cp.asnumpy(d_out).view(np.uint32)
    bad = np.flatnonzero(got != want)
    assert bad.size == 0, (
        f"fzu: {bad.size}/{n} rows differ; first alpha=0x{rows[bad[0]][0]:08X} "
        f"beta=0x{rows[bad[0]][1]:08X}")
