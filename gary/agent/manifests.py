"""Gary versions as manifests: one provider per layer (docs/CONTROL.md), and building a Gary from one.

A version is a choice per layer, nothing more. To try a variant, copy a manifest and change the
layer you're testing; everything else stays the same Gary.

    from gary.agent.manifests import build_gary
    gary = build_gary(hi, mapinfo, "v09", style=1)
"""

from __future__ import annotations

import os

import copy
from pathlib import Path

from gary.agent.army import LearnedArmy, WaveArmy
from gary.agent.arbiter import DrillArbiter, FixedPriority
from gary.agent.terran_executor import TerranExecutor
from gary.agent.zerg_executor import ZergExecutor
from gary.agent.protoss_executor import ProtossExecutor
from gary.agent.fight import RULES, FightLayer, PullRule
from gary.agent.gary import Gary
from gary.agent.macro import LearnedMacro, LingFloodDefense, OneBaseDefense
from gary.agent.motor import DirectMotor
from gary.agent.posture import (EarlyPoolPosture, EarlyPoolPostureV2, EarlyPoolPostureV3, EarlyPoolPostureV4,
                                EarlyPoolPostureV5, EarlyPoolPostureV6, NormalPosture)
from gary.version import announcement

REPO_ROOT = Path(__file__).resolve().parent.parent.parent
# the fight model v0.8 was judged with (RL run 4, round 70: 114 home defenses -61); later runs don't
# replace it unless they beat it and this is updated
V08_FIGHT_MODEL = REPO_ROOT / "runs" / "fight_cmd_rl" / "home_defense_20261005_091044" / "model.pt"

_LEARNED = {"provider": "learned", "model": "macro/latest"}
_ARMY = {"provider": "learned", "model": "army/latest"}
_V09_FIGHT = {"provider": "command", "model": "fight_cmd_rl/v08", "before": ["repair", "pull", "load"],
              "in_fight": ["reinforce"], "workers": False}
# what a Terran manifest built for TvZ plays against a non-Zerg (its "vs" section, by the enemy's race): the
# early-pool posture, the scripted rush builds, the answers to the Zerg's plan, the natural bunker and the
# strategy selector's TvZ table are the Zerg's; the role model is trained on TvZ only, so the fight layer's
# rules play (the first TvT game, Gary-T against Gary-T: both sides saw an early pool and built ramp bunkers)
_VS_NON_ZERG = {"posture": "normal", "macro": {"builds": [], "answers": False, "natural_bunker": False, "selector": None},
                "fight": {"provider": "roles", "model": None, "roles": {"post": 3}}}

MANIFESTS: dict[str, dict] = {
    # learned macro, army in waves of 16
    "v02": {"version": "v0.2", "posture": "normal", "macro": _LEARNED, "army": {"provider": "waves"}, "fight": None,
            "arbiter": "fixed_priority/v1"},
    # learned army, scouting, a worker-pull rule
    "v03": {"version": "v0.3", "posture": "normal", "macro": _LEARNED, "army": {**_ARMY, "pull": True}, "fight": None,
            "arbiter": "fixed_priority/v1"},
    # a learned fight model per unit; bunkers loaded by rule
    "v04": {"version": "v0.4", "posture": "normal", "macro": _LEARNED, "army": _ARMY,
            "fight": {"provider": "per_unit", "model": "fight/latest", "before": ["load"]},
            "arbiter": "fixed_priority/v1"},
    # the fight command model: one command at a time to a selection
    "v05": {"version": "v0.5", "posture": "normal", "macro": _LEARNED, "army": _ARMY,
            "fight": {"provider": "command", "model": "fight_cmd/latest", "before": ["load"]},
            "arbiter": "fixed_priority/v1"},
    # ...that remembers its recent commands
    "v06": {"version": "v0.6", "posture": "normal", "macro": _LEARNED, "army": _ARMY,
            "fight": {"provider": "command", "model": "fight_cmd/latest_memory", "before": ["load"]},
            "arbiter": "fixed_priority/v1"},
    # workers pulled by rule, not the model's; a guard rail on its moves and stops
    "v07": {"version": "v0.7", "posture": "normal", "macro": _LEARNED, "army": _ARMY,
            "fight": {"provider": "command", "model": "fight_cmd/latest_memory", "before": ["pull", "load"],
                      "guard_rail": True, "workers": False},
            "arbiter": "fixed_priority/v1"},
    # v0.7 without the guard rail: for judging fight models trained by RL (train/fight_cmd_rl.py)
    "v07free": {"version": "v0.7", "posture": "normal", "macro": _LEARNED, "army": _ARMY,
                "fight": {"provider": "command", "model": "fight_cmd/latest_memory", "before": ["pull", "load"],
                          "workers": False},
                "arbiter": "fixed_priority/v1"},
    # the fight model trained by RL, no guard rail
    "v08": {"version": "v0.8", "posture": "normal", "macro": _LEARNED, "army": _ARMY,
            "fight": {"provider": "command", "model": "fight_cmd_rl/v08", "before": ["pull", "load"], "workers": False},
            "arbiter": "fixed_priority/v1"},
    # holds early pools: the early-pool posture, its one-base build, repair and reinforce rules
    "v09": {"version": "v0.9", "posture": "early_pool/v1",
            "macro": {**_LEARNED, "builds": ["one_base_defense"]}, "army": _ARMY, "fight": _V09_FIGHT,
            "arbiter": "fixed_priority/v1"},
    # v0.10: roles instead of the fight model (hand rules, roles.py), leases enforced
    "v010": {"version": "v0.10", "posture": "early_pool/v1", "leases": "enforced",
             "macro": {**_LEARNED, "builds": ["one_base_defense"]}, "army": _ARMY,
             "fight": {**_V09_FIGHT, "provider": "roles", "model": None}, "arbiter": "fixed_priority/v1"},
    # v0.11: v0.10 pulling 3 workers per zerg (not 2), and holding a post by the Command Center
    "v011": {"version": "v0.11", "posture": "early_pool/v1", "leases": "enforced",
             "macro": {**_LEARNED, "builds": ["one_base_defense"]}, "army": _ARMY,
             "fight": {**_V09_FIGHT, "provider": "roles", "model": None, "roles": {"post": 3},
                       "rule_options": {"pull": {"per_enemy": 3}}},
             "arbiter": "fixed_priority/v1"},
    # v0.12: v0.11 with a bunker at the natural once it takes it, and its first Barracks ordered by
    # 1:18 if the model hasn't (macro.py)
    "v012": {"version": "v0.12", "posture": "early_pool/v1", "leases": "enforced",
             "macro": {**_LEARNED, "builds": ["one_base_defense"], "natural_bunker": True, "rax_by": 78 * 24},
             "army": _ARMY,
             "fight": {**_V09_FIGHT, "provider": "roles", "model": None, "roles": {"post": 3},
                       "rule_options": {"pull": {"per_enemy": 3}}},
             "arbiter": "fixed_priority/v1"},
    # v0.13: v0.12 with the rush bunker by the main's Command Center, not its way out (posture.py v2)
    "v013": {"version": "v0.13", "posture": "early_pool/v2", "leases": "enforced",
             "macro": {**_LEARNED, "builds": ["one_base_defense"], "natural_bunker": True, "rax_by": 78 * 24},
             "army": _ARMY,
             "fight": {**_V09_FIGHT, "provider": "roles", "model": None, "roles": {"post": 3},
                       "rule_options": {"pull": {"per_enemy": 3}}},
             "arbiter": "fixed_priority/v1"},
    # v0.14: v0.13 whose idle Barracks, Factories and Starports make the model's last unit for them
    # again (macro.py keep_busy; removed in gt0.7, so v0.14 to gt0.6 now play without it)
    "v014": {"version": "v0.14", "posture": "early_pool/v2", "leases": "enforced",
             "macro": {**_LEARNED, "builds": ["one_base_defense"], "natural_bunker": True, "rax_by": 78 * 24},
             "army": _ARMY,
             "fight": {**_V09_FIGHT, "provider": "roles", "model": None, "roles": {"post": 3},
                       "rule_options": {"pull": {"per_enemy": 3}}},
             "arbiter": "fixed_priority/v1"},
    # v0.15: v0.14 that keeps its bunkers loaded, not only once zerg are near (fight.py, load rule):
    # speedlings cross the 9 tiles in under 2 s, and marines walking in don't shoot
    "v015": {"version": "v0.15", "posture": "early_pool/v2", "leases": "enforced",
             "macro": {**_LEARNED, "builds": ["one_base_defense"], "natural_bunker": True, "rax_by": 78 * 24},
             "army": _ARMY,
             "fight": {**_V09_FIGHT, "provider": "roles", "model": None, "roles": {"post": 3},
                       "rule_options": {"pull": {"per_enemy": 3}, "load": {"always": True}}},
             "arbiter": "fixed_priority/v1"},
    # v0.16: v0.15 whose army hunts once no enemy army has been seen for a minute, scanning the bases
    # (army.py hunt, scan), and whose posture calls a pool finished by 2:40 an early pool (v3)
    "v016": {"version": "v0.16", "posture": "early_pool/v3", "leases": "enforced",
             "macro": {**_LEARNED, "builds": ["one_base_defense"], "natural_bunker": True, "rax_by": 78 * 24},
             "army": {**_ARMY, "hunt": True, "scan": True},
             "fight": {**_V09_FIGHT, "provider": "roles", "model": None, "roles": {"post": 3},
                       "rule_options": {"pull": {"per_enemy": 3}, "load": {"always": True}}},
             "arbiter": "fixed_priority/v1"},
    # v0.17: v0.16 that calls nothing seen an early pool only at 2:50 (posture v4)
    "v017": {"version": "v0.17", "posture": "early_pool/v4", "leases": "enforced",
             "macro": {**_LEARNED, "builds": ["one_base_defense"], "natural_bunker": True, "rax_by": 78 * 24},
             "army": {**_ARMY, "hunt": True, "scan": True},
             "fight": {**_V09_FIGHT, "provider": "roles", "model": None, "roles": {"post": 3},
                       "rule_options": {"pull": {"per_enemy": 3}, "load": {"always": True}}},
             "arbiter": "fixed_priority/v1"},
    # v0.18: v0.17 whose posture (v5) calls off an alarm from nothing seen until 4:00, and lets the
    # main's rush bunker out once the rush is over
    "v018": {"version": "v0.18", "posture": "early_pool/v5", "leases": "enforced",
             "macro": {**_LEARNED, "builds": ["one_base_defense"], "natural_bunker": True, "rax_by": 78 * 24},
             "army": {**_ARMY, "hunt": True, "scan": True},
             "fight": {**_V09_FIGHT, "provider": "roles", "model": None, "roles": {"post": 3},
                       "rule_options": {"pull": {"per_enemy": 3}, "load": {"always": True}}},
             "arbiter": "fixed_priority/v1"},
    # v0.19: v0.18 whose build style is chosen per map by the strategy selector (gary/agent/selector.py)
    "v019": {"version": "v0.19", "posture": "early_pool/v5", "leases": "enforced",
             "macro": {**_LEARNED, "builds": ["one_base_defense"], "natural_bunker": True, "rax_by": 78 * 24, "selector": "play"},
             "army": {**_ARMY, "hunt": True, "scan": True},
             "fight": {**_V09_FIGHT, "provider": "roles", "model": None, "roles": {"post": 3},
                       "rule_options": {"pull": {"per_enemy": 3}, "load": {"always": True}}},
             "arbiter": "fixed_priority/v1"},
    # v0.20: v0.19 whose new fighters gather as pros' marines do (executor.py rerally: inside the main's ramp,
    # at its bottom from 4:45, in front of the natural from 7:30)
    "v020": {"version": "v0.20", "posture": "early_pool/v5", "leases": "enforced", "rally": "ramp",
             "macro": {**_LEARNED, "builds": ["one_base_defense"], "natural_bunker": True, "rax_by": 78 * 24, "selector": "play"},
             "army": {**_ARMY, "hunt": True, "scan": True},
             "fight": {**_V09_FIGHT, "provider": "roles", "model": None, "roles": {"post": 3},
                       "rule_options": {"pull": {"per_enemy": 3}, "load": {"always": True}}},
             "arbiter": "fixed_priority/v1"},
    # v0.21: v0.20 whose workers astray go back to mining, at the least saturated safe base, with transfers
    # to a new base (executor.py home_scvs, balance)
    "v021": {"version": "v0.21", "posture": "early_pool/v5", "leases": "enforced", "rally": "ramp",
             "home_scvs": True, "balance": True,
             "macro": {**_LEARNED, "builds": ["one_base_defense"], "natural_bunker": True, "rax_by": 78 * 24, "selector": "play"},
             "army": {**_ARMY, "hunt": True, "scan": True},
             "fight": {**_V09_FIGHT, "provider": "roles", "model": None, "roles": {"post": 3},
                       "rule_options": {"pull": {"per_enemy": 3}, "load": {"always": True}}},
             "arbiter": "fixed_priority/v1"},
    # v0.22: v0.21 that defends against an early pool from 2:30 unless the rules switched first (posture.py
    # force_at) and scans burrowed lurkers near its fighters (fight.py DetectRule)
    "v022": {"version": "v0.22", "posture": "early_pool/v5", "leases": "enforced", "rally": "ramp",
             "home_scvs": True, "balance": True, "defend_early": 150 * 24,
             "macro": {**_LEARNED, "builds": ["one_base_defense"], "natural_bunker": True, "rax_by": 78 * 24, "selector": "play"},
             "army": {**_ARMY, "hunt": True, "scan": True},
             "fight": {**_V09_FIGHT, "provider": "roles", "model": None, "roles": {"post": 3},
                       "before": _V09_FIGHT["before"] + ["detect"],
                       "rule_options": {"pull": {"per_enemy": 3}, "load": {"always": True}}},
             "arbiter": "fixed_priority/v1"},
    # v0.23: v0.22 that takes a third base (and more) once the macro model's odds of expanding add up
    # to one (macro.py expand_mass)
    "v023": {"version": "v0.23", "posture": "early_pool/v5", "leases": "enforced", "rally": "ramp",
             "home_scvs": True, "balance": True, "defend_early": 150 * 24,
             "macro": {**_LEARNED, "builds": ["one_base_defense"], "natural_bunker": True, "rax_by": 78 * 24, "selector": "play", "expand_mass": 1.0},
             "army": {**_ARMY, "hunt": True, "scan": True},
             "fight": {**_V09_FIGHT, "provider": "roles", "model": None, "roles": {"post": 3},
                       "before": _V09_FIGHT["before"] + ["detect"],
                       "rule_options": {"pull": {"per_enemy": 3}, "load": {"always": True}}},
             "arbiter": "fixed_priority/v1"},
    # v0.24: v0.23 that reads the zerg's plan and answers lurkers as pros do (answers.py: Siege Mode, tanks,
    # a Science Facility, vessels, Irradiate, turrets one a base; a tech scan of their main at 6:30)
    "v024": {"version": "v0.24", "posture": "early_pool/v5", "leases": "enforced", "rally": "ramp",
             "home_scvs": True, "balance": True, "defend_early": 150 * 24,
             "macro": {**_LEARNED, "builds": ["one_base_defense"], "natural_bunker": True, "rax_by": 78 * 24, "selector": "play", "expand_mass": 1.0, "answers": True},
             "army": {**_ARMY, "hunt": True, "scan": True},
             "fight": {**_V09_FIGHT, "provider": "roles", "model": None, "roles": {"post": 3},
                       "before": _V09_FIGHT["before"] + ["detect"],
                       "rule_options": {"pull": {"per_enemy": 3}, "load": {"always": True}}},
             "arbiter": "fixed_priority/v1"},
    # v0.25: v0.24 whose hunts finish games (army.py, motor.py: a hunt's camera on a unit, 8 boxes, a scan of a
    # remembered building the army hasn't settled in 20 s, an Extractor destroyed forgotten). Shared code: the
    # manifest is v0.24's; the version marks where the fixes came in
    "v025": {"version": "v0.25", "posture": "early_pool/v5", "leases": "enforced", "rally": "ramp",
             "home_scvs": True, "balance": True, "defend_early": 150 * 24,
             "macro": {**_LEARNED, "builds": ["one_base_defense"], "natural_bunker": True, "rax_by": 78 * 24, "selector": "play", "expand_mass": 1.0, "answers": True},
             "army": {**_ARMY, "hunt": True, "scan": True},
             "fight": {**_V09_FIGHT, "provider": "roles", "model": None, "roles": {"post": 3},
                       "before": _V09_FIGHT["before"] + ["detect"],
                       "rule_options": {"pull": {"per_enemy": 3}, "load": {"always": True}}},
             "arbiter": "fixed_priority/v1"},
    # v0.26: v0.25 with the fixes from human game 1 (OPTIONS muta_answer, pull_cap), and the
    # parked build that keeps its SCV (executor.py, shared code)
    "v026": {"version": "v0.26", "posture": "early_pool/v5", "leases": "enforced", "rally": "ramp",
             "home_scvs": True, "balance": True, "defend_early": 150 * 24,
             "macro": {**_LEARNED, "builds": ["one_base_defense"], "natural_bunker": True, "rax_by": 78 * 24, "selector": "play", "expand_mass": 1.0, "answers": True,
                       "answer_options": {"mutas": True}},
             "army": {**_ARMY, "hunt": True, "scan": True},
             "fight": {**_V09_FIGHT, "provider": "roles", "model": None, "roles": {"post": 3},
                       "before": _V09_FIGHT["before"] + ["detect"],
                       "rule_options": {"pull": {"per_enemy": 3, "ground_only": True, "max_enemy": 8},
                                        "load": {"always": True}}},
             "arbiter": "fixed_priority/v1"},
    # v0.27: v0.26 with the fixes from human game 2: SCVs repair a mineral-line turret under attack (3, as pros
    # send several; OPTION repair_turrets); stim, learned from the pros' stims (OPTION stim); builders queued back
    # to the minerals (OPTION builder_back). Shared code: against mutalisks the answer's turrets go up first,
    # in the mineral line nearest the zerg first (the model's own turrets, built away from the minerals, wait
    # until then); live placement keeps add-on spots free (turrets had taken both Comsats' places); a pending
    # add-on's building isn't kept busy (an SCV queued just before its Comsat: the game refused it)
    "v027": {"version": "v0.27", "posture": "early_pool/v5", "leases": "enforced", "rally": "ramp",
             "home_scvs": True, "balance": True, "defend_early": 150 * 24, "builder_back": True,
             "macro": {**_LEARNED, "builds": ["one_base_defense"], "natural_bunker": True, "rax_by": 78 * 24, "selector": "play", "expand_mass": 1.0, "answers": True,
                       "answer_options": {"mutas": True}},
             "army": {**_ARMY, "hunt": True, "scan": True},
             "fight": {**_V09_FIGHT, "provider": "roles", "model": None, "roles": {"post": 3},
                       "before": _V09_FIGHT["before"] + ["detect", "stim"],
                       "rule_options": {"pull": {"per_enemy": 3, "ground_only": True, "max_enemy": 8},
                                        "load": {"always": True}, "repair": {"turrets": 3}}},
             "arbiter": "fixed_priority/v1"},
    # v0.28: v0.27 whose army isn't held by noise (the humanlikeness classifier's tell: the army stood still 78% of
    # 5-7 min, pros 37%): plain moves (positioning) always go; an attack is held only when the fight estimate says
    # it loses 5+ points of army share, or 5+ worse than staying (v0.27: 2 and 1, held ~90% of decisions at 5-6 min)
    "v028": {"version": "v0.28", "posture": "early_pool/v5", "leases": "enforced", "rally": "ramp",
             "home_scvs": True, "balance": True, "defend_early": 150 * 24, "builder_back": True,
             "macro": {**_LEARNED, "builds": ["one_base_defense"], "natural_bunker": True, "rax_by": 78 * 24, "selector": "play", "expand_mass": 1.0, "answers": True,
                       "answer_options": {"mutas": True}},
             "army": {**_ARMY, "hunt": True, "scan": True, "hold_moves": False, "hold_margin": 0.05},
             "fight": {**_V09_FIGHT, "provider": "roles", "model": None, "roles": {"post": 3},
                       "before": _V09_FIGHT["before"] + ["detect", "stim"],
                       "rule_options": {"pull": {"per_enemy": 3, "ground_only": True, "max_enemy": 8},
                                        "load": {"always": True}, "repair": {"turrets": 3}}},
             "arbiter": "fixed_priority/v1"},
    # v0.29: v0.28 whose fighters answer what they see before contact as the pros do: the role model (decisions:
    # keep or a new role, with a where head) learned from 600 pro games' units whenever a seen enemy fighter was
    # within 12 tiles (ingest/response_dataset.py: 1.3M labels before contact); the fight layer watches 12 tiles.
    # The hand rules in contact, the model before it (roles.py ahead/v1): its roles for every unit instead of
    # the rules lost 52 net value a home defense (226 pro scenarios), with or without its where; the watch
    # alone +4 +- 5
    "v029": {"version": "v0.29", "posture": "early_pool/v5", "leases": "enforced", "rally": "ramp",
             "home_scvs": True, "balance": True, "defend_early": 150 * 24, "builder_back": True,
             "macro": {**_LEARNED, "builds": ["one_base_defense"], "natural_bunker": True, "rax_by": 78 * 24, "selector": "play", "expand_mass": 1.0, "answers": True,
                       "answer_options": {"mutas": True}},
             "army": {**_ARMY, "hunt": True, "scan": True, "hold_moves": False, "hold_margin": 0.05},
             "fight": {**_V09_FIGHT, "provider": "role_ahead", "model": "runs/roles/20261016-195206/model.pt",
                       "roles": {"post": 3}, "watch_tiles": 12,
                       "before": _V09_FIGHT["before"] + ["detect", "stim"],
                       "rule_options": {"pull": {"per_enemy": 3, "ground_only": True, "max_enemy": 8},
                                        "load": {"always": True}, "repair": {"turrets": 3}}},
             "vs": {"T": _VS_NON_ZERG, "P": _VS_NON_ZERG},
             "arbiter": "fixed_priority/v1"},
    # v0.19 with learned roles (gary/policy/roles.py, with the terrain inputs; the model: --fight-model /
    # fight_path, default the latest in runs/roles): the same rules around them
    "v019roleml": {"version": "v0.19", "posture": "early_pool/v5", "leases": "enforced",
                   "macro": {**_LEARNED, "builds": ["one_base_defense"], "natural_bunker": True, "rax_by": 78 * 24, "selector": "play"},
                   "army": {**_ARMY, "hunt": True, "scan": True},
                   "fight": {**_V09_FIGHT, "provider": "roles", "model": "roles/latest", "roles": {"post": 3},
                             "rule_options": {"pull": {"per_enemy": 3}, "load": {"always": True}}},
                   "arbiter": "fixed_priority/v1"},
    # v0.17 with learned roles (gary/policy/roles.py; the model: --fight-model / fight_path, default
    # the latest in runs/roles): the same rules around them, roles' options passed on (the post)
    "v017roleml": {"version": "v0.17", "posture": "early_pool/v4", "leases": "enforced",
                   "macro": {**_LEARNED, "builds": ["one_base_defense"], "natural_bunker": True, "rax_by": 78 * 24},
                   "army": {**_ARMY, "hunt": True, "scan": True},
                   "fight": {**_V09_FIGHT, "provider": "roles", "model": "roles/latest", "roles": {"post": 3},
                             "rule_options": {"pull": {"per_enemy": 3}, "load": {"always": True}}},
                   "arbiter": "fixed_priority/v1"},
    # v0.17 with a learned override of its roles' rules (gary/agent/roles.py RoleOverride: per unit
    # join, hold, or the rules; the model: --fight-model / fight_path, default the latest in runs/roles)
    "v017override": {"version": "v0.17", "posture": "early_pool/v4", "leases": "enforced",
                     "macro": {**_LEARNED, "builds": ["one_base_defense"], "natural_bunker": True,
                               "rax_by": 78 * 24},
                     "army": {**_ARMY, "hunt": True, "scan": True},
                     "fight": {**_V09_FIGHT, "provider": "role_override", "model": "roles/latest",
                               "roles": {"post": 3}, "rule_options": {"pull": {"per_enemy": 3}, "load": {"always": True}}},
                     "arbiter": "fixed_priority/v1"},
    # step 4 (docs/CONTROL.md): v0.9 with leases enforced; and with roles instead of the fight model
    "v09lease": {"version": "v0.9", "posture": "early_pool/v1", "leases": "enforced",
                 "macro": {**_LEARNED, "builds": ["one_base_defense"]}, "army": _ARMY, "fight": _V09_FIGHT,
                 "arbiter": "fixed_priority/v1"},
    "v09roles": {"version": "v0.9", "posture": "early_pool/v1", "leases": "enforced",
                 "macro": {**_LEARNED, "builds": ["one_base_defense"]}, "army": _ARMY,
                 "fight": {**_V09_FIGHT, "provider": "roles", "model": None}, "arbiter": "fixed_priority/v1"},
    # step 5: the roles named by a model learned from the pros' role labels
    "v09roleml": {"version": "v0.9", "posture": "early_pool/v1", "leases": "enforced",
                  "macro": {**_LEARNED, "builds": ["one_base_defense"]}, "army": _ARMY,
                  "fight": {**_V09_FIGHT, "provider": "roles", "model": "roles/latest"}, "arbiter": "fixed_priority/v1"},
    # the one Gary playing Zerg (docs/REFACTOR.md Phase 1): the shared agent with the Zerg executor and Gary-Z's
    # macro options (the dice; one-offs and hatcheries by summed odds; a decision parked for its money while
    # the larvae go on; the model's tempo; no tech path under 10%; an overlord ahead; the pros' history; a rolled
    # style; a roll waiting for supply or money held, 2026-10-20: LearnedMacro.hold, round G11 against G9). Its army
    # and fights from Gary-Z (Phase 2)
    # gz0.2: its army on control groups by type (gary/agent/grouping.py; 96 paired games twice against gt1, rounds
    # GZ40a+b and GZ40c+d against L40a+b: Gary-T won 49 and 48 (57), lost 10 and 13 (8); Gary-Z's gap at 15-20
    # minutes nearer the pros both times, -0.073 (-0.102 to -0.017) the second)
    # gz0.3: the overlord's history its own (ownsupply) and overlords ahead of production gone, the model's own (96
    # paired games against gt1, ZS100a+b against B100a+b: the Terran's score -0.029 +- 0.103, the Zerg's gap +0.026,
    # -0.024 to +0.083: no measurable difference, so the stop-gap goes)
    # gz0.4: every build's fix of 2026-10-31 (as gt0.11's)
    "gz1": {"version": "gz0.4", "race": "Z", "posture": "zerg", "leases": "enforced", "balance": True, "rotate": True,
            "grouping": "types",
            "macro": {**_LEARNED, "builds": ["alarm"], "decoder": "dice", "odds_mass": 1.0, "hatch_mass": 0.5, "park": True, "pace": True,
                      "tech_min_p": 0.10, "wait_min_p": 0.05, "own_supply": True, "rax_by": 165 * 24, "history": "pro", "style": "roll",
                      "hold": True},
            # the army: clusters with commitments, drawn (Gary-Z's GARY_Z_COMMIT=latest), its ground army (the flyers
            # and lurkers have their own rules); no worker scout (its overlords)
            "army": {"provider": "learned", "model": "commit/latest", "commit": True, "draw": True, "scout": False,
                     "types": [37, 38, 39, 45, 46], "rules": ["posts", "raid", "join", "sweep", "press"], "hunt": True},
            # its fight roles from the pros' Zerg units in whole games to 30 minutes, old and modern (round R30Z against
            # B30: the Zerg ahead or winning at 30:00 in 9 of 48 games to 6, its gap at 21-30 minutes 0.40 to 0.46)
            "fight": {"provider": "zerg", "roles_data": "response_Z_30min.npz"}, "arbiter": "fixed_priority/v1"},
    # the one Gary playing Protoss (docs/REFACTOR.md Phase 4), crude: the Protoss executor, the Protoss macro model with
    # every game's style (every matchup's plans, taxonomy/label_all.py; a style rolled by the modern pros' shares) and the
    # gas head (train/macro.py --race P --styles v2, every matchup: P_all_v2all, gp0.4, as allstyles in place of
    # P_all_v2gas, which knew no PvP styles: 96 paired games each against gp0.3, AV171a+b, AZ171a+b, AP171a+b against
    # QV170a+b, QZ170a+b, PR168a+b: PvT -0.010 +- 0.091, PvZ -0.005 +- 0.074, PvP +0.143 +- 0.090; its style as told
    # PvT citadel first 50% of games (12%), PvZ nexus first 88% (62%), PvP robotics first 91%, nexus first 75%, citadel
    # first 19% (no style told before)) rolled (dice), its probes on gas the head's (gaswaits), one-offs and expansions by summed odds, builds parked as the money comes (three at once), a Pylon
    # ahead of production and for power; the army's commitments from the matchup's commit model
    # gp0.5: every build's fix of 2026-10-31 (as gt0.11's)
    # gp0.6: Reavers and Carriers kept full of Scarabs and Interceptors (the hands, executor.rearm: they are built empty,
    # and every one Gary-P made before never fired)
    # gp0.7: Pylons placed where they power new room (the hands, protoss_executor.py spot; as gp0.12dev's)
    "gp1": {"version": "gp0.7", "race": "P", "posture": "normal", "leases": "enforced", "balance": True, "builder_back": True,
            "macro": {"provider": "learned", "model": "runs/macro_exp/P_all_v2all/model.pt", "builds": [], "decoder": "dice",
                      "odds_mass": 1.0, "expand_mass": 1.0, "park": True, "supply_ahead": True, "parked_max": 3,
                      "gas_waits": True, "style": "roll", "look_seen": True, "unit_count": True, "history_styles": "v2"},
            # (its inputs as its datasets count them: what is in sight looked at every second, the probes inside the
            # Assimilators: seenall, unitcount, armyseen; the inputs test, a PvT game)
            "army": {"provider": "learned", "model": "commit/latest", "commit": True, "draw": True, "hunt": True,
                     "army_seen": True},
            # its fights by the matchup's Protoss role model (the pros' Protoss units in 600 modern games of the matchup to
            # 30 minutes, ingest/response_dataset.py --race P --matchups, train/roles.py --decisions --move), in contact too
            # (as gt1dev's), no Terran rules (repair, pull, load, stim). Each matchup by its own pros: PvP's in gp0.2 (as
            # mirrorroles: 96 paired games against gp0.1, PR168a+b against PP168a+b, -0.049 +- 0.098, the fight gap +0.001
            # [-0.071, +0.093]), PvT's and PvZ's in gp0.3 in place of one model over both (96 paired games each against
            # gp0.2, QV170a+b against PV170a+b and QZ170a+b against PZ170a+b: PvT +0.000 +- 0.077, the fight gap +0.044
            # [-0.039, +0.096]; PvZ -0.021 +- 0.067, -0.006 [-0.064, +0.058]: no measurable difference)
            "fight": {"provider": "roles", "model": "roles/latest", "workers": False,
                      "roles_data": {"PvT": "response_P_PvT_30min.npz", "PvZ": "response_P_PvZ_30min.npz",
                                     "PvP": "response_P_PvP_30min.npz"},
                      "watch_tiles": 12, "roles": {"post": 3, "draw": True}, "data_extras": True},
            "arbiter": "fixed_priority/v1"},
    # the fight layer alone, for micro drills (gary/drills.py)
    "drill": {"version": "drill", "posture": "normal", "macro": None, "army": None,
              "fight": {"provider": "command", "model": "fight_cmd/latest_memory", "workers": False},
              "arbiter": "drill/v1"},
}


# --- models ------------------------------------------------------------------------------------

def _newest(kind: str, matchup: str, race: str) -> Path:
    found = sorted((REPO_ROOT / "runs" / kind).glob(f"{matchup}_{race}_*/model.pt"))
    if not found:
        raise SystemExit(f"no trained {kind} model for {race} in {matchup} in runs/{kind} "
                         f"(python -m train.{kind} --matchup {matchup} --race {race})")
    return found[-1]


def _command_model(matchup: str, race: str, memory: bool) -> Path:
    """The newest fight command model, with or without memory of its own recent commands."""
    import torch
    for path in sorted((REPO_ROOT / "runs" / "fight_cmd").glob(f"{matchup}_{race}_*/model.pt"), reverse=True):
        if torch.load(path, map_location="cpu", weights_only=True)["config"]["net"].get("memory", False) == memory:
            return path
    raise SystemExit(f"no trained command model{' with memory' if memory else ''} for {race} in {matchup} in "
                     f"runs/fight_cmd (python -m train.fight_cmd --matchup {matchup} --race {race}"
                     f"{' --memory --data v3' if memory else ''})")


def _tvz_terran(kind: str, matchup: str, race: str, find) -> Path:
    """A kind trained for Gary-T in TvZ only (its runs aren't named by matchup)."""
    if (matchup, race) != ("TvZ", "T"):
        raise SystemExit(f"no {kind} model for {race} in {matchup}: there are only TvZ Terran ones (runs/{kind})")
    found = find()
    if not found:
        raise SystemExit(f"no trained {kind} model in runs/{kind}")
    return found[-1]


def _runs(kind: str, key=None) -> list[Path]:
    return sorted((REPO_ROOT / "runs" / kind).glob("*/model.pt"), key=key)


def model_for(kind: str, matchup: str, race: str) -> Path:
    """The model of this kind a player of this race uses in this matchup: the race's shared model where
    one covers the matchup (macro: gary.policy.macro.macro_model_path), else the matchup's own newest.
    None for the matchup: SystemExit (a manifest then has to name a rules provider). Kinds: macro,
    army, commit, engage, belief, plan, fight, army_rl, fight_cmd and fight_cmd_memory (the command model
    without and with memory), and TvZ Terran's own roles, macro_rl and fight_cmd_rl (v0.8's fight
    model, or else the newest trained by reinforcement learning)."""
    if kind == "macro":
        from gary.policy.macro import macro_model_path
        return macro_model_path(matchup, race)
    if kind in ("fight_cmd", "fight_cmd_memory"):
        return _command_model(matchup, race, kind == "fight_cmd_memory")
    if kind == "roles":
        return _tvz_terran(kind, matchup, race, lambda: _runs("roles"))
    if kind == "macro_rl":
        return _tvz_terran(kind, matchup, race, lambda: _runs("macro_rl"))
    if kind == "fight_cmd_rl":
        return _tvz_terran(kind, matchup, race, lambda: [V08_FIGHT_MODEL] if V08_FIGHT_MODEL.exists() else
                           _runs("fight_cmd_rl", key=lambda p: p.stat().st_mtime))
    return _newest(kind, matchup, race)


# a manifest's model references: "<kind>/latest", and these
REFS = {"fight_cmd/latest_memory": "fight_cmd_memory", "fight_cmd_rl/v08": "fight_cmd_rl"}


def _engage_model(g, m: dict):
    """The attack-or-hold model for the army layer (option engage; GARY_TENGAGE_MODEL pins it: the
    league loop's incumbent or candidate)."""
    ref = m["army"].get("engage")
    if not ref:
        return None
    from gary.policy.army import ArmyModel
    return ArmyModel.load(os.environ.get("GARY_TENGAGE_MODEL") or model_path(ref, g.matchup, g.race.letter))


def _learned_posture(g, m: dict, models: dict):
    """The plan policy deciding the posture's mode (gary/policy/plan.py; docs/CONTROL.md step 7)."""
    from gary.agent.posture import LearnedPosture
    from gary.policy.plan import PlanModel
    model = PlanModel.load(model_path(m.get("plan_model", "plan/latest"), g.matchup, g.race.letter))
    g.plan_model = model.path            # (not in the start-of-game chat: one more line shifts the game)
    return LearnedPosture(g, model, m.get("plan_temperature", 0.0))


HISTORY_FADE = 12                    # option history: minutes over which the pros' history fades to the player's own


def rolled_style(model, matchup: str, race: str, seed: int) -> int | None:
    """A build style rolled among the model's, by the pros' shares of them where the taxonomy is here
    (data/interim/taxonomy/<matchup>_<race>_plan.json, Gary-Z's plan roll; else the tech clusters', <matchup>_<race>
    _tech.json: Terran TvZ 1 standard bio 81%, 2 Factory and vultures 13%, 3 Factory and Starport 4%, 4 two-Barracks
    marines 2%), else the v2 catalogue's modern shares; None (no style: the style input "unknown", as the model
    learned the matchup's games) where the race has no styles in this matchup (a TvZ style was told in PvT)."""
    import json
    import random
    styles = model.spec.styles
    if not styles:
        return None
    shares = None
    try:
        from ingest.inventory import data_root
        d = json.loads((data_root() / "interim" / "taxonomy" / f"{matchup}_{race}_plan.json").read_text(encoding="utf-8"))
        counts = [0] * len(d["names"])
        for k in d["assignments"].values():
            counts[k] += 1
        shares = [c / max(1, sum(counts)) for c in counts]
    except Exception:                         # (no plan taxonomy here: the tech clusters', by style number)
        try:
            from ingest.inventory import data_root
            d = json.loads((data_root() / "interim" / "taxonomy" / f"{matchup}_{race}_tech.json").read_text(encoding="utf-8"))
            vals = list(d["assignments"].values())
            shares = [vals.count(k) / max(1, len(vals)) for k in range(max(vals) + 1)]
        except Exception:
            pass
    try:                                      # (the modern pros' shares on the ladder maps, eval/style_adherence.py
        from ingest.inventory import data_root   # --write-shares: Terran TvZ 64/22/13/1 against the all-era 81/13/4/2)
        modern = json.loads((data_root() / "interim" / "taxonomy" / f"{matchup}_{race}_modern_shares.json").read_text(encoding="utf-8"))
        shares = [modern["shares"].get(str(k), 0.0) for k in range(max(int(k) for k in modern["shares"]) + 1)]
    except Exception:
        pass
    from gary import styles as catalogue
    c = catalogue.catalog(matchup, race)
    if shares is None:                        # (else the v2 catalogue's modern shares: the Protoss's, label_all.py)
        if c is None:
            return None
        weights = [c["shares"].get(s, 0.0) for s in styles]
    else:
        weights = [shares[s] if s < len(shares) else 1.0 for s in styles]
    if c is not None:                         # (only this matchup's plans: a model trained on every matchup knows the
        no_plan = lambda name: name is None or name == "other" or "undecided" in name    # others' ids; "other" and
        weights = [0.0 if no_plan(c["names"].get(s)) else w for s, w in zip(styles, weights)]   # "undecided": no plan)
    if sum(weights) <= 0:                     # (a model trained before the matchup's catalogue: none of its styles)
        return None
    return random.Random(seed).choices(styles, weights=weights)[0]


def _by_matchup(ref, matchup: str):
    """A manifest value given per matchup ({matchup: value, "*": the others'}), or the value itself."""
    return (ref[matchup] if matchup in ref else ref["*"]) if isinstance(ref, dict) else ref


def model_path(ref, matchup: str, race: str) -> Path:
    """A manifest's model reference ("macro/latest", ...) for this matchup and race, or a checkpoint path; or a dict of
    them by matchup, "*" for the others (a checkpoint trained for one matchup: gz1dev's TvZ macro model played PvZ blind
    to the Protoss, none of its units among its inputs)."""
    ref = _by_matchup(ref, matchup)
    if ref in REFS:
        return model_for(REFS[ref], matchup, race)
    if ref.endswith("/latest"):
        return model_for(ref[:-len("/latest")], matchup, race)
    return Path(ref)


def load_model(kind: str, path: str | Path):
    """kind: "macro", "army" or "fight" (the fight model or the command model, whichever the
    checkpoint holds)."""
    from gary.policy.army import ArmyModel
    from gary.policy.fight_cmd import load_fight_policy
    from gary.policy.macro import MacroModel
    return {"macro": MacroModel.load, "army": ArmyModel.load, "fight": load_fight_policy}[kind](path)


# --- building a Gary ---------------------------------------------------------------------------

def _roles(**options):
    return lambda m: m["fight"].setdefault("roles", {}).update(options)


def _pull(**options):
    return lambda m: m["fight"].setdefault("rule_options", {}).setdefault("pull", {}).update(options)


def _mirror_roles(m: dict) -> None:
    """The fights in the mirror by the matchup's role model (the pros' players of the race in TvT, ZvZ or PvP:
    ingest/response_dataset.py --matchups): the Terran's in its "vs" section against a Terran, where the roles' rules
    played (as pvtroles against a Protoss, its modes drawn by their odds: the likeliest laid no mines, #60); the
    Zerg's and the Protoss's role data by matchup."""
    race = m.get("race", "T")
    data = f"response_{race}_{race}v{race}_30min.npz"
    if race == "T":
        f = m["vs"]["T"]["fight"]
        f.update(model="roles/latest", roles_model=None, roles_data=data, roles={**f.get("roles", {}), "mode_dice": True})
        return
    old = m["fight"].get("roles_data", "response_Z.npz" if race == "Z" else None)
    m["fight"]["roles_data"] = {**(old if isinstance(old, dict) else {"*": old}), f"{race}v{race}": data}


# options to try on top of a manifest, "v010+post+suspend" (docs/CONTROL.md: every layer swappable);
# home defenses (114; [239]: the 239 of all held-out games), reactive Zerg, 8 draws, vs v0.10 (+ is
# better, ± 1 s.e.), and immediate 9-pools lost of 16 (v0.10: 0 of these 16, but 4 of 48: a
# loss or three in 16 is noise); 2026-10-06
OPTIONS = {
    "brace": _roles(brace=True),            # roles.py: let the zerg come, nobody closes in     -8 ± 11
    "leash": _roles(leash=True),            # close in only on zerg attacking or by buildings   -9 ± 9
    "volley": _roles(volley=True),          # close in by moving, then fire together           -38 ± 10
    "regroup": _roles(regroup=True),        # loose units rejoin the pack, the pack closes in  -13 ± 10
    # roles.py anchor (units out in the open fall back to the Command Centers and bunkers; the leash
    # ignores zerg on units out there) and army.py home_guard (no army moves out while enemy fighters
    # are at home): Gary's army split in its losses to Zerg v2's all-in (41% of its army's deaths at
    # 5:00-8:00 out in the open; with anchor 36%). On v0.18, lost (v0.18): Zerg v2 (72) Fighting Spirit
    # 10 (8), Python 7 (11); replayed pros (48) Python 4 (3), Fighting Spirit 2 (5), Heartbreak Ridge 1
    # (3); the 9-pool 1 (1), won 31 (36): 25 of 336 (31). Home defenses [239] -7 ± 10. Not adopted
    "anchor": lambda m: (m["fight"].setdefault("roles", {}).update(anchor=True), m["army"].update(home_guard=True)),
    "holds": _roles(holds=True),            # units on hold position stay on it                 -4 ± 9
    "kite": _roles(kite=True),              # vultures pull back from zerglings                  -5 ± 2
    "fire_here": _roles(fire="here"),       # fire: attack-move to the group's own middle       -8 ± 5
    "fire_hold": _roles(fire="hold"),       # fire: hold position                              -23 ± 10
    "post": _roles(post=3),                 # hold a post by the Command Center (and leash)     +8 ± 9, [239] +7 ± 5,
                                            # and +7 ± 5 on top of pull_three: in v0.11
    "post0": _roles(post=0),                # ...at the Command Center                          +6 ± 10, [239] +4 ± 5
    "post6": _roles(post=6),                # ...6 tiles from it                                -4 ± 8
    # vultures skirmish (move away, shoot, ease off; roles.py): [239] −14 ± 4, worse in 36 of the
    # 47 with vultures: 18% fewer vultures lost, but fewer zerg killed and more SCVs lost
    "vultures": _roles(vultures=True),
    # posts inside the wall gaps (gary/walls.py), holding: on v0.11 [239] -7 ± 4 (better in 26, worse
    # in 42; 0c50ac60 +104): the home defenses start with the zerg at home, past the wall's job;
    # on top of sim city, in 78 wall fights (eval/walls_bench.py) -12 ± 12
    "gap_post": _roles(gap_post=True),
    # depots, barracks, academies wall the frontier, a door left (simcity.py)
    # the first Barracks ordered by 1:18 (not 1:30): on v0.12 without it, replayed pros on three maps
    # lost 15 of 144 (19), the 9-pool 2 either way. Placed at ~1:38: Gary's money comes ~10 s late
    "rax118": lambda m: m["macro"].update(rax_by=78 * 24),
    # a bunker at the natural once Gary takes it, where pros put theirs (macro.py): on v0.11, against
    # the replayed pros (48 seeds), lost 28 of 192 on three maps (v0.11 37); 9-pool lost 2 either way
    "natbunker": lambda m: m["macro"].update(natural_bunker=True),
    "simcity": lambda m: m.update(simcity=True),
    "simcity_closed": lambda m: m.update(simcity=True, simcity_door=0),   # ...closed
    # roles.py, pros' marines move 20% of the time a zerg is in range, Gary's 6%: on v0.14 [239]
    "surround2": _roles(surround=2),        # units with 2+ melee zerg on them walk to the pack -17 ± 6
    "surround3": _roles(surround=3),        # ...3+                                              -6 ± 3
    "pull75": _roles(pull_hp=0.75),         # pull back below 75% HP (not 50%)                  -5 ± 2
    # fight.py: a loaded bunker with no zerg near lets its marines out to the fight elsewhere (the
    # main's rush bunker while the natural is attacked). On v0.14 against Zerg v2 (72 seeds, 12 min)
    # lost 22 (15). Not adopted
    "unload": lambda m: m["fight"].update(before=m["fight"]["before"] + ["unload"]),
    # fight.py: 4 SCVs repair a bunker (not 2): against Zerg v2 (72 seeds) lost 15 (15)
    "repair4": lambda m: m["fight"].setdefault("rule_options", {}).update(repair={"n": 4}),
    # fight.py: 4 SCVs move past the bunker, then repair it (spread around it); and new fighters rally
    # to the main's mineral line while the zerg at home outweigh Gary's fighters there. Both on top of
    # v0.17+posture5+ramp, lost (ramp alone): Zerg v2 on Fighting Spirit 16 (8) and Python 13 (12) of
    # 72; replayed pros (48) Fighting Spirit 2 (5), Python 5 (5); the 9-pool 1 (1). Not adopted
    "repair_surround": lambda m: m["fight"].setdefault("rule_options", {}).update(repair={"n": 4, "surround": True}),
    "safe_rally": lambda m: m["fight"].setdefault("rule_options", {}).update(reinforce={"safe": True}),
    # fight.py: bunkers kept loaded. On v0.14: Zerg v2 (72 seeds, 12 min) lost 8 (15); replayed pros on
    # three maps lost 14 of 144 (15), the 9-pool 3 (3); home defenses [239] +2 ± 5. In v0.15
    "preload": lambda m: m["fight"].setdefault("rule_options", {}).update(load={"always": True}),
    # army.py: from 8:00, 20+ army units and no enemy army seen for a minute, the army goes where enemy
    # buildings were, then to the bases. On v0.15: replayed pros on Fighting Spirit to 18:00 (16 seeds)
    # won 8 (2), lost 2 (2); to 12:00 on three maps won 4 of 144 (0), lost 14 (14); Zerg v2 (72 seeds)
    # won 2 (0), lost 8 (8). In v0.16
    "hunt": lambda m: m["army"].update(hunt=True),
    # roles.py (with a role model that has a where head): retreat, pull back and reposition by the rules'
    # skills, not where the model moves them (ablation of v0.29)
    "nowhere": lambda m: m["fight"].setdefault("roles", {}).update(where=False),
    # army.py: destinations and move/attack drawn from the army model's odds, logged for the league's RL
    # (Gary-Z's likeliest-cell army stood at home 79% at 8-10 min; drawn 56%, pros 35%)
    "draw": lambda m: (m["army"].update(draw=True),
                       m["fight"].setdefault("roles", {}).update(draw=True) if m["fight"].get("provider") == "role_ahead" else None),
    # the army model updated by the league's RL (train/league_rl.py --layer army_t), drawing as it learned
    "army_rl": lambda m: m["army"].update(model="army_rl/latest", draw=True),
    # army.py: attack or hold drawn by the engage model (train/engage.py, from the pros' orders: held-out AUC
    # 0.80), destinations from the army model on that side; the league's learner for the army's initiative
    "engage": lambda m: m["army"].update(draw=True, engage="engage/latest"),
    # army.py: commitments (train/commit.py: keep / engage / move every 5 s per cluster, given its commitment,
    # learned from the pros' armies between orders too); the army model replaced by the commit model, whose
    # destination head was trained along (GARY_TCOMMIT_MODEL pins it)
    # In play the likeliest of keep / engage / move and the likeliest cell; drawn only with +draw (the league's
    # training): human game 3 was played drawn, and the two retreats that threw it were 4.8% and 5.1% draws
    "commit": lambda m: m["army"].update(commit=True, model="commit/latest"),
    # army.py: no hunt (v0.16's scripted attack once no enemy army was seen for a minute): with commitments the
    # engage choice decides when the army goes for the enemy's buildings. In human game 3 the hunt sent 23
    # marines into three sunkens at "100% sure", one by one, twice
    "nohunt": lambda m: m["army"].update(hunt=False),
    # army.py commit_act: with commit, a new commitment once the model's odds of one reach 41% (where the
    # deterministic rate matches the drawn one, the pros'), the likelier of engage and move; the plain likeliest
    # is keep most ticks and Gary-T turned passive (won 7 of 24 against Gary-Z, 17 at time; drawn 13 and 11)
    "act": lambda m: m["army"].update(commit_act=0.41),
    # army.py commit_floor (with commit and draw): the drawn decode without its disasters: no keep / engage / move
    # drawn under 15% (human game 3's 19 low draws were all under 14%), the destination among the 5 likeliest
    # cells. The deterministic decodes won fewer games against Gary-Z than drawing (6-7 of 24 against 13)
    "floor": lambda m: m["army"].update(commit_floor=0.15),
    # army_rules.py LordHunt: one or two marines hunt an exposed overlord (the user, after human game 4)
    "lords": lambda m: m["army"].update(rules=[*m["army"].get("rules", ()), "lords"]),
    # army_rules.py ClusterRules (Gary-Z's, shared): join, a cluster under the main one's size walks to it rather than
    # deciding alone (Gary-T's attacks: 0.26 late arrivals per fighter there, the pros' 0.06, eval/attacks.py); sweep,
    # the main body attacks a packet it outweighs; press, far ahead and nothing at home, it attacks the buildings
    # that end the game. Not adopted for gt1 (48 games against G13: +join won 20 (21), the Zerg ahead at 20:00 in 8
    # (2); +press won 22 but the Zerg ahead in 7; +join+press won 18)
    **{r: (lambda r: lambda m: m["army"].update(rules=[*m["army"].get("rules", ()), r]))(r) for r in ("join", "sweep", "press")},
    # army.py (STOP-GAP, AGENTS.md; in gt1, shared by every race's learned army): hunt_ahead, the hunt also at 4x
    # the enemy fighters seen in the last minute; hunt_split, unseen bases searched by squads; static_odds, an engage
    # only where the group outweighs the ground static defense there (6 supply each) and the enemy fighters seen
    # near it 1.5 times
    "hunt4": lambda m: m["army"].update(hunt_ahead=4.0),
    "split": lambda m: m["army"].update(hunt_split=True),
    "static": lambda m: m["army"].update(static_odds=1.5),
    # army.py gather (STOP-GAP, AGENTS.md): a commit engage with a quarter of the army elsewhere gathers it at a staging
    # point short of the target first, then attacks with it (any race's learned army)
    "gather": lambda m: m["army"].update(gather=True),
    # the fight roles model trained on whole games to 30 minutes, old and modern (ingest/response_dataset.py --era
    # both; until 2026-10-20 the first 20 minutes on the three 1.16 maps): either race's. In gz1 and gt1
    "roles30": lambda m: m["fight"].update(roles_data=f"response_{m.get('race', 'T')}_30min.npz"),
    # the role model imitated from attended pro units only, told the player's order rate (train/roles.py --attended
    # --budget): Gary's own budget from its hands (order_budget); the roles RL's start (docs/PROGRESS.md)
    # the role model decides in contact too (roles.py learned/v1, not RoleAhead's hand rules there), the same skills
    # carrying its groups out: what the roles RL trains reaches every fight command
    "incontact": lambda m: m["fight"].update(provider="roles"),
    # fight.py attend: the fight's share of the hands held at the pros' attended share of fight moments
    "attend": lambda m: m["fight"].update(attend=True),
    # the first roles RL run that moved and improved (train/roles_rl.py from gt1dev, round 50 of 60 by validation on
    # the training games' scenarios): the held-out state-selected suite +195 against its start's +87 (paired +105,
    # +44 to +169), against RoleAhead's +141 +50 (-51 to +151)
    "rl1": lambda m: m["fight"].update(roles_model="runs/roles_rl/20261022_185355/model.pt"),
    # gary/agent/roles.py own_extra: the role model's extras 3-5 (a unit's age, its distance to Gary's biggest bunch,
    # that bunch's size) left 0, as in the response datasets the models learned from (always 0 there: their weights
    # stayed at their initialization's scale, and play fed them 1-4)
    "dataextras": lambda m: m["fight"].update(data_extras=True),
    # gary/agent/zerg_roles.py full_hp: Gary-Z's role model given hidden enemies' HP as full, as its data (it reads 0)
    "zfullhp": lambda m: m["fight"].update(full_hp=True),
    # the third roles RL run, from rl1 with each decision credited over 20 s (--horizon 20; rl2's 10 s won the suite
    # and lost in games): the held-out suite +268 against rl1's +195 (paired +71, +12 to +135), against RoleAhead +122
    "rl3": lambda m: m["fight"].update(roles_model="runs/roles_rl/20261023_043828/model.pt"),
    # the second roles RL run, from rl1 (60 rounds, its best validation at round 60, -53 against rl1's -152): the
    # held-out suite +255 against rl1's +195 (paired +67, +3 to +134), against RoleAhead's +141 +117 (+12 to +231)
    "rl2": lambda m: m["fight"].update(roles_model="runs/roles_rl/20261023_014740/model.pt"),
    # roles.py learned/v1 batch: up to 4 orders a fight turn, a group per role, given as the hands come free
    "batch": lambda m: m["fight"].setdefault("roles", {}).update(batch=4),
    # the attended model with the again decision and its offset head (train/roles.py --again: the pros' re-issues)
    # roles.py learned/v1 together: a key's units draw their decisions with one shared random number (a group decides
    # as one, as the pros' keys do; with grouping)
    "together": lambda m: m["fight"].setdefault("roles", {}).update(together=True),
    # roles.py learned/v1 by_key: a key whose units all drew one decision gets one order, the whole key
    "bykey": lambda m: m["fight"].setdefault("roles", {}).update(by_key=True),
    "again": lambda m: m["fight"].update(roles_data=f"response_{m.get('race', 'T')}_att_again.npz"),
    "att": lambda m: m["fight"].update(roles_data=f"response_{m.get('race', 'T')}_att.npz"),
    # roles.py RoleAhead lone: a unit alone and outnumbered in contact decided by the roles model, not the hand rules
    "lone": lambda m: m["fight"].setdefault("roles", {}).update(lone=True),
    # roles.py refresh: the skills keep their orders current (a standing role's order given again when its target moved
    # a tile: half to three quarters of the pros' fight commands)
    "refresh": lambda m: m["fight"].setdefault("roles", {}).update(refresh=True),
    # gary/agent/grouping.py: the army on control groups, a unit type of a cluster on a key, re-assigned (the pros'
    # habit); the motor recalls a key when all its members get an order, key by key
    "grouping": lambda m: m.update(grouping="types"),
    # the learned provider: the grouping model's groups (gary/policy/grouping_model.py, train/groups.py)
    "grouplearned": lambda m: m.update(grouping="learned"),
    # the same on keys 1-3 with the buildings' keys left where they are (executor.py): is the Terran's cost the layout
    # (production on 3 keys instead of 4) or the grouping? (rounds GT40c/d against L40a/b)
    "grouping3": lambda m: m.update(grouping="types", grouping_layout=False),
    # fight.py: enemy fighters within 12 tiles make a fight (the model's 8 by default; ablation of v0.29)
    "watch12": lambda m: m["fight"].update(watch_tiles=12),
    # army.py: groups going away from home hold when the belief model's likely unseen enemy army
    # (gary/policy/belief.py, 80th percentile less what was seen in 3 min) outweighs them. On v0.17,
    # replayed pros on three maps lost 12 of 144 (11); it held 637 times. Not adopted
    "belief": lambda m: m["army"].update(belief="belief/latest"),
    # army.py hunt_belief: the hunt (no enemy army seen for a minute) only with an army at least the belief
    # model's 80th percentile of the zerg's (the belief loaded for this alone: no holds). On v0.25 (432 games,
    # Zerg v3 to 25 min): won 125 (139), lost 19 (12): no pressure losses (27 won lost 2 -> 31, 0), but lurker
    # games won 10 (20) (the belief, learned from pros' Zergs, expects 40-50 supply at 15:00 where v3 has
    # none) and Zerg v2 lost 14 (8): early hunts pay against these Zergs. Not adopted
    "hunt_belief": lambda m: m["army"].update(hunt_belief=True),
    # ...against all the enemy army it likely has, not only what wasn't seen (what was seen may be
    # dead): lost 13 of 144 (11), held 854 times. Not adopted
    "belief_total": lambda m: m["army"].update(belief="belief/latest", belief_total=True),
    # army.py: the hunt scans bases before walking there: on v0.16 without it, replayed pros on Fighting
    # Spirit to 18:00 (16 seeds) won 11 (8). In v0.16
    "scan": lambda m: m["army"].update(scan=True),
    # army.py watch: the scout stays in the Zerg's bases (moving, away from zerglings) until hunted or
    # 5:00, then watches outside Gary's natural; replaced once if lost by 4:30. Zerg in sight 3:00-6:00:
    # 78 s (44; pros 104). On v0.18 against Zerg v2 (72 seeds) Fighting Spirit lost 11 (8), won 9 (3);
    # Python lost 10 (11), won 3 (1). The macro sees the zerglings now but builds no more Barracks.
    # With the waypoint tour (in sight 103 s): Fighting Spirit lost 10 (8), won 10 (3); Python 8 (11), 3 (1)
    # On v0.19 over the whole pool (fresh seeds, 432 games, Zerg v3 to 20 min): lost 30 (25), won 127 (133);
    # against v3 won 54 (64), lost 4 (1): an SCV off minerals for minutes, for information no decision uses
    "watch": lambda m: m["army"].update(watch=True),
    # executor.py rerally: new fighters gather inside the main's ramp, at its bottom from 4:45, in front
    # of the natural from 7:30, as the pros' marines (the rally in front of the natural from the start
    # put a quarter of Gary's marines in the open at 3:00-6:00, the pros' 3-8%)
    # On v0.19 over the whole pool (fresh seeds, 432 games, Zerg v3 to 20 min): lost 24 (25), won 135 (133);
    # replayed pros lost 13 (17), Zerg v3 won 59 (64). In v0.20
    "rally_ramp": lambda m: m.update(rally="ramp"),
    # executor.py _idle, motor.py unpull: workers away from every Command Center, idle or still attack-moving
    # with nobody holding them, go back to mining (the sweep finds them off screen, pulled or not), and a
    # pull's workers go back to the nearest base Gary owns (before: the nearest base on the map)
    "home_scvs": lambda m: m.update(home_scvs=True),
    # executor.py: a builder's next order queued on a mineral field, and the mining task's other idle workers
    # on the screen added before sending (human game 2: 11-17 of 30-39 SCVs idle from 8:00 to 12:00). In v0.27
    "builder_back": lambda m: m.update(builder_back=True),
    # home_scvs, and executor.py balance: workers sent to mine go to the least saturated safe base (not the
    # nearest), a group of workers moves from a base over 1.8 a patch to a safe one under 1.0 (a new
    # Command Center), and workers out in the field are selected with one ctrl+click
    # On v0.20 over the whole pool (fresh seeds, 432 games, Zerg v3 to 20 min): lost 23 (24), won 140 (135);
    # Zerg v3 won 68 (59) lost 0 (3), Zerg v2 lost 5 (8), the replayed pros on Heartbreak Ridge lost 10 (6).
    # home_scvs alone, before its defenders were left alone in fights: lost 26, won 139. In v0.21
    "balance": lambda m: m.update(home_scvs=True, balance=True),
    # fight.py DetectRule: a lurker that burrowed near Gary's fighters is scanned (a Comsat with 50 energy).
    # On v0.21: scans in 18 of 32 lurker games, no result changed in 432 (the lurker games end undecided). In v0.22
    "detect": lambda m: m["fight"].update(before=list(m["fight"].get("before", [])) + ["detect"]),
    # posture.py force_at: the early-pool defense from 2:30 whatever the rules see (unless they switched first).
    # Learned from paired games (train/early_switch.py, v021+watch, 312 games with Zerg v3's three plans):
    # a tree over what the scout saw gains no more than this (+0.089 a game across seeds, both). On v0.21
    # (432 games, the new baseline): lost 15 (30), won 115 (118). In v0.22
    "defend_early": lambda m: m.update(defend_early=150 * 24),
    # macro.py expand_mass: the expansion once the model's odds of it, summed over Gary's decisions since
    # the last, reach one (the favorite never picks a third base). On v0.22 (432 games): won 109 (108), lost
    # 11 (11); Zerg v3 games at 20:00 on 3+ Command Centers 31 of 48 (5 of 49). Forcing the natural too
    # (at 4:00-6:00, under pressure) lost 15. In v0.23
    "expand": lambda m: m["macro"].update(expand_mass=1.0),
    # macro.py odds_mass: every one-off decision (a tech building, an add-on, research, an upgrade) once its odds,
    # summed over the decisions taken while it was possible, reach one (as expand_mass for expansions)
    "mass": lambda m: m["macro"].update(odds_mass=1.0),
    # macro.py: no bunker at the natural (the 2010s TvZ habit: against the modern pros on the ladder maps Gary-T
    # had 2 bunkers at 5-10 minutes where they have 0-1, its biggest tell there; eval/humanlike.py --pros-era modern)
    "nonatbunker": lambda m: m["macro"].update(natural_bunker=False),
    # macro.py: a depot ahead of production (each producer under 2 supply left), as the scripted builds: the model
    # leaves Gary-T supply-blocked (42 of 48 games at 4-8 minutes, L5b; pros almost never are)
    "depots": lambda m: m["macro"].update(supply_ahead=True),
    # zerg_posture.py: no alarm (the normal posture, no alarm build): while on, the alarm forbade drones, 46% of 5-12
    # minutes in round G6, and gz1 ended there with 22 drones to the pros' 27-33
    "noalarm": lambda m: (m.update(posture="normal"), m["macro"].update(builds=[])),
    # zerg_posture.py NaturalColonies: the pros' natural colonies (a sunken from 3:45, a spare colony from 5:00 morphed
    # when a push is seen), the alarm's drones not forbidden
    "colonies": lambda m: (m.update(colonies=True, alarm_drones=False), m["macro"].update(builds=["alarm", "colonies"])),
    # answers.py: the zerg's plan read from what Gary saw (a tech scan of its main at 6:30 if nothing is
    # known), and the pros' answer to it as macro goals (against lurkers: Siege Mode, tanks, vessels,
    # Irradiate, turrets one a base; against mutalisks nothing: the model's own turrets do). On v0.23 (432
    # games): won 112 (109), lost 10 (11); against Zerg v3's lurkers won 11 of 32 (7). In v0.24
    "answers": lambda m: m["macro"].update(answers=True),
    # Human game 1 (v0.25 vs the user's Zerg, 2026-10-16, lost at 12:17): answers.py against mutalisks
    # (Engineering Bay, Academy, 2 turrets in every mineral line); fight.py's pull not against flyers nor
    # more than 8 zerg supply (x2). (Not a rule to end the rush defense: how much to commit to defense is
    # learned, the user's call: pros pull back just enough to survive, and the nuances are too many to script)
    # Judged by the next games against humans; the headless pool only checks they break nothing. In v0.26
    "muta_answer": lambda m: m["macro"].setdefault("answer_options", {}).update(mutas=True),
    # fight.py StimRule: stims when the pros would (gary/policy/stim.py, learned from 400 of their TvZ games;
    # human game 2: stim researched, never used)
    "stim": lambda m: m["fight"].__setitem__("before", m["fight"]["before"] + ["stim"]),
    # fight.py CastRule: Psionic Storms when and where the pros cast them (gary/policy/cast.py, train/cast.py; #4)
    "storm": lambda m: (m["fight"].update(before=list(m["fight"].get("before", [])) + ["cast"]),
                        m["fight"].setdefault("rule_options", {}).setdefault("cast", {}).update(spell="storm")),
    "repair_turrets": lambda m: m["fight"].setdefault("rule_options", {}).setdefault("repair", {}).update(turrets=3),
    "pull_cap": lambda m: m["fight"].setdefault("rule_options", {}).setdefault("pull", {}).update(ground_only=True, max_enemy=8),
    # posture.py v3: a pool finished by 2:40 is an early pool, with a natural or not. On v0.16 (v2),
    # replayed pros (buildings going up) lost 13 of 144 (15; Heartbreak Ridge 7, 9), the same hatch
    # firsts called early pools. In v0.16
    "pool_sure": lambda m: m.update(posture="early_pool/v3"),
    # fight.py: new fighters join Gary's nearest bunch of fighters, not the zerg directly. On v0.17:
    # Python (48 seeds) lost 5 (5); Zerg v2 (72) lost 13 (9); with regroup too 5 and 14 (regroup
    # alone 5 and 12). Not adopted
    "reinforce_pack": lambda m: m["fight"].setdefault("rule_options", {}).update(reinforce={"to_pack": True}),
    # posture.py v5: an alarm from nothing seen called off until 4:00; the main's bunker let out after.
    # On v0.17: replayed pros on three maps lost 11 of 144 (9), won 9 (2); the 9-pool lost 1 (1), won
    # 36 (27); Zerg v2 (72) lost 8 (10). In v0.18
    "posture5": lambda m: m.update(posture="early_pool/v5"),
    # posture.py v6: a zergling mass seen (6+ at once, 1.5x Gary's army, 3:30-8:00): the
    # ling_flood_defense build (macro.py), no expansion, the army home, bunkers manned. With watch
    # (the scout that sees it coming), on v0.18, lost (v0.18): Zerg v2 (72) Fighting Spirit 8 (8),
    # Python 7 (11); replayed pros (48) Python 8 (3), Fighting Spirit 6 (5), Heartbreak Ridge 4 (3);
    # the 9-pool 1 (1), won 32 (36): 34 of 336 (31). It switches in 40% of the replayed pros' games
    # (false alarms), and in the losses only once the zerglings attack (6:07, 6:47); Gary floats
    # 400-700 minerals at 6:00 on one Barracks either way. Not adopted
    # the posture's mode from the plan policy (gary/policy/plan.py, the newest run: distilled from
    # v6's rules, then trained) with v6's builds
    "plan": lambda m: (m.update(posture="plan/v1"),
                       m["macro"].update(builds=m["macro"]["builds"] + ["ling_flood_defense"])),
    "flood": lambda m: (m.update(posture="early_pool/v6"),
                        m["macro"].update(builds=m["macro"]["builds"] + ["ling_flood_defense"])),
    # fight.py BlockRule: the chokes asked for (g.blocks; nothing in play asks yet: eval/block_drill.py
    # does) closed with units' bodies (gary/agent/block.py). ramp_auto: it asks for the main's ramp
    # itself on one base when zerg fighters are seen there. With the body block, on v0.18, lost
    # (without): Zerg v2 on Fighting Spirit 12 (8) and Python 10 (11) of 72; replayed pros (48)
    # Python 7 (3), Fighting Spirit 5 (5), Heartbreak Ridge 5 (3); the 9-pool 4 (1), won 25 (36): 43
    # of 336 (31). Against the 9-pool it takes the first marines the rush bunker at the ramp wants.
    # Not adopted: when to block is for a learned decision
    "block": lambda m: m["fight"].update(before=m["fight"]["before"] + ["block"]),
    # the decision learned from branches (train/block_decision.py, the newest run): on held-out games
    # -25 a moment against never blocking's 0 (docs/PROGRESS.md). Not adopted
    "block_learned": lambda m: (m["fight"].update(before=m["fight"]["before"] + ["block"]),
                                m["fight"].setdefault("rule_options", {}).update(block={"decide": "latest"})),
    "ramp_auto": lambda m: (m["fight"].update(before=m["fight"]["before"] + ["block"]),
                            m["fight"].setdefault("rule_options", {}).update(block={"auto_ramp": True})),
    "post_minerals": _roles(post="minerals"),   # ...between it and the minerals                +2 ± 8
    "post_bunker": _roles(post="bunker"),       # ...just behind the bunker by it nearest the zerg
    "post_ramp": _roles(post="ramp"),           # ...just inside the main's ramp (at the main)
    # posture.py v2: the rush bunker by the main's CC. On v0.12: replayed pros on three maps lost 3 of
    # 144 (19); the dummy's 9-pool 0 (2), its 7:00 rush 3 (0); won 3 and 3 (12 and 10)
    "bunker_cc": lambda m: m.update(posture="early_pool/v2"),
    # macro.py: roll the model's odds (a weighted shuffle) instead of taking the most likely decision.
    # Offline, on pros' states, it matched their Factory timing (63% by 8:00, theirs 62%; the
    # favorite 4%). In games on v0.14 (Fighting Spirit, replayed pros, 32 seeds): fewer SCVs (28 at
    # 12:00 against 41: the SCV is rolled less often than it's the favorite), army built 40 by 12:00
    # (57), a Factory by 8:00 in 9% (19%), lost 3 (2). Not adopted
    "dice": lambda m: m["macro"].update(decoder="dice"),
    # macro.py dice_t 0.7: dice from the odds raised to 1/0.7 (a 4.5% option about 1%, a 30% one about 30%): gt1dev's
    # dice drew 8.9 bunkers a game at 4.5% (pros build 0.5-1 by 10:00)
    "dice07": lambda m: m["macro"].update(dice_t=0.7),
    # docs/RACES.md step 2 (one macro decoder): the Zerg's decoder rules that aren't the larvae's, for any race: the next
    # look when the model's timing head says the pros' next decision comes (pace), a roll that waits for supply kept as
    # the roll for 30 s (hold), and while one waits anything doable at 5% or more taken (wait_min_p, in place of the
    # under-half rule). All three (ZP174a+b, ZT174a+b, 2026-10-30, 96 paired games against gz1dev): PvZ -0.086 +- 0.061,
    # TvZ -0.159 +- 0.079, the macro gap further at 5-25 minutes in both; pace took a third fewer decisions at 5-20
    # minutes (the Terran 163 a game, 235 without; the Protoss 203, 266), the bank up (the Terran's 2,631 minerals at
    # 10-20 minutes, 1,834), the army down: the pros' wait to their next decision is a larva burst's for the Zerg, one
    # unit's otherwise. So the two apart: pace alone, and holdwait (hold and the 5% floor)
    "zdecoder": lambda m: m["macro"].update(pace=True, hold=True, wait_min_p=0.05),
    # holdwait (HP175a+b, HT175a+b): PvZ -0.055 +- 0.065, TvZ +0.070 +- 0.095, the macro gap further at 5-10 minutes in
    # both (+0.062 [+0.035, +0.083], +0.071 [+0.046, +0.085]): the Protoss's 26 workers there (31 without, pros 36), the
    # 5% taken while a Probe waited for its Nexus; the under-half rule keeps a busy building's favorite, the 5% floor is
    # the larvae's
    # docs/RACES.md step 3 (the fight rules for every race): the Terran's workers' pull against an attack on a base
    # (its options: 3 workers an attacker, flyers not counted, not against more than 8 zergling's worth) and its new
    # fighters sent to a fight at home, for any race's fight layer
    "fightrules": lambda m: m["fight"].update(before=["pull"], in_fight=["reinforce"],
                                              rule_options={"pull": {"per_enemy": 3, "ground_only": True, "max_enemy": 8}}),
    "holdwait": lambda m: m["macro"].update(hold=True, wait_min_p=0.05),
    # training (docs/CONTROL.md step 7): the macro draws its next decision at temperature 1 (or
    # sample_t05: 0.5), each draw logged (g.macro.draws)
    "sample": lambda m: m["macro"].update(decoder="sample", temperature=1.0),
    "sample_t05": lambda m: m["macro"].update(decoder="sample", temperature=0.5),
    # the macro model trained from branches (train/macro_rl.py, the newest run)
    "macro_rl": lambda m: m["macro"].update(model="macro_rl/latest"),
    # the shared Terran macro model trained with every game's style (#54: the v2 catalogue, train/macro.py --styles v2;
    # the deployed one read the modern games' style as unknown)
    "stylev2": lambda m: m["macro"].update(model="runs/macro_exp/T_all_v2/model.pt"),
    # the stylev2 model with a gas head: its workers on gas (#55), the executor matching them
    "gastarget": lambda m: m["macro"].update(model="runs/macro_exp/T_all_v2gas/model.pt"),
    # the Zerg's: its TvZ macro model trained with every game's style (v2) and the gas head, its drones on gas
    "zgastarget": lambda m: m["macro"].update(model={"TvZ": "runs/macro_exp/Z_TvZ_v2gas/model.pt", "*": "macro/latest"}),
    # ...one model for every Zerg matchup (the matchup an input, as the Terran's and the Protoss's), with the styles and
    # the gas head: modern held-out top-1 / non-routine TvZ 0.567 / 0.489 (Z_TvZ_v2gas 0.557 / 0.481), PvZ 0.584 / 0.556
    # (its own 0.554 / 0.530, no gas head), ZvZ 0.644 / 0.637 (0.636 / 0.635)
    "zall": lambda m: m["macro"].update(model="runs/macro_exp/Z_all_v2gas/model.pt"),
    # each race's one macro model trained with every matchup's build styles (v2: taxonomy/label_all.py's plans for the
    # Terran in PvT and TvT, the Zerg in PvZ and ZvZ, the Protoss in PvP; the gas head): modern held-out non-routine
    # top-1 against the v2gas models', Terran TvZ 0.448 (0.452), TvT 0.377 (0.371), PvT 0.367 (0.368); Protoss PvT
    # 0.318 (0.316), PvZ 0.321 (0.320); Zerg TvZ 0.487 (Z_all_v2gas 0.489), PvZ 0.556 (0.556), ZvZ 0.651 (0.637)
    "allstyles": lambda m: m["macro"].update(model=f"runs/macro_exp/{m.get('race', 'T')}_all_v2all/model.pt",
                                             history_styles="v2"),     # (the pros' history per style by its catalogue)
    "mirrorroles": _mirror_roles,
    # the Zerg's fights against a Protoss by its role model from the pros' Zerg in PvZ (ingest/response_dataset.py --race Z
    # --matchups PvZ), not the TvZ one
    "pvzroles": lambda m: m["fight"].update(roles_data={"PvZ": "response_Z_PvZ_30min.npz",
                                                        "*": m["fight"].get("roles_data", "response_Z.npz")}),
    # the Terran's fights against a Protoss by its role model from the pros' Terran in PvT (in its "vs" section: there the
    # roles' rules played, and its pinned TvZ role model would come back with a model)
    "pvtroles": lambda m: m.update(vs={**m.get("vs", {}), "P": {**m["vs"]["P"], "fight": {
        **m["vs"]["P"]["fight"], "model": "roles/latest", "roles_model": None, "roles_data": "response_T_PvT_30min.npz"}}}),
    # ...from the same pros relabelled (#60): their tanks' and goliaths' turret fire and their medics' heals are fire, a
    # follow a move, and sieging, unsieging and laying a mine roles of their own, which the roles carry out (28% of the
    # labels were "other" before, carried out as nothing)
    "pvtmodes": lambda m: m["vs"]["P"]["fight"].update(roles_data="response_T_PvT_modes_30min.npz"),
    # roles.py learned/v1: the modes (siege, unsiege, a mine) drawn by their odds, the rest the likeliest (a decoder: the
    # likeliest laid 0.4 mines a game, the pros about 29, #60)
    "modedice": lambda m: [f.update(roles={**f.get("roles", {}), "mode_dice": True})
                           for f in [m["fight"]] + [v["fight"] for v in m.get("vs", {}).values() if "fight" in v]
                           if f.get("provider") == "roles" and f.get("model")],
    # the strategy selector (gary/agent/selector.py; its table: eval/selector_table.py): the build style
    # per map with the best expected score (selector_explore: a draw from each, Thompson sampling).
    # On v0.18 (fresh seeds 101+, 333 games): lost 30 (57), won 64 (57); Zerg v2 on Fighting Spirit
    # lost 3 of 72 (22). In v0.19
    "selector": lambda m: m["macro"].update(selector="play"),
    # the build style rolled per game by the pros' shares (rolled_style), not the selector's table: that was counted
    # in eval/vs_rush.py's short games against rushes on the 1.16 maps (2026-10-13), where two-Barracks marines (style
    # 4, 1.5% of pro Terrans: gas in 10% of them, no Factory) won most, and every 30-minute game on the ladder maps
    # borrowed it: Gary-T played style 4 in all 96 of rounds R50a+b (its macro gap: no gas, no Factory, mass marines)
    # terran_executor.py addon_room: a Factory, Starport or Science Facility placed only where its add-on fits
    "addonroom": lambda m: m.update(addon_room=True),
    # the pros' decision history in the macro model's inputs, fading to its own over HISTORY_FADE minutes (as gz1's): on
    # gt1's own marine-heavy states the model, calibrated on the pros', asked for Marines 42% and no mech (the macro
    # check); its own past fed back on itself
    "prohist": lambda m: m["macro"].update(history="pro"),
    # the Zerg's macro model reading its own decisions so far, as its data counts them (the pros' history off: the stop-gap
    # "the pros' decision history", AGENTS.md; ownsupply, its exception, then has nothing to act on)
    "ownhist": lambda m: m["macro"].update(history=None),
    # gary/policy/macro.py own_keys: with the pros' history, the supply provider's entry its own (the pros' early
    # overlord in it told Gary-Z's model one was coming: at 9/9 it gave Overlord under 1%, blocked 67% of 2:00)
    "ownsupply": lambda m: m["macro"].update(own_supply=True),
    # the gas head reads the decisions waiting for their money (the goal, the parked decision) as decided: a Lair parked
    # for its gas read as no Lair at 3:00, where pros pull off gas, and the Lair waited 30 s for gas that never came (#51)
    "gaswaits": lambda m: m["macro"].update(gas_waits=True),
    # up to three builds parked at once, each one's worker walking to its spot while production goes on (one at a time:
    # a build goal waited behind the parked one and held the macro, 580 of Gary-Z's 775 goals timed out in 96 games, #51)
    "parkmany": lambda m: m["macro"].update(parked_max=3),
    # gary/policy/macro.py look: the macro model's inputs as the replays it learned from count them, what is in sight
    # looked at every second (not only when the model is queried: its "most enemies seen" stayed 0 in play) and the
    # units inside a bunker counted (5 marines seen where the replay had 13 at 6:00)
    "seenall": lambda m: m["macro"].update(look_seen=True),
    # gary/policy/macro.py reconcile: the buildings among the model's decisions so far as the replays count them (every
    # building started, a rule's too; a decided one never started taken back): its looks need seenall
    "builtcount": lambda m: m["macro"].update(built_count=True, look_seen=True),
    # gary/policy/macro.py pending_own: a building decided and not started yet among the model's own counts, as the
    # replays count it (a pro's builder walks before the order); with builtcount's pending decisions
    "pendown": lambda m: m["macro"].update(pending_own=True, built_count=True, look_seen=True),
    # the Protoss macro model with Archon and Dark Archon merges among its decisions (the pros' merge orders, one decision
    # an Archon begun: ingest/macro_dataset.py), carried out by two Templar merged (protoss_executor.py); P_all_v2arch,
    # held out 47.8% top-1 against P_all_v2all's 47.5% on the same samples
    "archons": lambda m: m["macro"].update(model="runs/macro_exp/P_all_v2arch/model.pt"),
    # macro.py count_first: the models' own counts as the replays count them (a building's queue past its unit in
    # training left out, the workers inside a gas building in; #50): its looks need seenall
    "unitcount": lambda m: m["macro"].update(unit_count=True, look_seen=True),
    # gary/policy/army.py extra_units: the army model's own unit counts with the units in production and inside a
    # bunker, as its dataset counts them (in play: 5-6 marines where the dataset had 13-15, issue #29)
    "armyseen": lambda m: m["army"].update(army_seen=True),
    # macro.py eggs_seen: a race whose production is in sight (the Zerg's eggs) doesn't add its units in production to
    # the macro model's own counts, as the replays don't (22 zerglings read at 6:00 where the replay had 6)
    "eggs": lambda m: m["macro"].update(eggs_seen=True),
    # three registered rules off (AGENTS.md): the pros' caps per minute; SCVs capped at the bases' saturation (MAX_SCVS
    # stays); depots ahead of production
    "nocaps": lambda m: m["macro"].update(caps=False),
    "noscvcap": lambda m: m.update(scv_saturation=False),
    "nodepots": lambda m: m["macro"].update(supply_ahead=False),
    # macro.py bank_escape off: the runner-up isn't taken just because the bank is over 400 while the favorite waits
    # (with the caps off it made 341 of 1,174 turrets at 5-20 minutes, and 759 of 2,206 SCVs with the SCV cap off)
    "nobank": lambda m: m["macro"].update(bank_escape=False),
    # macro.py queue_depth 2: two of the model's waiting units per producer (pros queue in the building; one each,
    # the favorite blocked, the decoder took the runner-up: 58% of the turrets with the caps off)
    "qdepth2": lambda m: m["macro"].update(queue_depth=2),
    # terran_executor.py train_depth 2: the model's unit trained into a busy building's own queue (two deep) and paid
    # for, as pros queue; else it waits for the building and, its queue full, holds the macro (the bank escape covers
    # for that: off, 1,124 minerals banked at 5-15 minutes, pros 511)
    "gamequeue": lambda m: m.update(train_depth=2),
    # army.py hunt_advice: with the hunt off, what it would do written to the records (the rule's labels on the
    # model's own states, to imitate it)
    "huntadvice": lambda m: m["army"].update(hunt_advice=True),
    # macro.py rethink: a unit whose producers' queues are full isn't held as the goal; the model is asked again
    "rethink": lambda m: m["macro"].update(rethink=True),
    # macro.py nosave: a goal the money doesn't cover yet isn't held; the model is asked again at its next look
    "nosave": lambda m: m["macro"].update(nosave=True),
    # the stop-gaps over the layers being learned off (AGENTS.md: gt1dev and gz1dev run without them, so the models
    # own those decisions and are judged without the rules): over the army the commit model moves, the static guard,
    # the hunt (its search and scans), the overlord hunt, Gary-Z's join, sweep and press; over the macro, the pros'
    # caps, the SCV saturation cap, the bank escape, supply ahead of production. Kept: the rules that alone move units
    # no model decides (Gary-Z's overlord posts and mutalisk raid), and the decoders (the tech path's floor: without it
    # dice drew Gary-Z a Lair and a Hydralisk Den on 8 drones)
    "unscripted": lambda m: (m["army"].update(static_odds=None, hunt=False,
                                              rules=[r for r in m["army"].get("rules", ()) if r in ("posts", "raid")]),
                             m["macro"].update(caps=False, bank_escape=False, supply_ahead=False),
                             m.update(scv_saturation=False)),
    # army.py static_odds off: the static guard's veto gone (pros attack spots it forbids: 29% of their engages into
    # static defense are under 1.5 times it, held-out modern TvZ)
    "noguard": lambda m: m["army"].update(static_odds=None),
    # army.py static_beta 2: the static guard as a nudge, not a veto: a spot the group doesn't outweigh 1.5 times keeps
    # its odds times (the group / 1.5 times its defense) squared (a quarter at half of it)
    "softguard": lambda m: m["army"].update(static_beta=2.0),
    # Terran commit models on army dataset v4's 4,841 player-games (train/commit.py --out runs/commit_exp/...): with the
    # enemy's static defense as a map channel, and its control without it (the same games)
    "cmstatic": lambda m: m["army"].update(model="runs/commit_exp/TvZ_T_v4_static/model.pt"),
    "cmnostatic": lambda m: m["army"].update(model="runs/commit_exp/TvZ_T_v4_nostatic/model.pt"),
    # Terran commit models on army dataset v5 (the hunt's inputs: enemy buildings known still standing, cells unseen):
    # imitating the scripted hunt (its advice in 96 gt1dev games as engage labels, x4: where it acts, held-out, engage
    # 0.80 and its target among the five likeliest cells 0.94, the control's 0.16 and 0.12), and the control
    "cmhunt": lambda m: m["army"].update(model="runs/commit_exp/TvZ_T_v5_hunt/model.pt"),
    "cmv5": lambda m: m["army"].update(model="runs/commit_exp/TvZ_T_v5_inputs/model.pt"),
    # the same on all of army dataset v5 (16,549 TvZ games, 60 ticks a player-game): the control and the hunt imitated
    # (held-out order AUC 0.767 / 0.765, engage 0.778 / 0.776; where the hunt acts 0.81 engage, its target in the
    # five likeliest 0.91)
    "cmv5all": lambda m: m["army"].update(model="runs/commit_exp/TvZ_T_v5all_inputs/model.pt"),
    "cmhuntall": lambda m: m["army"].update(model="runs/commit_exp/TvZ_T_v5all_hunt/model.pt"),
    # all of v5 with the deployed model's inputs (no new channels): whether the v5 models trail it for the channels
    # army.py engage_bias ln 2: the commit model's engage odds doubled against move's (issue #28: at the locked pairs'
    # moments engaging beat moving by +0.81 a pair, +0.42 to +1.24, the deployed model engaging 55% of them)
    "engagebias": lambda m: m["army"].update(engage_bias=0.693),
    # army.py hold_target: a commitment decided again keeps its destination while the model still rates it among the
    # five likeliest cells (a decoder, tried for the pipe check, issue #47; HT120a against DC100a -0.011 +- 0.087: not
    # adopted, the army's redirects are the pros' rate on the same measure)
    "holdtarget": lambda m: m["army"].update(hold_target=True),
    # army.py unit_commits: a cluster's order leaves out units on another cluster's fresh commitment (issue #47; UC120a
    # against BL120a -0.048 +- 0.064: not adopted)
    "unitcommits": lambda m: m["army"].update(unit_commits=True),
    # executor.py wide_spot: with no spot at Gary's bases, the main's box widened (its own level first), then the
    # natural's area with no town hall yet (a full main on one base dropped 16.8 builds a game in gt1dev; issue #47)
    "widespot": lambda m: m.update(wide_spot=True),
    # executor.py place: a building's base and side drawn from the placement model's odds (the pros' buildings against
    # what they knew: gary/policy/placement.py, #65), where the matchup's race has one (the Protoss)
    "place": lambda m: m.update(place=True),
    # the deployed commit model fine-tuned 2 epochs on army dataset v3, with the hunt's labels (x4) and without (the
    # control): the labels' effect apart from v5's data change (issue #3; FH120a against FC120a -0.078 +- 0.090)
    "cmfthunt": lambda m: m["army"].update(model="runs/commit_exp/TvZ_T_ft_hunt/model.pt"),
    "cmftctl": lambda m: m["army"].update(model="runs/commit_exp/TvZ_T_ft_control/model.pt"),
    "cmv5plain": lambda m: m["army"].update(model="runs/commit_exp/TvZ_T_v5all_plain/model.pt"),
    # the hunt imitated only where its target has no known static defense (401 of its 644 labels; the first copied its
    # attacks into sunkens, 0.51 of its engages)
    "cmhuntu": lambda m: m["army"].update(model="runs/commit_exp/TvZ_T_v5_hunt_undef/model.pt"),
    "styleroll": lambda m: m["macro"].update(selector=None, style="roll"),
    "selector_explore": lambda m: m["macro"].update(selector="explore"),
    # fight.py: pull workers only for zerg in the mineral line (not at a bunker further out). On the
    # fast pools that beat v0.12 on Heartbreak Ridge it kept a few more SCVs; the bunker's spot mattered
    "pull_line": _pull(mineral_line=True),
    "pull_attacked": _pull(attacked_only=True),   # fight.py: pull workers only when zerg attack  +2 ± 3, [239] +3 ± 3
    "pull_ratio15": _pull(ratio=1.5),       # ...when the zerg outweigh the army 1.5 to 1      [239] -3 ± 4
    "pull_ratio2": _pull(ratio=2.0),        #                                                   [239] -6 ± 5
    "pull_delay2": _pull(delay_s=2),        # ...after 2 s of threat without a break           [239] -4 ± 4
    "pull_delay4": _pull(delay_s=4),        #                                                   [239] -19 ± 7
    "pull_one": _pull(per_enemy=1),         # one worker per enemy unit (and one)               [239] -13 ± 4
    "pull_three": _pull(per_enemy=3),       # [239] +8 ± 2 (4: +8 ± 3, 5: +9 ± 3); 9-pool 6 of 48 (v0.10 4): in v0.11
    "pull_three_half": _pull(per_enemy=3, max_share=0.5),   # ...at most half the base's workers (9-pool: no change)
    "pull_three_60": _pull(per_enemy=3, max_share=0.6),
    "pull_four": _pull(per_enemy=4),
    "pull_five": _pull(per_enemy=5),
    "pull_ratio07": _pull(ratio=0.7),       # ...already when the zerg are 0.7 of the army      [239] +1 ± 4
    # a fight interrupts waiting builds: +3 ± 6, [239] +6 ± 4; but 9-pool lost 3 (the bunker comes late)
    "suspend": lambda m: m.update(arbiter="fixed_priority/v2"),
}


def manifest_of(name: str | dict) -> dict:
    """A manifest by name, with options: "v010+post+suspend" is v010 with those OPTIONS."""
    if not isinstance(name, str):
        return copy.deepcopy(name)
    base, *options = name.split("+")
    m = copy.deepcopy(MANIFESTS[base])
    for o in options:
        OPTIONS[o](m)
    return m


# the one Gary playing Terran (2026-10-20): v0.29 with the options adopted round by round since (commit, draw,
# floor, mass, nonatbunker, depots: docs/PROGRESS.md L5-L6; lords: round G13), folded into one name; and the hunt
# (army.py) also when 4x ahead of the enemy fighters seen in the last minute, searching unseen bases with squads
# (round Jhs against G13: won 24 (21), lost 2 (3)); engages only where the group outweighs the static defense
# (round Jstatic against Jhs: the same 24 won, led at 20:00 15 (12), supply killed / lost 78.8 / 44.8 a game to
# 71.9 / 52.6); the fight roles from whole games to 30 minutes, old and modern (96 paired games against gt0.3,
# rounds B30 + B30b against R30T + R30Tb: won 54 (57), lost 9 (7), the gap per 5-minute window within noise in
# every window; adopted as the model that has seen late-game and modern fights); a unit alone and outnumbered in
# contact decided by the roles model, not the hand rules (96 paired games against gt0.4: won 57 (54), lost 8 (9),
# gap within noise; retreats doubled, though the model still rarely backs a lone unit off: its calibration is the
# next step, self-play's). Changes are judged as options against it, and an adopted one goes in here
# gt0.6: Factories, Starports and Science Facilities placed where their add-on fits (option addonroom; 96 paired games
# against gt0.5, rounds AR50a+b against B50a+b: won 49 lost 10 against 48 and 13, better in 23 and worse in 13, the
# gap even; Control Towers 0.82 -> 1.42 and Science Vessels 1.8 -> 2.9 at 16:00)
# gt0.7: keep_busy gone (it trained idle producers' last unit, half the marines at 10-20 minutes), the model's waiting
# decisions queued up to one per producer instead (48 games against gt0.6, Q60a against B60a: won 30 lost 5 against 29
# and 5, the gap -0.002; macro decisions 13,203 -> 19,347, the caps fired 0.63 -> 0.46 a decision)
# gt0.8: depots ahead of production gone, the model's own depots (96 paired games against gt0.7, ND70a+b against
# Q60a+b: won 49 lost 18 against 50 and 16, paired -0.018 +- 0.101, the gap -0.013, -0.040 to +0.012; blocked at 5-10
# minutes 14% of the time, pros 9%, gt0.7 2%; at 10-20 minutes 2%, pros 14%, gt0.7 0.2%)
# gt0.9: the model's units trained into a busy building's own queue, two deep (gamequeue; 96 paired games against
# gt0.8, GQ80a+b against ND70a+b: won 56 lost 12 against 49 and 18, better in 34 and worse in 21, +0.068 +- 0.102, the
# gap +0.018, -0.010 to +0.037; macro decisions 20.1 a minute, the pros' 20.3)
# gt0.10: the static guard a nudge, not a veto (softguard; 96 paired games against the hard guard, SG80a+b against
# ND70a+b: better in 4, worse in 9, -0.016 +- 0.035, the gap +0.001: no measurable difference, so the veto goes)
# gt0.11: every build's fix of 2026-10-31: the model's decisions that ended without their command taken back from its
# decisions so far, and a key the hands didn't give (no APM left) given again (#47, as gt0.25dev's)
MANIFESTS["gt1"] = {**manifest_of("v029+commit+draw+floor+mass+nonatbunker+lords+hunt4+split+static+roles30+lone"
                                  "+addonroom+gamequeue+softguard"), "version": "gt0.11"}
# gt1dev: the Terran Gary that learning is trained and judged in (AGENTS.md): gt1 with the role model deciding in
# contact as well (attended pro units with their re-issues as a decision, again, Gary's own order rate as input, its
# moves kept current, several orders a turn) and the army on control groups by type, a key's units drawing their
# decisions together (again in it since its pipe check moves reach: 67% -> 72% pushed, without it none). Weaker than gt1 today
# (the state-selected suite: +110 against +141; Terran grouping 45 won 17 lost against 57 and 8 in 96 games); it
# becomes gt1 when it beats it in 96 paired games
# gt0.6dev: its role model from the first roles RL run (option rl1; 96 paired games against gt0.5dev, rounds R50a+b
# against D50a+b: won 54 lost 15 against 39 and 16, better in 34 games and worse in 20, the gap -0.046, -0.070 to
# -0.012, macro features -0.053; against gt1 better in 28 and worse in 20, the gap even, macro +0.035, -0.009 to +0.070)
# gt0.7dev: gt1's add-on room (gt0.6); gt0.8dev: gt1's queue without keep_busy (gt0.7); gt0.9dev: gt1's own depots
# (gt0.8); gt0.10dev: gt1's in-building queue (gt0.9), without the army's and the macro's stop-gaps (unscripted), the
# hunt in advice mode (huntadvice: its labels in the records, play unchanged; baseline DV90a+b); gt0.11dev: the macro
# draws from the model's odds (dice; 96 paired games against gt0.10dev, DC100a+b against DV90a+b: lost 18 against 29,
# +0.058 +- 0.083, the gap -0.073, -0.096 to -0.035, macro -0.105; the bank at 5-15 minutes 263, pros 511, 843 before)
# gt0.12dev: buildings placed in a wider box at the main, then the natural, when its bases are full (widespot; 96 paired
# games against gt0.11dev, WS121a+b against BL121a+b: -0.013 +- 0.029, the gap -0.021, 25-30 minutes -0.062, -0.098 to
# -0.030; builds dropped for "no spot" 17.3 a game to 3.4, decisions carried out 0.82 to 0.86, eval/macro_pipe.py)
# gt0.13dev: the macro model's inputs as the replays it learned from count them (seenall: what is in sight looked at
# every second, the units inside a bunker counted; in play its most-enemies-seen inputs had stayed 0). A fix: 96 paired
# games against gt0.12dev, SA125a+b against WS121a+b: +0.031 +- 0.069, lost 22 (32), the gap -0.023, -0.076 to +0.028
# gt0.14dev: the army model's own unit counts as its dataset's (armyseen: the units in production and inside a bunker;
# in play it read 5-6 marines where the dataset had 13-15). A fix: 96 paired games against gt0.13dev, AS141a+b against
# SA125a+b: +0.016 +- 0.050, lost 18 (22), the gap -0.010. (On the Zerg it leaned worse, -0.044 +- 0.053: not in gz1dev.)
# gt0.15dev: the buildings among the model's decisions so far counted as the replays count them (builtcount; 3 Barracks
# where the replay had 1, the rules' bunkers never counted). A fix: 96 paired games against gt0.14dev (BC142a+b against
# BX141a+b): -0.005 +- 0.068, macro -0.036 (-0.092 to +0.006), bunkers at 10-20 minutes 3.31 (3.87; pros 0.5-0.75)
# gt0.16dev: the models' own counts as the replays count them (unitcount: the queue past the unit in training left out,
# the SCVs in a Refinery in). A fix: 96 paired games against gt0.15dev (UC143a+b against BC142a+b): -0.031 +- 0.073,
# the gap +0.024, macro +0.039 (-0.011 to +0.099), not measurably different
# gt0.17dev: the pros' build styles by their shares (styleroll: standard bio 82%) in place of the selector's style 4
# (two-Barracks gasless marines, 1.5% of pro Terran games, from a table counted on 1.16 anti-rush games). Judged on the
# build first (AGENTS.md, fidelity before wins): 96 paired games against gt0.16dev (SR144a+b against UC143a+b), every
# 5-minute window of the gap nearer the pros (-0.050 to -0.112; macro -0.073 to -0.159), a Refinery by 5:00 in 36% (6%;
# pros 95%), Factories at 20-30 minutes 2.1 (1.2; 3.4), tanks 5.3 (3.3; 7.0), vultures 0.9 (0; 2.3); results +0.076 +- 0.087
# gt0.18dev: without the early-pool posture (noalarm: it went to rush defense in every game, half of them blind, and held
# off gas and the natural to 3.6-4.6 minutes); the macro model sees the pool and the zerglings itself (seenall). Judged per
# style (eval/style_adherence.py) against the modern pros of that style on the ladder maps, 96 paired games (NA145a+b
# against SR144a+b): style 1 played in 100% (96%), its natural at 3.2 minutes (4.5; pros 2.7), gas 3.6 (4.5; 3.1), a
# bunker at 6.1 in 60% (2.5 in 100%; 5.5 in 56%), a Factory by 8:00 in 59% (45%; 88%); style 2 in 100% (75%), its Factory
# at 3.1 (4.2; 2.5); results +0.018 +- 0.072, lost 21 (28). And the styles rolled by the modern pros' shares
# gt0.19dev: the macro model trained with every game's style (stylev2, #54). Judged per style against the modern pros of
# that style, 96 paired games (SV147a+b against BL146a+b): style 1 a Factory by 8:00 in 66% of games (50%; pros 88%), a
# Starport 16% (13%; 55%); style 2 its natural by 8:00 in 47% (19%; 98%), a Starport 50% (16%; 69%); style 1's natural
# 89% (100%). The gap 0-5 minutes -0.025 [-0.046, +0.002], all -0.058, 10-30 minutes further; results -0.14 (lost 39, 28):
# kept on here by "Fidelity before wins" (AGENTS.md), the losses reviewed: the same SCV odds a decision on an economy
# behind the pros' from 2:00 (#55: workers 22 at 5:00, 23 before, pros 29)
# gt0.20dev: the workers on gas the macro model's decision (gastarget: the stylev2 model with a gas head, #55). Judged
# per style, 96 paired games (GT152a+b against GW151a+b): style 2's gas mined by 150/180/210 s 36/124/184 (48/200/356;
# pros 104/108/188), its natural at 3.6 minutes in 100% (4.6 in 72%; 3.2 in 98%), a Starport 81% (59%; 69%); style 1 a
# Factory by 8:00 in 95% (73%; 88%); results +0.036 +- 0.123 and -0.010 +- 0.131, lost 28 (32)
# gt0.21dev: against a Protoss, its fights by the role model of the pros' Terran in PvT (pvtroles) in place of the roles'
# rules. 48 paired games against gt0.20dev (PV163a against PV162a): the Protoss's score -0.016 +- 0.152, its fight gap
# +0.067 [-0.015, +0.143] (10-15 minutes +0.149): no measurable difference; the pros' "other" role (28% of the labels,
# siege and mines) is carried out as nothing (#60). TvZ unchanged
# gt0.22dev: against a Protoss, the PvT role model relabelled with siege, unsiege and mine roles the roles carry out
# (pvtmodes) and those modes drawn by their odds (modedice, #60). The relabelled model alone, 96 paired games against
# gt0.21dev (PV165a+b against PV164a+b): the Protoss's score -0.049 +- 0.096, the fight gap -0.002 [-0.072, +0.057], 0.4
# mines a game (a mine is never a Vulture's likeliest role). Drawn, against it (PV166a+b against PV165a+b): +0.039 +-
# 0.082, the fight gap -0.112 [-0.168, -0.040] nearer, by 20:00 sieges 101 (27; pros 52), mines 17 (0.2; 114), its tanks
# sieged 21% of their time (10%; 47%)
# gt0.23dev: against a Terran, its fights by the role model of the pros' Terran in TvT (mirrorroles, its modes drawn),
# not the TvZ one. 96 paired games against gt0.22dev, side A of the mirror (TR168a+b against TT168a+b): the score
# -0.029 +- 0.091, the fight gap -0.193 [-0.274, -0.049] nearer (10-15 minutes -0.493, 15-20 -0.302, 20-25 -0.316).
# TvZ and PvT unchanged
# gt0.24dev: its macro model trained with every matchup's styles (allstyles: T_all_v2all), so it plays a style in PvT
# and TvT too. 96 paired TvZ games against gt0.22dev/gt0.23dev (TS169a+TS170b against ZB169a+TB170b, the second half
# against gz0.11dev): the Terran's score +0.086 +- 0.077, the gap -0.001 [-0.041, +0.040], its styles played as before
# gt0.26dev: every dev build's fix of 2026-11-02: a building placed that never started (the game refused it at the spot, or its
# order was lost) taken out of its decisions so far at once, as the replays count only buildings that started (builtcount
# kept it 60 s, and the model didn't decide it again meanwhile: a Cybernetics Core refused at 3:44 never came, gp0.12dev);
# a plain fix, adopted on the input check; refused tech buildings decided again after a median 33 s (62 s), 8 PvZ games
# (RF189a against PY188a's)
# gt0.28dev: the fix of 2026-11-03, every build's hands (executor.py): a placed build's builder no longer hidden from
# the idle check for its walk's 40 s, and a worker Gary knows is due (just made, or a builder walked home) looked at
# at once off screen; Gary-P's Probes idle at the main at 1:40-4:20 0.22 at a time (0.46, the pros 0.13), 16 PvZ games
# on the same seeds (PL203a against PL201a)
# gt0.27dev: every dev build's fix of 2026-11-02 (later): a building decided and not started yet counted among its own
# units (pendown), as the replays count it (a pro's builder walks before the order, the building starts with it: a
# Stargate decided and none in the pros' own in 99 of 25,884 PvZ states at 3-8 minutes); an input fix, adopted on the
# input check (no new difference). Gary-P's second Stargate 1.5 to 1.2 a game (the pros 1.0), its Corsairs at 12:00
# 7.4 to 4.2, 16 PvZ games paired on map and seed (PD190a against BL191a)
# gt0.25dev: every build's fix of 2026-10-31: decisions that ended without their command (dropped while waiting, their
# building gone, refused by the game) taken back from its decisions so far, as the replays count the commands given, and a
# key the hands didn't give (no APM left) given again, not lost; plain fixes, adopted on the input check (#47: 7 Marines
# and 2 SCVs decided over the replay's at 9:00 of its game, now none; the decided block off at 57% of moments, now 5%)
MANIFESTS["gt1dev"] = {**manifest_of("gt1+again+refresh+incontact+batch+grouping+together+rl1+unscripted+huntadvice"
                                     "+dice+widespot+seenall+armyseen+builtcount+unitcount+styleroll+noalarm+gastarget"
                                     "+pvtroles+pvtmodes+modedice+mirrorroles+allstyles+pendown"),
                       "version": "gt0.28dev"}

# gz0.2dev: gz1 without the stop-gaps over its learned layers (unscripted): the Zerg side of TvZ self-play;
# gz0.3dev: the overlord's history its own (ownsupply: the pros' history in its inputs held their 9-supply overlord,
# so the model thought one was coming; 48 paired games against gt1dev, ZO110a against ZD110a: the Terran's score
# -0.286 +- 0.117, the Zerg winning or ahead at 30:00 in 22 of 48 (4), blocked at 3:00 1% (42%), drones at 10:00 30
# (20, pros 28))
# gz0.4dev: the macro model's inputs as its replays count them (seenall, as gt0.13dev): 96 paired games against
# gz0.3dev, both against gt1dev+seenall (ZS140a+b against ZB140a+b): the Zerg's score +0.042 +- 0.051, its gap +0.057
# (-0.003 to +0.114), macro +0.086 (+0.006 to +0.170) further over whole games, no window measurable
# gz0.5dev: Gary-Z's role model given hidden enemies' HP as full, as its data (zfullhp; it read 0): a fix, its 96 paired
# games against gz0.4dev (ZH142a+b against LB141a+b) -0.029 +- 0.052, not measurably different; its decisions barely move
# (retreat 6.6% of them against 6.2%, close in 4.8% against 4.1%; the retreat rule weighs supply, not HP)
# gz0.6dev: the units in eggs not counted twice in the macro model's own counts (eggs), as its replays count them. On by
# AGENTS.md's fidelity rule though its 96 paired games lost (EG141a+b against ZP141a+b, the Zerg -0.117 +- 0.063): the
# right counts move the model off zerglings to Hydralisks and it slows (#48), which is the thing to fix, not the input
# gz0.7dev: the drones on gas the macro model's decision (zgastarget: its TvZ model with every game's style and the gas
# head, the floating-gas rule off with it, #55). 96 paired games against gz1dev, both against gt0.20dev (ZG153a+b against
# ZB153a+b): gas mined by 5:00 / 8:00 in style 0 496 / 1,840 (448 / 1,440; pros 840 / 2,624), the first Extractor 2.2
# minutes (2.9; pros 2.0); the hatchery-first styles opened pool first more (style 1 in 62% of games, 38%), its gas banked
# (632 at 8:00, 340); the Terran's score +0.047 +- 0.082, the Zerg's gap +0.004 [-0.062, +0.086]: no measurable difference
# gz0.8dev: its buildings, tech and expansions in the history its own (ownbuilds, #56). 96 paired games against gz0.7dev
# (OB154a+b against ZG153a+b): told a hatchery-first style it plays it (style 1 in 38% of games, 0%; style 4 75%, 17%;
# style 6 50%, 0%), pool first in style 2 as before (62%, 69%); the Terran's score +0.000 +- 0.082, the gap +0.008
# [-0.051, +0.065]
# gz0.9dev: three builds parked at once (parkmany) and the gas head reading the decisions waiting for money as decided
# (gaswaits, #51). 96 paired games against gz0.8dev (PG155a+b against OB154a+b): goals timed out 142 (775), banked at 15:00
# 930 minerals (1,676; pros 819), drones 36 (32; pros 37), the Lair at 3.0-3.3 minutes (3.5-3.9; pros 2.9-3.1); the
# Terran's score -0.193 +- 0.078 (Gary-Z won 22, 11); the gap +0.063 [+0.007, +0.126] further, its macro part: gas banked
# (920 at 10-15 minutes, pros 499) and 138 supply at 20-30 (84), the fight part -0.040 [-0.107, +0.018]
# gz0.10dev: against a Protoss, its fights by the role model of the pros' Zerg in PvZ (pvzroles), not the TvZ one. 48
# paired games against gz0.9dev (PZ163a against PZ162a): the Protoss's score -0.031 +- 0.095, its fight gap -0.077 [-0.202,
# +0.038] nearer (25-30 minutes -0.253 [-0.420, -0.083]). TvZ unchanged
# gz0.11dev: one macro model for every Zerg matchup, as the Terran's and the Protoss's (allstyles: Z_all_v2all, the
# matchup an input, every matchup's styles, the pros' history per style), in place of the TvZ model and the older
# shared one. 48 paired games against gz0.10dev, both against gt1dev (ZS169a against ZB169a): the Zerg's score -0.062
# +- 0.107, not measurably different (Z_all_v2gas, zall: -0.078 +- 0.076 over 96), its style played as told in 56% of
# games (48%), the fight gap -0.059 [-0.091, +0.002]. And against a Zerg, its fights by the role model of the pros' Zerg
# in ZvZ (mirrorroles): 96 paired games against gz0.10dev (ZR168a+b against ZZ168a+b) +0.016 +- 0.068, the fight gap
# +0.021 [-0.010, +0.057]: no measurable difference, each matchup by its own pros as the other races
# gz0.12dev: its macro model reading its own decisions so far, as its data counts them (ownhist: the pros' history off,
# and with it ownbuilds, gz0.8dev's exception to it). 96 paired games against gz0.11dev, both against gt1dev (HO172a+b
# against HB172a+TS170b): the Zerg's score +0.039 +- 0.092; drones 27% of its decisions at 6:00-7:30 (26% with the history,
# pros 17-24%): the feedback loop the history was for didn't come back; the macro gap -0.022 [-0.142, +0.094] (10-15
# minutes +0.051 [+0.013, +0.081] further, 20-30 nearer)
# gz0.13dev: the buildings among its decisions so far counted as the replays count them (builtcount, as gt1dev's), an
# input fix adopted on the input check (tests/test_inputs.py: the Spire and the Mutalisks decided no longer counted over
# the replay's, +0.37 each without it), with the tracker copy's pending fixed (a copy for the gas head, gaswaits, put its
# decisions in the live tracker's pending)
# gz0.14dev: every build's fix of 2026-10-31 (as gt0.25dev's): decisions that ended without their command taken back
# from its decisions so far; 4 of the input check game's 17 Mutalisk morphs were refused by the game (sent a second
# after another) and still counted, now none (#47)
# gz0.15dev: the fix of 2026-11-02 (as gt0.26dev's): a building placed that never started taken out of its decisions so far
# gz0.16dev: a building decided and not started yet among its own units, its Drone gone (pendown, as gt0.27dev's)
# gz0.17dev: gt0.28dev's fix
MANIFESTS["gz1dev"] = {**manifest_of("gz1+unscripted+seenall+zfullhp+eggs+allstyles+gaswaits+parkmany"
                                     "+pvzroles+mirrorroles+ownhist+builtcount+pendown"),
                       "version": "gz0.17dev"}

# gp0.4dev: gp1 without the stop-gaps over its learned layers (unscripted: the hunt, a Pylon ahead of production) and
# its army on control groups by type (grouping, as gt1dev's and gz1's): the Protoss's dev build, where its learning is
# done and judged as the other races'. 96 paired games each against gp1: PvT against gt1dev (DV173a+b against
# AV171a+b) -0.029 +- 0.096, the gap -0.024 [-0.076, +0.020]; PvZ against gz1dev (DZ173a+b against BZ173a+b) -0.068
# +- 0.065, -0.021 [-0.060, +0.018] (10-30 minutes further: Dragoons decided by 20:00 21 a game, 34 with gp1, more
# cannons and Pylons); PvP against gp1 (DP173a+b against BP173a+b) -0.076 +- 0.101, +0.014 [-0.053, +0.057]. Its keys:
# 3 army keys, 2.0 assigns and 3.7 recalls a minute in PvT (the Protoss pros 4, 5.9 and 44.6; gp1 none)
# gp0.5dev: its model's units trained into a busy building's queue, two deep and paid for (gamequeue, as gt1dev's;
# docs/RACES.md step 2). PvZ against gz1dev, 96 paired games (QP176a+b against DZ173a+b): +0.023 +- 0.065, the macro
# gap nearer at 0-5 (-0.028 [-0.037, -0.002]) and 5-10 minutes (-0.024 [-0.044, -0.001]), no measurable difference
# later; at 10-20 minutes workers 46.7 (43.6 without, pros 46.4), army supply 44.2 (40.6, pros 53.3), Dragoons 6.7 (5.7,
# pros 9.2)
# gp0.6dev: builtcount, as gt1dev's and gz1dev's (its decisions so far as the replays count them: the same through 9
# minutes of the input check's game, every building it decided started)
# gp0.7dev: every build's fix of 2026-10-31 (as gt0.25dev's: decisions that ended without their command taken back)
# gp0.8dev: Reavers and Carriers kept full (as gp0.6's)
# gp0.9dev: Archons merged as the pros merge them (archons: its macro model with the merges among its decisions, two
# Templar merged and held). Judged on fidelity (AGENTS.md): PvZ against gz1dev (AR182a), Archons at 12, 16 and 20 minutes
# 0.2, 0.6, 1.3 a game, in 13%, 35% and 55% of games (the pros 0.1, 0.4, 1.0; 11%, 24%, 44%; none before), 279 of 303
# merges formed; won 10 lost 0 of 48 (BZ179a, gp0.7dev: 9 and 3)
# gp0.10dev: the Protoss pros' key layout (gary/agent/grouping.py LAYOUTS: army on 1-4, production on 5-8, a Nexus on 9;
# it was the army on 1-3, Nexuses on 4-5, production on 6-9)
# gp0.11dev: Psionic Storms when and where the pros cast them (storm: fight.py CastRule, gary/policy/cast.py; #4).
# Judged on fidelity: PvZ against gz1dev (ST186a), storms in 88% of games, 3.9 by 15:00 and 7.3 by 20:00 (the pros 84%,
# 5.9, 10.9; its High Templar 3.3 and 4.2 at 16 and 20 minutes, the pros' 4.1 and 6.9), the spot's enemy supply 4.7
# (6.1); PvT against gt1dev (SV187a) 73%, 0.7 and 3.2 (46%, 1.2, 3.5). Paired, no measurable difference: PvZ against
# ZB184a -0.026 +- 0.066, PvT against KP183a -0.005 +- 0.037
# gp0.12dev: Pylons placed where they power new room (protoss_executor.py spot, a fix of the hands): Gateways dropped
# for no spot 914 to 221 in 48 PvZ games (PY188a against ST186a), 692 to 147 in PvT (PT188a against SV187a); Gateways at
# 20:00 PvZ 7.5 (6.3, the pros 9.1), PvT 8.7 (6.7, 11.6); supply at 20:00 PvZ 183 (209, 182); won 11 lost 1 (5 and 1),
# PvT 4 and 9 (2 and 11); paired +0.005 +- 0.110 and +0.005 +- 0.116
# gp0.13dev: the fix of 2026-11-02 (as gt0.26dev's): a building placed that never started taken out of its decisions so far
# gp0.14dev: a building decided and not started yet among its own units (pendown, as gt0.27dev's)
# gp0.15dev: its buildings placed where the pros place them (place: each one's base and side drawn from the pros' PvZ
# table, gary/protoss.py PLACE, eval/placement.py), the forge-first wall at the natural and cannons at every base. Judged
# on fidelity, 16 PvZ games against PD190a's same seeds (PL197a): before 5:00 at the natural Forges 79%, cannons 90% (the
# pros 85%, 92%; none before); cannons at 8-12 minutes main/natural 41/57% (96/4, the pros 27/48 and 25 at newer bases);
# Probes lost to raids at 3-8 minutes 3.6 a game (9.9, the pros 0.9); Probes at 12:00 38.7 (35.8, the pros 46.2)
# gp0.16dev: place's hands (fixes, judged on fidelity, 16 PvZ games on the same seeds, PL201a against PL197a): a
# mineral-side spot on the mineral side as eval/placement.py tells it and as near the workers' lanes as the pros build
# there (gary/protoss.py PLACE_LANE), and each game keeping the table's shares (a window's first by dice, each next where
# its count falls furthest below its share): cannons by the mineral line 38% at 5-12 minutes (10%, the pros 36%), every
# Mutalisk raid's main with one; Probes lost to raids at 3-8 minutes 0.75 a game (3.6, the pros 0.9), to Mutalisk raids
# 0.38 each (4.6, the pros 1.3); Probes at 12:00 45.9 (38.7, the pros 46.2)
# gp0.17dev: gt0.28dev's fix
# gp0.18dev: place's draw fixed and the pros' tables for every matchup (judged on fidelity, 16 games a matchup on the
# same seeds, rounds PL/PT/PP210a): one draw a decision (drawn anew every tick while the macro saved, a build at
# another base set out earlier and the natural won the race: PvT's Cybernetics Core, 6% at the natural, there in 38%
# of games), the dice seeded per map and start (by the seed alone every map drew the same: a 16-game round two
# openings), each building's first and second of the game by the pros' own shares for its build style
# (PLACE_FIRST_STYLE: PvZ's first Pylon at the natural 100%, the pros 92%; its window's share 47%), PvT and PvP tables
# (their opening tech in the main 94-100%, the pros 94-99%), a full main or a warping Pylon calling the next Pylon
# there, every table from 240 pro games. Probes lost to raids at 3-8 minutes in PvZ 4.9 a game, 1.7 with the firsts
# off on the same draws (PL211a): single games of 13-32 (an undefended main), the table blind to Mutalisks (#65) and
# the macro's gateway-first openings without units; kept on (AGENTS.md, fidelity before wins)
# gp0.19dev: the gateway-first opening's hands (16 PvZ games on the same seeds, PL212a and PL213a against PL210a): the
# natural's Nexus site kept out of a Pylon's room as the spot search keeps it (the natural's first Pylon powered
# mostly that site, the Gateway found no spot: placed at 2:26, the pros' 1:13), and a decision waiting for a Pylon
# warping in kept 60 s (dropped at 30 s, 2 s before the power). Gateway-first's Gateway at 1:33-1:35, its first Zealot
# at 2:28-2:40 (3:27, the pros 1:54); Probes lost to raids at 3-8 minutes 1.3 and 4.2 a game in two rounds of nearly
# the same code (4.9): 16 games don't measure them
# gp0.20dev: the Terran's pull and reinforce (fightrules), stop-gaps no learned layer has an output for (AGENTS.md),
# judged on the pull's own measure: Probes lost to raids at 3-8 minutes in 48 PvZ games paired on map and seed (PL215a
# against PL214a) 2.31 a game (3.48, the pros 0.90), -1.17 [-2.31, -0.15]; games with 10 or more lost 8% (17%, the
# pros 2%); Probes pulled in 40% of Zergling raids (14%, the pros 59%), 8.0 at a time (the pros 5.5); Probes at 12:00
# 48.1 (43.2, the pros 46.2). Off since 2026-10-31 on a score with no difference
# gp0.21dev: place's base and side by the learned placement model in place of the pros' table (#65: the stop-gap gone),
# judged on the table's measures, 48 PvZ games paired on map and seed (PL216a against PL215a): cannons by the minerals
# at 7-9 minutes with a Spire or Mutalisks seen 0.51 (0.35, the pros 0.54), without 0.21 (0.31, the pros 0.24), at
# 9-12 minutes with 0.39 (0.30, the pros 0.46); Mutalisk raids at 3-8 minutes with no cannon by the Nexus 32% (50%, the
# pros 6%); Probes lost to raids at 3-8 minutes 1.90 a game (2.31, the pros 0.90), -0.42 [-1.88, +1.02]; the shares by
# base and side per window as near the pros' (0.123 off them, 0.113), the first cannon in the main 23% (10%, the pros
# 5%); won 5 (8), ahead at 20:00 in 25 (19)
# gp0.22dev: place's hands and inputs (fixes, judged on their checks, 48 PvZ games to 12 minutes on the same seeds): a
# building drawn for a base with no Pylon gets one there first and waits for it (spot()'s fallback stood it at another
# base), a Pylon within 16 tiles of a base at it (12: the natural's wall Pylon wasn't, and a Forge called one every
# 12 s, round PL217a); one die a decision read against the odds of the moment until its builder sets out, as the
# dataset reads the pros' state as each building appears (drawn once when first asked, before the natural's Nexus had
# started: the inputs test's worst minute off 2.26 to 0.42, 13 s to 8 s from the read to the building). The first
# cannon in the main 10% of games (PL219a; 23% in PL216a and in PL218a with the Pylon alone, the pros 5%), cannons
# before 5:00 at the natural 90% (the pros 90%); Probes lost to raids at 3-8 minutes 2.77 a game (1.92 in PL218a),
# +0.85 [-0.02, +1.81], from five games of 12-22 (Mutalisks at mains whose cannons stood away from the Nexus,
# Zerglings at bases with none): to be looked into
MANIFESTS["gp1dev"] = {**manifest_of("gp1+unscripted+grouping+gamequeue+builtcount+archons+storm+pendown+place"
                                     "+fightrules"),
                       "version": "gp0.22dev"}


def _against(m: dict, vs: dict) -> dict:
    """A manifest with its overrides for the enemy's race (its "vs" section): a layer's dict merged key by key, the
    rest replaced."""
    out = copy.deepcopy(m)
    for k, v in vs.items():
        out[k] = {**(out.get(k) or {}), **v} if isinstance(v, dict) and isinstance(out.get(k), dict) else copy.deepcopy(v)
    return out


def manifest_name(name: str) -> str:
    """For argparse (type=): a manifest name, with options, that exists."""
    base, *options = name.split("+")
    if base not in MANIFESTS or base == "drill" or any(o not in OPTIONS for o in options):
        raise ValueError(name)
    return name


def build_gary(hi, mapinfo, manifest: str | dict, style: int | str | None = None, verbose: bool = True,
               fight_path: str | Path | None = None, load=load_model, seed: int = 0,
               flip: tuple[bool, bool] | None = None, interruptions: bool = True, fight_model=None) -> Gary:
    """A Gary from a manifest (a name in MANIFESTS, or a dict like them). fight_path (or an already
    loaded fight_model) replaces the manifest's fight model; load(kind, path) loads models (callers
    that cache pass their own); seed seeds the fight layer's sampling; flip and interruptions are
    for drills (no map)."""
    import torch
    torch.set_num_threads(1)       # its models are small: games run side by side (14 at once: 2.7x faster)
    m = manifest_of(manifest)
    g = Gary(hi, mapinfo, m["version"], verbose, m.get("race", "T"))
    g.game_seed = seed                            # (the rules that draw: fight.py CastRule)
    if style is not None:                         # (by id or by name, for this race in this matchup: gary/styles.py)
        from gary.styles import resolve
        style = resolve(g.matchup, g.race.letter, style)
    chosen = style is not None                    # (chosen by the caller: the records say so)
    if g.enemy is not None and g.enemy.race in m.get("vs", {}):
        m = _against(m, m["vs"][g.enemy.race])
    g.army_types = set(g.race.army) | set(g.race.in_mode)
    g.production_types = g.race.production if mapinfo is not None else tuple(g.race.town_halls)
    if flip is not None:
        g.flip = flip
    models: dict[str, str] = {}
    g.motor = DirectMotor(g)
    if m.get("grouping"):                     # (gary/agent/grouping.py: the control-group provider; none: no keys)
        from gary.agent.grouping import LAYOUTS, PROVIDERS as GROUPINGS
        g.motor.grouping = GROUPINGS[m["grouping"]](g)
        layout = LAYOUTS.get(g.race.letter, {})
        if m.get("grouping_layout", True) is False:      # (the army on 1-3, the buildings' keys as they were)
            from gary.agent.grouping import ARMY_KEYS
            g.motor.grouping.keys = list(ARMY_KEYS)
        elif "hall" in layout:                # (the buildings' keys moved for the army's)
            g.key_pools = (layout["hall"], layout["production"])
    g.leases.enforced = m.get("leases") == "enforced"
    if m["macro"] is not None or m["army"] is not None:
        g.executor = {"T": TerranExecutor, "Z": ZergExecutor, "P": ProtossExecutor}[g.race.letter](g)
        g.rally_plan = m.get("rally")
        g.home_scvs = m.get("home_scvs", False)
        g.builder_back = m.get("builder_back", False)
        g.balance = m.get("balance", False)
        if m.get("simcity"):
            from gary.agent.simcity import SimCity
            g.simcity = SimCity(g, m.get("simcity_door", 32))
    from gary.agent.zerg_posture import AlarmDefense, NaturalColonies, ZergPosture
    g.posture = {"normal": NormalPosture, "zerg": lambda g: ZergPosture(g, m.get("colonies", False), m.get("alarm_drones", True)),
                 "early_pool/v1": EarlyPoolPosture,
                 "early_pool/v2": EarlyPoolPostureV2, "early_pool/v3": EarlyPoolPostureV3,
                 "early_pool/v4": EarlyPoolPostureV4, "early_pool/v5": EarlyPoolPostureV5,
                 "early_pool/v6": EarlyPoolPostureV6,
                 "plan/v1": lambda g: _learned_posture(g, m, models)}[m["posture"]](g)
    if m.get("defend_early") and hasattr(g.posture, "force_at"):
        g.posture.force_at = m["defend_early"]          # (option defend_early: the rush defense from then)
    if m["macro"] is not None:
        path = model_path(m["macro"]["model"], g.matchup, g.race.letter)
        macro = load("macro", str(path))
        models["macro"] = getattr(macro, "path", "?")
        builds = {k: c(g) for k, c in (("one_base_defense", OneBaseDefense), ("ling_flood_defense", LingFloodDefense),
                                        ("alarm", AlarmDefense), ("colonies", NaturalColonies))
                  if k in m["macro"].get("builds", [])}
        if style is None and m["macro"].get("selector") and mapinfo is not None:
            # the strategy selector (gary/agent/selector.py): the build style for this map, from games counted
            import random
            from gary.agent.selector import StrategySelector, map_key
            explore = m["macro"]["selector"] == "explore"
            style = StrategySelector().choose(map_key(mapinfo), explore, random.Random(seed * 7919 + int(map_key(mapinfo), 16) % 1000))
            g.selected_style = style
        if style is None and m["macro"].get("style") == "roll":
            style = rolled_style(macro, g.matchup, g.race.letter, seed)
            g.selected_style = style
        if style is not None:                     # (the style it was told, in the game's records: eval/style_adherence.py)
            from gary.decision_log import LOG
            LOG.decision(getattr(hi, "side", None) or g.race.letter, "style", 0, int(style),
                         by="chosen" if chosen else "selector" if m["macro"].get("selector")
                         else "roll" if m["macro"].get("style") == "roll" else "manifest")
        g.macro = LearnedMacro(g, macro, style, builds, m["macro"].get("natural_bunker", False),
                               m["macro"].get("rax_by", 90 * 24),
                               m["macro"].get("decoder", "favorite"), seed, m["macro"].get("temperature", 1.0),
                               m["macro"].get("park", False), m["macro"].get("pace", False), m["macro"].get("tech_min_p"),
                               m["macro"].get("hatch_mass"), m["macro"].get("wait_min_p"))
        g.macro.expand_mass = m["macro"].get("expand_mass")
        g.macro.caps_on = m["macro"].get("caps", True)
        g.macro.bank_escape = m["macro"].get("bank_escape", True)
        g.macro.queue_depth = m["macro"].get("queue_depth", 1)
        g.macro.rethink = m["macro"].get("rethink", False)
        g.macro.nosave = m["macro"].get("nosave", False)
        g.macro.dice_t = m["macro"].get("dice_t", 1.0)
        if hasattr(g.executor, "scv_saturation"):
            g.executor.scv_saturation = m.get("scv_saturation", True)
        g.executor.train_depth = m.get("train_depth", 1)
        g.executor.wide_spot = m.get("wide_spot", False)
        g.executor.place_on = m.get("place", False)
        if g.executor.place_on:
            from gary.policy.placement import Losses, PlacementModel
            g.executor.place_model = PlacementModel.find(g.matchup, g.race.letter)
            g.executor.place_look = Losses(g.race) if g.executor.place_model is not None else None
        if hasattr(g.executor, "addon_room"):
            g.executor.addon_room = m.get("addon_room", False)
        g.macro.odds_mass = m["macro"].get("odds_mass")
        g.macro.supply_ahead = m["macro"].get("supply_ahead", False)
        g.macro.hold = m["macro"].get("hold", False)
        g.macro.gas_waits = m["macro"].get("gas_waits", False)
        g.parked_max = m["macro"].get("parked_max", 1)
        if hasattr(g.macro, "tracker"):
            g.macro.tracker.look_every = 24 if m["macro"].get("look_seen") else 0
            g.macro.tracker.reconcile = bool(m["macro"].get("built_count"))
            g.macro.tracker.pending_own = bool(m["macro"].get("pending_own"))
            g.macro.count_first = bool(m["macro"].get("unit_count"))
            g.macro.eggs_seen = bool(m["macro"].get("eggs_seen")) and g.race.production_in_sight
        if m["macro"].get("history") == "pro":
            # STOP-GAP (AGENTS.md): Gary-Z's: the pros' decision history in the model's inputs, fading to its own over
            # HISTORY_FADE minutes, so its own drone-heavy past doesn't feed back on itself
            from gary.policy.macro import pro_history
            g.macro.tracker.history = pro_history(g.race.letter, style, g.matchup, m["macro"].get("history_styles"))
            g.macro.tracker.history_weight = 1.0
            g.macro.tracker.history_until = HISTORY_FADE
            spec = g.macro.model.spec
            if m["macro"].get("own_supply"):
                g.macro.tracker.own_keys = [k for k, (act, uid) in enumerate(spec.decisions) if uid == g.race.supply_provider]
        if m["macro"].get("answers"):
            from gary.agent.answers import Answers
            g.macro.answers = Answers(g, **m["macro"].get("answer_options", {}))
    if m["army"] is not None:
        if m["army"]["provider"] == "waves":
            g.army = WaveArmy(g)
        else:
            pinned = os.environ.get("GARY_TCOMMIT_MODEL" if m["army"].get("commit") else "GARY_TARMY_MODEL")                 if m["army"].get("draw") and g.race.letter == "T" else None                      # (the league loop's; the Terran's)
            army = load("army", pinned or str(model_path(m["army"]["model"], g.matchup, g.race.letter)))
            models["army"] = getattr(army, "path", "?")
            belief = None
            if m["army"].get("belief") or m["army"].get("hunt_belief"):
                from gary.policy.belief import BeliefModel
                belief = BeliefModel.load(model_path(m["army"].get("belief") or "belief/latest", g.matchup, g.race.letter))
                models["belief"] = belief.path
            g.army = LearnedArmy(g, army, PullRule(g) if m["army"].get("pull") else None, hunt=m["army"].get("hunt", False),
                                 scan=m["army"].get("scan", False), belief=belief,
                                 belief_total=m["army"].get("belief_total", False), watch=m["army"].get("watch", False),
                                 home_guard=m["army"].get("home_guard", False),
                                 belief_hold=bool(m["army"].get("belief")), hunt_belief=m["army"].get("hunt_belief", False),
                                 hold_moves=m["army"].get("hold_moves", True), hold_margin=m["army"].get("hold_margin"),
                                 draw=m["army"].get("draw", False), engage=_engage_model(g, m),
                                 commit=m["army"].get("commit", False), commit_act=m["army"].get("commit_act"),
                                 scout=m["army"].get("scout", True), types=m["army"].get("types"),
                                 rules=m["army"].get("rules", ()))
            g.army.commit_floor = m["army"].get("commit_floor")
            g.army.hunt_ahead = m["army"].get("hunt_ahead")
            g.army.hunt_split = m["army"].get("hunt_split", False)
            g.army.static_odds = m["army"].get("static_odds")
            g.army.static_beta = m["army"].get("static_beta")
            g.army.hunt_advice = m["army"].get("hunt_advice", False)
            g.army.engage_bias = m["army"].get("engage_bias", 0.0)
            g.army.hold_target = m["army"].get("hold_target", False)
            g.army.unit_commits_on = m["army"].get("unit_commits", False)
            g.army.gather_on = m["army"].get("gather", False)
            if m["army"].get("army_seen"):
                g.army.tracker.extra_units = g.army.unseen_own
    rule = lambda r: RULES[r](g, **m["fight"].get("rule_options", {}).get(r, {}))
    if m["fight"] is not None and m["fight"]["provider"] == "zerg":
        from gary.agent.zerg_fight import ZergFight
        g.fight = ZergFight(g, m["fight"].get("roles", True), m["fight"].get("lurkers", True), seed,
                            _by_matchup(m["fight"].get("roles_data", "response_Z.npz"), g.matchup),
                            [rule(r) for r in m["fight"].get("before", [])], [rule(r) for r in m["fight"].get("in_fight", [])])
        models["fight"] = g.fight.model_path or "none"
    elif m["fight"] is not None:
        f = m["fight"]
        if f["provider"] == "roles" and f.get("model") is None:
            fight = None
            models["fight"] = "roles/rules_v1"   # (the chat says so: as many lines as with a model)
        elif f["provider"] in ("roles", "role_override", "role_ahead"):
            from gary.policy.roles import RoleModel
            if f.get("roles_model") and fight_path is None and fight_model is None:
                fight_path = f["roles_model"]                # (a pinned checkpoint: an RL run's, say)
            if f.get("roles_data") and fight_path is None and fight_model is None:
                from gary.policy.roles import latest_trained_on
                fight_path = latest_trained_on(_by_matchup(f["roles_data"], g.matchup))
                if fight_path is None:
                    raise FileNotFoundError(f"no role model trained on {f['roles_data']}")
            fight = fight_model or RoleModel.load(fight_path or model_path(f["model"], g.matchup, g.race.letter))
            models["fight"] = fight.path
        else:
            fight = fight_model or load("fight", str(fight_path or model_path(f["model"], g.matchup, g.race.letter)))
            models["fight"] = getattr(fight, "path", "?")
        g.fight = FightLayer(g, fight, f["provider"], [rule(r) for r in f.get("before", [])],
                             [rule(r) for r in f.get("in_fight", [])], f.get("guard_rail", False),
                             f.get("workers", True), seed, f.get("ctrl_click", False),
                             f.get("watch_tiles", 0) * 32, f.get("roles", {}), f.get("attend", False))
    if m["fight"] is not None and m["fight"].get("data_extras") and getattr(g.fight, "roles", None) is not None:
        g.fight.roles.own_extra = False
    if m["fight"] is not None and m["fight"].get("full_hp") and getattr(g.fight, "roles", None) is not None:
        g.fight.roles.full_hp = True
    if m["arbiter"] == "drill/v1":
        g.arbiter = DrillArbiter(g, seed, interruptions)
    else:
        g.arbiter = FixedPriority(g, suspend_builds=m["arbiter"] == "fixed_priority/v2", rotate=m.get("rotate", False))
        g.announce = announcement(g.version, style, models)
    return g
