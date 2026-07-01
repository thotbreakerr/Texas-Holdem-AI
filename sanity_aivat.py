"""
sanity_aivat.py — covers equity, icm, aivat
--------------------------------------------
Gate 1 sanity coverage for core/equity.py, core/icm.py, core/aivat.py.
"""
import sys
import random
import math
sys.path.insert(0, ".")

from core.equity import equity, equity_bucket
from core.icm import equities as icm_equities, equity_delta
from core.aivat import value as aivat_value, Snapshot
from bots.icm_bot import icm_equity as bot_icm_equity

PASS = True
rounds = 50  # average over 50 calls for stable MC numbers


def avg_equity(hole, board, n_opp, n_sims=200):
    total = sum(equity(hole, board, n_opp, n_sims=n_sims) for _ in range(rounds))
    return total / rounds


def decay_payouts(n, decay=0.6):
    raw = [decay ** i for i in range(n)]
    total = sum(raw)
    return [x / total for x in raw]


def default_committed(pot, alive):
    live = [i for i, is_alive in enumerate(alive) if is_alive]
    committed = [0] * len(alive)
    if not live:
        return tuple(committed)
    base = pot // len(live)
    remainder = pot % len(live)
    for idx, seat in enumerate(live):
        committed[seat] = base + (1 if idx < remainder else 0)
    return tuple(committed)


# ═══════════════════════════════════════════════════════════════════════════
#  EQUITY TESTS
# ═══════════════════════════════════════════════════════════════════════════

print("=" * 60)
print("EQUITY: Preflop absolute bounds")
print("=" * 60)

# AA vs random heads-up ≈ 0.85
aa = [("A", "h"), ("A", "s")]
eq_aa = avg_equity(aa, [], 1, n_sims=200)
print(f"  AA vs 1 random: {eq_aa:.4f} (expect ~0.85)")
if abs(eq_aa - 0.85) < 0.03:
    print("  [PASS]")
else:
    print(f"  [FAIL] (delta = {abs(eq_aa - 0.85):.4f})")
    PASS = False

# AKs vs random ≈ 0.67
aks = [("A", "h"), ("K", "h")]
eq_aks = avg_equity(aks, [], 1, n_sims=200)
print(f"  AKs vs 1 random: {eq_aks:.4f} (expect ~0.67)")
if abs(eq_aks - 0.67) < 0.03:
    print("  [PASS]")
else:
    print(f"  [FAIL] (delta = {abs(eq_aks - 0.67):.4f})")
    PASS = False

# 72o vs random ≈ 0.35
bad = [("7", "h"), ("2", "s")]
eq_bad = avg_equity(bad, [], 1, n_sims=200)
print(f"  72o vs 1 random: {eq_bad:.4f} (expect ~0.35)")
if abs(eq_bad - 0.35) < 0.03:
    print("  [PASS]")
else:
    print(f"  [FAIL] (delta = {abs(eq_bad - 0.35):.4f})")
    PASS = False

print()

# Multiway monotonicity: AQ on A72 board
print("=" * 60)
print("EQUITY: Multiway monotonicity (AQ on A72)")
print("=" * 60)

hole_aq = [("A", "h"), ("Q", "s")]
board_a72 = [("A", "s"), ("7", "d"), ("2", "c")]
eq_1 = avg_equity(hole_aq, board_a72, 1)
eq_2 = avg_equity(hole_aq, board_a72, 2)
eq_5 = avg_equity(hole_aq, board_a72, 5)
print(f"  n_opp=1: {eq_1:.4f}, n_opp=2: {eq_2:.4f}, n_opp=5: {eq_5:.4f}")
if eq_1 > eq_2 > eq_5:
    print("  [PASS] — monotonically decreasing")
else:
    print("  [FAIL] — NOT monotonically decreasing")
    PASS = False

# Heads-up symmetry: P1 + P2 ≈ 1.0
print()
print("EQUITY: Heads-up symmetry")
random.seed(42)
total_sym = 0.0
trials = 20
for _ in range(trials):
    h1 = random.sample([c for c in [("A","h"),("K","s"),("Q","d"),("J","c"),("T","h"),
                                     ("9","s"),("8","d"),("7","c"),("6","h"),("5","s")]], 2)
    eq1 = equity(h1, [], 1, n_sims=500)
    total_sym += eq1
avg_sym = total_sym / trials
# On average over random matchups, hero equity should be ~0.5
print(f"  Average hero equity over {trials} random matchups: {avg_sym:.4f}")
if abs(avg_sym - 0.5) < 0.05:
    print("  [PASS] — close to 0.5")
else:
    print(f"  [FAIL] — expected ~0.5")
    PASS = False

# Tie handling: AA vs AA → 0.5
print()
print("EQUITY: Tie handling (AA vs AA)")
# We can't do AA vs AA directly with equity() since it samples random opponents.
# But we can verify the tie logic by noting AA vs random should be high.
# Instead, verify conceptually: equity with n_sims should handle ties.
eq_tie = equity([("A","h"),("A","s")], [("A","d"),("A","c"),("K","h"),("K","d"),("K","s")], 1, n_sims=500)
# With the board AAAKKK, hero has AA and the best 5-card hand is AAAKK.
# Any random opponent hand can at best make AAKKK or AAKKx.
# Hero always wins or ties here.
print(f"  AA on AAAKK board: equity = {eq_tie:.4f} (expect very high)")
if eq_tie >= 0.4:
    print("  [PASS]")
else:
    print("  [FAIL]")
    PASS = False

print()

# ═══════════════════════════════════════════════════════════════════════════
#  ICM TESTS
# ═══════════════════════════════════════════════════════════════════════════

print("=" * 60)
print("ICM: Basic tests")
print("=" * 60)

# Total equity sums to 1.0
wta = [1.0, 0.0, 0.0]
stacks_3 = [800, 100, 100]
eq = icm_equities(stacks_3, wta)
total_eq = sum(eq)
print(f"  Stacks {stacks_3}, WTA payouts: equities = {[f'{e:.4f}' for e in eq]}")
print(f"  Sum = {total_eq:.4f}")
if abs(total_eq - 1.0) < 0.001:
    print("  [PASS] — sums to 1.0")
else:
    print("  [FAIL] — does NOT sum to 1.0")
    PASS = False

# Stack leader > 0.8
if eq[0] >= 0.8:
    print(f"  Stack leader equity {eq[0]:.4f} >= 0.8  [PASS]")
else:
    print(f"  Stack leader equity {eq[0]:.4f} < 0.8  [FAIL]")
    PASS = False

# Short stacks <= 0.1 each
if eq[1] <= 0.1 and eq[2] <= 0.1:
    print(f"  Short stacks {eq[1]:.4f}, {eq[2]:.4f} both <= 0.1  [PASS]")
else:
    print(f"  Short stacks {eq[1]:.4f}, {eq[2]:.4f}  [FAIL]")
    PASS = False

# Heads-up equal stacks → [0.5, 0.5]
wta2 = [1.0, 0.0]
eq_hu = icm_equities([500, 500], wta2)
print(f"  Equal stacks HU: {[f'{e:.4f}' for e in eq_hu]}")
if abs(eq_hu[0] - 0.5) < 0.001 and abs(eq_hu[1] - 0.5) < 0.001:
    print("  [PASS] — [0.5, 0.5]")
else:
    print("  [FAIL]")
    PASS = False

# Busted players (stack=0) → 0 equity
eq_busted = icm_equities([800, 0, 200], [1.0, 0.0, 0.0])
print(f"  Busted player: equities = {[f'{e:.4f}' for e in eq_busted]}")
if eq_busted[1] == 0.0:
    print("  [PASS] — busted player has 0 equity")
else:
    print("  [FAIL] — busted player has non-zero equity")
    PASS = False

# 2-player ICM = chip ratio in winner-take-all
eq_ratio = icm_equities([700, 300], [1.0, 0.0])
print(f"  2-player WTA [700, 300]: {[f'{e:.4f}' for e in eq_ratio]}")
if abs(eq_ratio[0] - 0.7) < 0.001 and abs(eq_ratio[1] - 0.3) < 0.001:
    print("  [PASS] — matches chip ratio")
else:
    print("  [FAIL]")
    PASS = False

# Non-WTA payouts should sum to 1 and compress the chip leader below chip share
top_heavy_3 = decay_payouts(3, decay=0.6)
eq_non_wta = icm_equities(stacks_3, top_heavy_3)
print(f"  3-player non-WTA payouts: {[f'{p:.3f}' for p in top_heavy_3]}")
print(f"  Non-WTA equities: {[f'{e:.4f}' for e in eq_non_wta]}")
if abs(sum(eq_non_wta) - 1.0) < 0.001:
    print("  [PASS] — non-WTA equities sum to 1.0")
else:
    print("  [FAIL] — non-WTA equities do not sum to 1.0")
    PASS = False
chip_share = stacks_3[0] / sum(stacks_3)
if eq_non_wta[0] < chip_share:
    print("  [PASS] — leader equity below chip share with place payouts")
else:
    print(f"  [FAIL] — leader equity {eq_non_wta[0]:.4f} >= chip share {chip_share:.4f}")
    PASS = False

# ICMBot consumes core.icm with non-WTA payouts; smoke the 6-player path.
bot_stacks = {"P1": 1500, "P2": 900, "P3": 800, "P4": 700, "P5": 600, "P6": 500}
bot_eq = bot_icm_equity(bot_stacks)
bot_total = sum(bot_eq.values())
print(f"  ICMBot 6-player equity sum: {bot_total:.4f}")
if abs(bot_total - 1.0) < 0.001 and all(v >= 0 for v in bot_eq.values()):
    print("  [PASS] — ICMBot non-WTA equities are sane")
else:
    print("  [FAIL] — ICMBot non-WTA equities invalid")
    PASS = False

print()

# ═══════════════════════════════════════════════════════════════════════════
#  AIVAT CHIP-EV TESTS
# ═══════════════════════════════════════════════════════════════════════════

print("=" * 60)
print("AIVAT: chip-EV tests")
print("=" * 60)

# Helper to build a snapshot
def _snap(hero_hole, opp_hole, board=(), pot=100, stacks=(1000, 1000),
          alive=(True, True), to_call=0, hero_committed=0,
          committed_per_seat=None):
    if committed_per_seat is None:
        committed_per_seat = default_committed(pot, alive)
    return Snapshot(
        hole_cards={0: tuple(hero_hole), 1: tuple(opp_hole)},
        board=tuple(board),
        pot=pot,
        stacks=tuple(stacks),
        alive=tuple(alive),
        to_call=to_call,
        hero_committed=hero_committed,
        committed_per_seat=tuple(committed_per_seat),
    )

# AA preflop heads-up: value ≈ equity_AA * pot > 0.7 * pot
random.seed(123)
snap_aa = _snap([("A","h"),("A","s")], [("7","c"),("2","d")], pot=100)
val_aa = aivat_value(snap_aa, hero_seat=0, n_sims=300)
print(f"  AA preflop HU: value = {val_aa:.2f}, pot = 100")
if val_aa > 0.7 * 100:
    print(f"  [PASS] — value > 70 (0.7 * pot)")
else:
    print(f"  [FAIL] — expected value > 70")
    PASS = False

# 72o preflop HU: value ≈ equity_72o * pot < 0.4 * pot
snap_72 = _snap([("7","h"),("2","s")], [("A","c"),("K","d")], pot=100)
val_72 = aivat_value(snap_72, hero_seat=0, n_sims=300)
print(f"  72o preflop HU: value = {val_72:.2f}, pot = 100")
if val_72 < 0.4 * 100:
    print(f"  [PASS] — value < 40 (0.4 * pot)")
else:
    print(f"  [FAIL] — expected value < 40")
    PASS = False

# Monotonicity: value(AA) > value(AKs) > value(72o)
snap_aks = _snap([("A","h"),("K","h")], [("7","c"),("2","d")], pot=100)
val_aks = aivat_value(snap_aks, hero_seat=0, n_sims=300)
print(f"  AKs preflop HU: value = {val_aks:.2f}")
if val_aa > val_aks > val_72:
    print("  [PASS] — AA > AKs > 72o")
else:
    print(f"  [FAIL] — AA={val_aa:.2f}, AKs={val_aks:.2f}, 72o={val_72:.2f}")
    PASS = False

# Hero already folded → value = 0
snap_folded = _snap([("A","h"),("A","s")], [("7","c"),("2","d")],
                     pot=100, alive=(False, True))
val_folded = aivat_value(snap_folded, hero_seat=0)
print(f"  Hero folded: value = {val_folded:.4f}")
if val_folded == 0.0:
    print("  [PASS] — exactly 0")
else:
    print("  [FAIL] — expected 0")
    PASS = False

# All opponents folded → value = pot
snap_uncontested = _snap([("A","h"),("A","s")], [("7","c"),("2","d")],
                          pot=100, alive=(True, False))
val_unc = aivat_value(snap_uncontested, hero_seat=0)
print(f"  All opponents folded: value = {val_unc:.2f}, pot = 100")
if val_unc == 100.0:
    print("  [PASS] — equals pot")
else:
    print(f"  [FAIL] — expected 100.0, got {val_unc}")
    PASS = False

# Side-pot: stack-limited hero
snap_side = _snap([("A","h"),("A","s")], [("7","c"),("2","d")],
                   pot=300, stacks=(100, 1000), alive=(True, True))
val_side = aivat_value(snap_side, hero_seat=0, n_sims=300)
print(f"  Side-pot (hero stack=100, pot=300): value = {val_side:.2f}")
if not math.isnan(val_side) and math.isfinite(val_side):
    print("  [PASS] — finite, non-NaN")
else:
    print("  [FAIL] — NaN or infinite")
    PASS = False

# Asymmetric side pot: hero has the best hand but can only win the main pot.
snap_asym_side = Snapshot(
    hole_cards={
        0: (("A","h"),("A","s")),
        1: (("7","c"),("2","d")),
        2: (("8","c"),("3","d")),
    },
    board=(("K","h"),("Q","d"),("J","c"),("T","s"),("4","h")),
    pot=900,
    stacks=(0, 700, 500),
    alive=(True, True, True),
    to_call=0,
    hero_committed=100,
    committed_per_seat=(100, 300, 500),
)
val_asym_side = aivat_value(snap_asym_side, hero_seat=0)
print(f"  Asymmetric side pot value: {val_asym_side:.2f} (expect 300.00)")
if abs(val_asym_side - 300.0) < 1e-9:
    print("  [PASS] — hero wins main pot only")
else:
    print("  [FAIL] — side-pot settlement awarded wrong hero share")
    PASS = False

side_payouts = decay_payouts(3, decay=0.6)
val_asym_tournament = aivat_value(
    snap_asym_side, hero_seat=0, mode="tournament", payouts=side_payouts
)
expected_side_stacks = [300, 700, 1100]
# Chip-conserving fold baseline: hero (seat 0) folds and forfeits the 900 pot,
# which the remaining players split proportionally to their stacks (700:500),
# giving [0, 1225, 875].  Both worlds total 2100 chips, so the ICM-equity
# difference is a valid delta.  (Comparing against the bare current stacks —
# total 1200 — was non-conserving and biased the value downward.)
expected_fold_stacks = [0, 1225, 875]
assert sum(expected_fold_stacks) == sum(expected_side_stacks), \
    "fold baseline must conserve chips with the play world"
expected_side_delta = (
    icm_equities(expected_side_stacks, side_payouts)[0] -
    icm_equities(expected_fold_stacks, side_payouts)[0]
)
print(f"  Tournament side-pot delta: {val_asym_tournament:.6f}")
if abs(val_asym_tournament - expected_side_delta) < 1e-9:
    print("  [PASS] — tournament value uses chip-conserving fold baseline")
else:
    print("  [FAIL] — tournament side-pot ICM delta mismatch")
    PASS = False

# River: deterministic, same value on repeated calls
snap_river = _snap(
    [("A","h"),("A","s")], [("7","c"),("2","d")],
    board=(("K","h"),("Q","d"),("J","c"),("T","s"),("3","h")),
    pot=200,
)
val_r1 = aivat_value(snap_river, hero_seat=0)
val_r2 = aivat_value(snap_river, hero_seat=0)
print(f"  River deterministic: val1 = {val_r1:.2f}, val2 = {val_r2:.2f}")
if val_r1 == val_r2:
    print("  [PASS] — identical on repeated calls")
else:
    print("  [FAIL] — different values")
    PASS = False

# Empty board (preflop) returns sane value
snap_preflop = _snap([("A","h"),("K","s")], [("Q","c"),("J","d")], pot=50)
val_pf = aivat_value(snap_preflop, hero_seat=0, n_sims=200)
print(f"  Preflop snapshot: value = {val_pf:.2f}")
if not math.isnan(val_pf) and math.isfinite(val_pf) and val_pf >= 0:
    print("  [PASS] — sane value")
else:
    print("  [FAIL]")
    PASS = False

# All-in state: no further decisions
snap_allin = _snap(
    [("A","h"),("A","s")], [("K","c"),("K","d")],
    board=(("Q","h"),("J","d"),("T","c")),
    pot=2000, stacks=(0, 0), alive=(True, True),
)
val_allin = aivat_value(snap_allin, hero_seat=0, n_sims=200)
print(f"  All-in state: value = {val_allin:.2f}")
if not math.isnan(val_allin) and math.isfinite(val_allin):
    print("  [PASS] — sane value")
else:
    print("  [FAIL]")
    PASS = False

print()

# ═══════════════════════════════════════════════════════════════════════════
#  AIVAT TOURNAMENT TESTS
# ═══════════════════════════════════════════════════════════════════════════

print("=" * 60)
print("AIVAT: tournament tests")
print("=" * 60)

payouts_non_wta = decay_payouts(6, decay=0.6)
loss_board = (("K","h"),("Q","d"),("J","c"),("T","s"),("4","h"))
loss_holes = {
    0: (("7","c"),("2","d")),
    1: (("A","h"),("A","s")),
    2: (("8","h"),("3","s")),
    3: (("9","c"),("4","d")),
    4: (("T","h"),("5","s")),
    5: (("J","c"),("6","d")),
}

# Chip-loss framing: same losing all-in pot, but with a near-bust player
# elsewhere. Non-WTA payouts make survival pressure visible.
snap_early = Snapshot(
    hole_cards=loss_holes,
    board=loss_board,
    pot=200,
    stacks=(100, 900, 1000, 1000, 1000, 1000),
    alive=(True, True, False, False, False, False),
    to_call=100,
    hero_committed=100,
    committed_per_seat=(100, 100, 0, 0, 0, 0),
)
snap_bubble = Snapshot(
    hole_cards=loss_holes,
    board=loss_board,
    pot=200,
    stacks=(100, 900, 1000, 1000, 1000, 50),
    alive=(True, True, False, False, False, False),
    to_call=100,
    hero_committed=100,
    committed_per_seat=(100, 100, 0, 0, 0, 0),
)
val_early = aivat_value(snap_early, hero_seat=0, mode="tournament",
                         payouts=payouts_non_wta)
val_bubble = aivat_value(snap_bubble, hero_seat=0, mode="tournament",
                          payouts=payouts_non_wta)

# With a chip-conserving fold baseline, a LOSING showdown forfeits exactly the
# pot the hero would forfeit by folding, so the tournament delta is ~0 in both
# scenarios.  (The old non-conserving baseline manufactured a spurious nonzero,
# stack-dependent value, which this test previously relied on.)
print(f"  Early-game losing value: {val_early:.6f}")
print(f"  Bubble losing value: {val_bubble:.6f}")
if abs(val_early) < 1e-9 and abs(val_bubble) < 1e-9:
    print("  [PASS] — losing showdown ≈ folding (chip-conserving baseline)")
else:
    print(f"  [FAIL] — losing tournament value should be ~0 "
          f"(early={val_early:.6f}, bubble={val_bubble:.6f})")
    PASS = False

# A WINNING all-in must gain positive tournament equity over folding.
win_holes = dict(loss_holes)
win_holes[0] = (("A","h"),("A","s"))
win_holes[1] = (("7","c"),("2","d"))
snap_win = Snapshot(
    hole_cards=win_holes,
    board=loss_board,
    pot=200,
    stacks=(100, 900, 1000, 1000, 1000, 1000),
    alive=(True, True, False, False, False, False),
    to_call=0,
    hero_committed=100,
    committed_per_seat=(100, 100, 0, 0, 0, 0),
)
val_win = aivat_value(snap_win, hero_seat=0, mode="tournament",
                      payouts=payouts_non_wta)
print(f"  Winning all-in value: {val_win:.6f}")
if val_win > 0:
    print("  [PASS] — winning showdown gains ICM equity over folding")
else:
    print(f"  [FAIL] — winning tournament value should be > 0 (got {val_win:.6f})")
    PASS = False

# Tournament value bounded by [-1, 1]
print(f"  |early| = {abs(val_early):.6f}, |bubble| = {abs(val_bubble):.6f}")
if abs(val_early) <= 1.0 and abs(val_bubble) <= 1.0:
    print("  [PASS] — tournament values bounded by [-1, 1]")
else:
    print("  [FAIL] — tournament value out of bounds")
    PASS = False

print()

if "--diagnostic" in sys.argv:
    # This is only a toy diagnostic: it compares a conditional expectation
    # against a Bernoulli sampled outcome. A real variance-reduction test would
    # use paired poker trajectories and a control variate at decision points.
    print("=" * 60)
    print("[DIAGNOSTIC] AIVAT: toy variance comparison")
    print("=" * 60)

    random.seed(42)
    chip_deltas = []
    aivat_values = []

    for i in range(200):
        hero_hole = tuple(random.sample([c for c in
            [("A","h"),("K","s"),("Q","d"),("J","c"),("T","h"),("9","s"),("8","d"),
             ("7","c"),("6","h"),("5","s"),("4","d"),("3","c"),("2","h")]
        ], 2))
        opp_hole = tuple(random.sample([c for c in
            [("A","d"),("K","c"),("Q","h"),("J","s"),("T","d"),("9","c"),("8","h"),
             ("7","s"),("6","d"),("5","c"),("4","h"),("3","s"),("2","d")]
        ], 2))

        pot = random.randint(20, 200)
        snap = Snapshot(
            hole_cards={0: hero_hole, 1: opp_hole},
            board=(),
            pot=pot,
            stacks=(1000, 1000),
            alive=(True, True),
            to_call=0,
            hero_committed=0,
            committed_per_seat=default_committed(pot, (True, True)),
        )

        av = aivat_value(snap, hero_seat=0, n_sims=50)
        aivat_values.append(av)

        eq = equity(list(hero_hole), [], 1, n_sims=50)
        chip_deltas.append(pot if random.random() < eq else 0)

    mean_cd = sum(chip_deltas) / len(chip_deltas)
    var_cd = sum((x - mean_cd)**2 for x in chip_deltas) / len(chip_deltas)

    mean_av = sum(aivat_values) / len(aivat_values)
    var_av = sum((x - mean_av)**2 for x in aivat_values) / len(aivat_values)

    print(f"  Chip delta variance: {var_cd:.2f}")
    print(f"  AIVAT value variance: {var_av:.2f}")
    ratio = var_av / var_cd if var_cd > 0 else float('inf')
    print(f"  Ratio (aivat/chip): {ratio:.4f}")
    print()

# ═══════════════════════════════════════════════════════════════════════════
#  LEAF THROUGHPUT KNOBS (2026-07-01): max_enumerate + LeafScoreCache
# ═══════════════════════════════════════════════════════════════════════════

print("=" * 60)
print("AIVAT: max_enumerate / LeafScoreCache (Path A throughput fix)")
print("=" * 60)

from core.aivat import LeafScoreCache

_leaf_hole = {
    0: (("A", "s"), ("K", "s")),
    1: (("Q", "h"), ("Q", "d")),
    2: (("7", "c"), ("2", "c")),
}
_leaf_flop = Snapshot(
    hole_cards=_leaf_hole,
    board=(("K", "h"), ("8", "d"), ("3", "c")),
    pot=120, stacks=(900, 900, 900), alive=(True, True, True),
    to_call=0, hero_committed=40, committed_per_seat=(40, 40, 40),
)
_leaf_turn = Snapshot(
    hole_cards=_leaf_hole,
    board=(("K", "h"), ("8", "d"), ("3", "c"), ("9", "h")),
    pot=120, stacks=(900, 900, 900), alive=(True, True, True),
    to_call=0, hero_committed=40, committed_per_seat=(40, 40, 40),
)

# 1. Defaults unchanged: no cap + no cache is the historical exact path.
v_exact = aivat_value(_leaf_flop, hero_seat=0)
print(f"  Flop exact value: {v_exact:.3f}")

# 2. Cache with no cap must be bit-identical to exact (pure memoization).
v_cached = aivat_value(_leaf_flop, hero_seat=0, cache=LeafScoreCache())
print(f"  Cache-only == exact: {v_cached == v_exact}")
if v_cached == v_exact:
    print("  [PASS] — LeafScoreCache is value-neutral")
else:
    PASS = False
    print(f"  [FAIL] — cache changed the value ({v_cached:.6f} vs {v_exact:.6f})")

# 3. Turn stays exact under any cap >= 44 remaining rivers.
v_turn_exact = aivat_value(_leaf_turn, hero_seat=0)
v_turn_capped = aivat_value(_leaf_turn, hero_seat=0, max_enumerate=120)
if v_turn_capped == v_turn_exact:
    print("  [PASS] — turn enumeration untouched by cap 120")
else:
    PASS = False
    print(f"  [FAIL] — turn value changed under cap "
          f"({v_turn_capped:.6f} vs {v_turn_exact:.6f})")

# 4. Capped flop sampling lands near exact (avg over rounds vs MC noise).
random.seed(20260701)
samp = sum(
    aivat_value(_leaf_flop, hero_seat=0, max_enumerate=120)
    for _ in range(rounds)
) / rounds
rel_err = abs(samp - v_exact) / v_exact
print(f"  Flop sampled(120) avg over {rounds}: {samp:.3f} "
      f"(exact {v_exact:.3f}, rel err {rel_err:.2%})")
if rel_err < 0.05:
    print("  [PASS] — sampled flop value within 5% of exact")
else:
    PASS = False
    print("  [FAIL] — sampled flop value drifted from exact")

# 5. Cache reuse: a second identical call must not consume RNG (the
#    completion set and scores are memoized for the traversal).
_c = LeafScoreCache()
random.seed(7)
v1 = aivat_value(_leaf_flop, hero_seat=0, max_enumerate=120, cache=_c)
_rng_state = random.getstate()
v2 = aivat_value(_leaf_flop, hero_seat=0, max_enumerate=120, cache=_c)
if v1 == v2 and random.getstate() == _rng_state:
    print("  [PASS] — cached leaf re-eval is free (no RNG, same value)")
else:
    PASS = False
    print("  [FAIL] — cache did not short-circuit the second evaluation")
print()

# ═══════════════════════════════════════════════════════════════════════════
#  OVERALL
# ═══════════════════════════════════════════════════════════════════════════

print("=" * 60)
if PASS:
    print("ALL CHECKS PASSED [PASS]")
else:
    print("SOME CHECKS FAILED [FAIL]")
    sys.exit(1)
print("=" * 60)
