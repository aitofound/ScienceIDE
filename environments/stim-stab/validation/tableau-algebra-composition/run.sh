#!/usr/bin/env bash
KNOB_HELP=""
CHECK_DIR="${CHECK_DIR:-$(cd "$(dirname "${BASH_SOURCE[0]}")" && pwd -P)}"
DEF() { python3 -c "import json,sys;print(json.load(open(sys.argv[1]))[sys.argv[2]])" "$CHECK_DIR/ic/nominal/params.json" "$1"; }
knob() { local name=$1 default=$2 desc=$3; [ -n "${!name:-}" ] || printf -v "$name" '%s' "$default"; export "$name"; KNOB_HELP+="$name=$default  $desc"$'\n'; }
# Parallel build jobs default to the CPUs this container may use (cgroup v2 cpu.max), not the host
# count. Ninja's own default is nproc+2 and nproc reports the HOST's cores even under
# `docker run --cpus`, so on a many-core grading host an unbounded build starts ~90 g++ processes
# inside the declared 4 GB and the container is OOM-killed before run.sh prints anything.
cpus_allowed() { local q p; if [ -r /sys/fs/cgroup/cpu.max ] && read -r q p < /sys/fs/cgroup/cpu.max && [ "$q" != max ]; then echo $(( (q + p - 1) / p )); else nproc 2>/dev/null || getconf _NPROCESSORS_ONLN; fi; }
knob SAB_DIM "$(DEF dim)" "tableau dimension (default: ic params). Tableau composition is O(dim^3) bit operations across simd_bits words, so this is the workload knob"
knob SAB_COMPOSITIONS "$(DEF n_compositions)" "successive compositions applied (default: ic params). Linear in runtime"
knob SAB_BUILD_JOBS "$(cpus_allowed)" "parallel jobs for this check's one build of the pinned source (default: the CPUs this container may use). Build time only; it does not touch the graded output"
# Alternative build. -DSIMD_WIDTH=128 is stim's own knob: CMakeLists.txt:25-35
# turns it into -mno-avx2 -msse2, so simd_word.h:28-34 resolves MAX_BITWORD_WIDTH
# to 128 and the build compiles bitword_128_sse instead of the host-native
# bitword_256_avx. Same compiler, same -O3 Release flags, same source, same
# nominal inputs - the alternative machine the codebase's own --seed CAUTION
# names ("a machine that supports AVX instructions and one that only supports
# SSE instructions may produce different simulation results").
ALTBUILD="the same pinned source configured with -DSIMD_WIDTH=128, which CMakeLists.txt:25-35 turns into -mno-avx2 -msse2 so stim compiles the SSE2 bitword_128 word backend instead of the host-native AVX2 bitword_256, with the same compiler, the same -O3 Release flags and ic/nominal unchanged: a build a correct candidate could plausibly be, and the one stim's own --seed CAUTION names. It takes effect only on x86_64, where stim's machine flags apply; off x86_64 run.sh altbuild refuses rather than report a floor that would mean nothing"
if [ "${1:-}" = "--help" ]; then printf '%s' "$KNOB_HELP"; [ -z "$ALTBUILD" ] || echo "altbuild: $ALTBUILD"; exit 0; fi

set -euo pipefail
IC="${1:?usage: run.sh <nominal|variant|altbuild> | run.sh --help}"
: "${SOURCE_DIR:?}" "${OUT_DIR:?}" "${CHECK_DIR:?}"
INPUTS="$IC"; CMAKE_EXTRA=()
if [ "$IC" = altbuild ]; then
  [ -n "$ALTBUILD" ] || { echo "run.sh: this check declares no alternative build" >&2; exit 2; }
  INPUTS=nominal; CMAKE_EXTRA=(-DSIMD_WIDTH=128)
fi
[ -d "$CHECK_DIR/ic/$INPUTS" ] || { echo "run.sh: no initial condition ic/$INPUTS" >&2; exit 2; }
WORK="$(mktemp -d)"; trap 'rm -rf "$WORK"' EXIT
cp -R "$SOURCE_DIR/." "$WORK/src"

BUILD_START=$(date +%s)
# The Python module is the observable: stim's CLI exposes no tableau or
# Pauli-string surface, so these checks grade through the bindings that
# CMakeLists.txt:95-97 builds only when pybind11 is found. pybind11 must satisfy
# code/stim/pyproject.toml's `pybind11~=2.11.1`; the image pins it via pip.
cmake -S "$WORK/src" -B "$WORK/b" -G Ninja -DCMAKE_BUILD_TYPE=Release "${CMAKE_EXTRA[@]}" \
      -Dpybind11_DIR="$(python3 -m pybind11 --cmakedir)" >"$WORK/cmake.log" 2>&1

# The machine flag this configure resolved, read from the generated ninja file:
# ninja prints targets and not command lines, so the flags never reach cmake.log.
# `|| true`: grep exits 1 when it matches nothing, and under `set -o pipefail`
# that failed the assignment and killed run.sh silently, before it printed
# anything - on every host where stim resolves no machine flags, which is every
# non-x86_64 host. The empty case is legitimate and the guard below handles it.
MFLAG="$(grep -hoE -- '-march=native|-mno-avx2|-mavx2|-mno-sse2|-msse2' "$WORK/b/build.ninja" 2>/dev/null | sort -u | tr '\n' ' ' || true)"
# An altbuild that did not actually change the build would report a floor of 0 for
# every check and mean nothing, so it fails loudly instead. Stim guards its machine
# flags on CMAKE_SYSTEM_PROCESSOR (CMakeLists.txt:25) and every one of them is x86,
# so -DSIMD_WIDTH has no effect off x86_64.
case "$IC:$MFLAG" in
  altbuild:*-mno-avx2*) ;;
  altbuild:*) echo "run.sh: altbuild asked for -DSIMD_WIDTH=128 but this configure resolved machine flags '${MFLAG:-none}', so the alternative build is identical to the nominal one and its floor would be meaningless. Run the altbuild on an x86_64 host (the curator's ruling puts this leaf's official run on x86_64 with AVX2), or declare altbuild as \"none: <reason>\" for this host." >&2; exit 1 ;;
esac
cmake --build "$WORK/b" --target stim_python_bindings -j "$SAB_BUILD_JOBS" >>"$WORK/cmake.log" 2>&1
echo "SAB_BUILD_SECONDS=$(( $(date +%s) - BUILD_START ))"
MOD="$(find "$WORK/b" -name 'stim*.so' | head -1)"
[ -n "$MOD" ] || { cp "$WORK/cmake.log" "$OUT_DIR/cmake-failed.log" 2>/dev/null; echo "run.sh: stim python module not built; see cmake-failed.log" >&2; exit 1; }

# Which vector word backend this build actually compiled, resolved exactly the
# way src/stim/mem/simd_word.h:28-34 resolves it: __AVX2__ -> bitword_256_avx,
# __SSE2__ -> bitword_128_sse, otherwise bitword_64. Stim's machine flags are
# guarded on CMAKE_SYSTEM_PROCESSOR (CMakeLists.txt:25) and its backends are
# x86-only, so the same source yields bitword_256_avx on an AVX2 host,
# bitword_128_sse under the altbuild's SIMD_WIDTH=128, and the portable
# bitword_64 where no flag applies. The incumbent is meaningless without this,
# so it is written beside the graded output rather than inferred.
{ echo "${MFLAG:-no-machine-flag}"
  ${CXX:-c++} ${MFLAG} -dM -E -x c++ /dev/null 2>/dev/null |
    awk '/define __AVX2__/{a=1} /define __SSE2__/{s=1} END{print (a ? "bitword_256_avx" : (s ? "bitword_128_sse" : "bitword_64"))}'
  uname -m; } > "$OUT_DIR/word_backend.txt"

PARAMS="$CHECK_DIR/ic/$INPUTS/params.json" OUT="$OUT_DIR" MOD="$MOD" python3 - <<'PYEOF'
import json, os, sys, importlib.util
import numpy as np
spec = importlib.util.spec_from_file_location("stim", os.environ["MOD"])
stim = importlib.util.module_from_spec(spec); spec.loader.exec_module(stim)
p = json.load(open(os.environ["PARAMS"])); out = os.environ["OUT"]

# stim.Tableau.random(num_qubits) takes NO seed and is genuinely
# non-deterministic - verified: two unseeded random(8) calls compare unequal.
# Using it would make every run a different instance, so with identical initial
# conditions the two solves would disagree at order one and the check could
# never pass. Build the Clifford deterministically instead: a fixed-length
# sequence of named gates chosen by a seeded numpy RNG. Verified reproducible
# for a given seed and distinct across seeds.
def det_tableau(dim, seed):
    rng = np.random.default_rng(seed)
    t = stim.Tableau(dim)
    names = ["H", "S", "CNOT", "CZ", "SWAP"]
    for _ in range(4 * dim):
        g = names[int(rng.integers(0, len(names)))]
        if g in ("H", "S"):
            q = int(rng.integers(0, dim))
            t.append(stim.Tableau.from_named_gate(g), [q])
        else:
            a, b = rng.choice(dim, size=2, replace=False)
            t.append(stim.Tableau.from_named_gate(g), [int(a), int(b)])
    return t

dim = int(os.environ.get("SAB_DIM") or p["dim"])
n   = int(os.environ.get("SAB_COMPOSITIONS") or p["n_compositions"])

t = det_tableau(dim, int(p["seed"]))
acc = stim.Tableau(dim)
for i in range(n):
    acc = acc.then(t)

# to_numpy() returns the four bit blocks (x2x, x2z, z2x, z2z) plus the two sign
# vectors: the packed bit-table representation exactly as stored. This is the
# module owning its own data layout, graded without reinterpretation.
blocks = acc.to_numpy()
for name, arr in zip(("x2x","x2z","z2x","z2z","x_signs","z_signs"), blocks):
    np.save(os.path.join(out, f"acc_{name}.npy"), np.ascontiguousarray(arr).astype(np.uint8))

# The inverse round-trip is a structural invariant: composing with the inverse
# must give the identity exactly. A port that broke composition or inversion
# fails this even if its individual blocks looked plausible.
ident = (acc.then(acc.inverse())) == stim.Tableau(dim)
np.save(os.path.join(out, "inverse_roundtrip.npy"), np.array([1 if ident else 0], dtype=np.uint8))

print(f"dim={dim} compositions={n} identity_roundtrip={ident} "
      f"popcount_x2x={int(np.asarray(blocks[0]).sum())}")
PYEOF
