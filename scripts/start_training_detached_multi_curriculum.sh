#!/usr/bin/env bash
set -eo pipefail

PROJECT_ROOT="$(cd "$(dirname "${BASH_SOURCE[0]}")/.." && pwd)"
TD3_DIR="$PROJECT_ROOT/TD3"
LOG_DIR="$PROJECT_ROOT/logs"
ROS_WORKSPACE_ROOT="${DRL_MULTI_ROS_WORKSPACE_ROOT:-$PROJECT_ROOT}"
STAGE="${1:-stage1_single}"
ROS_PORT="${DRL_MULTI_ROS_PORT:-11367}"
GAZEBO_PORT="${DRL_MULTI_GAZEBO_PORT:-11407}"

port_in_use() {
  local port="$1"
  ss -ltn "( sport = :$port )" 2>/dev/null | tail -n +2 | grep -q .
}

case "$STAGE" in
  stage1_single)
    NUM_AGENTS="${DRL_MULTI_NUM_AGENTS:-1}"
    MODEL_NAME="${DRL_MULTI_TRAIN_FILE_NAME:-TD3_velodyne_multi_v4_curriculum_stage1_single}"
    LOAD_MODEL_NAME="${DRL_MULTI_LOAD_MODEL_NAME:-TD3_velodyne_multi_v4}"
    CASES_PATH="$PROJECT_ROOT/experiments/02_课程学习/cases/stage1_single_local_cases.json"
    VERSION="multi-agent-curriculum-stage1-single-local-v1"
    DEFAULT_MAX_EPOCHS=8
    DEFAULT_EVAL_EPISODES=24
    DEFAULT_EXPL_NOISE=0.45
    DEFAULT_EXPL_MIN=0.08
    DEFAULT_ACTOR_LR=0.0005
    DEFAULT_CRITIC_LR=0.0005
    ;;
  stage1b_single)
    NUM_AGENTS="${DRL_MULTI_NUM_AGENTS:-1}"
    MODEL_NAME="${DRL_MULTI_TRAIN_FILE_NAME:-TD3_velodyne_multi_v4_curriculum_stage1b_single}"
    LOAD_MODEL_NAME="${DRL_MULTI_LOAD_MODEL_NAME:-TD3_velodyne_multi_v4_curriculum_stage1_single_best}"
    CASES_PATH="$PROJECT_ROOT/experiments/02_课程学习/cases/stage1b_single_near_goal_sidewall_cases.json"
    VERSION="multi-agent-curriculum-stage1b-near-goal-sidewall-v1"
    DEFAULT_MAX_EPOCHS=8
    DEFAULT_EVAL_EPISODES=32
    DEFAULT_EXPL_NOISE=0.28
    DEFAULT_EXPL_MIN=0.06
    DEFAULT_ACTOR_LR=0.0002
    DEFAULT_CRITIC_LR=0.0002
    ;;
  stage1e_single_rescue)
    NUM_AGENTS="${DRL_MULTI_NUM_AGENTS:-1}"
    MODEL_NAME="${DRL_MULTI_TRAIN_FILE_NAME:-TD3_velodyne_multi_v4_curriculum_stage1e_single_rescue_from_stage1_single}"
    LOAD_MODEL_NAME="${DRL_MULTI_LOAD_MODEL_NAME:-TD3_velodyne_multi_v4_curriculum_stage1_single_best}"
    CASES_PATH="$PROJECT_ROOT/experiments/02_课程学习/cases/stage1e_single_rescue_cases.json"
    VERSION="multi-agent-curriculum-stage1e-single-rescue-v1"
    DEFAULT_MAX_EPOCHS=10
    DEFAULT_EVAL_EPISODES=48
    DEFAULT_EXPL_NOISE=0.34
    DEFAULT_EXPL_MIN=0.06
    DEFAULT_ACTOR_LR=0.0003
    DEFAULT_CRITIC_LR=0.0003
    ;;
  stage1f_wall_parallel_rescue)
    NUM_AGENTS="${DRL_MULTI_NUM_AGENTS:-1}"
    MODEL_NAME="${DRL_MULTI_TRAIN_FILE_NAME:-TD3_velodyne_multi_v4_curriculum_stage1f_wall_parallel_rescue_from_stage1e}"
    LOAD_MODEL_NAME="${DRL_MULTI_LOAD_MODEL_NAME:-TD3_velodyne_multi_v4_curriculum_stage1e_single_rescue_from_stage1_single_best}"
    CASES_PATH="$PROJECT_ROOT/experiments/02_课程学习/cases/stage1f_wall_parallel_rescue_cases.json"
    VERSION="multi-agent-curriculum-stage1f-wall-parallel-rescue-v1"
    DEFAULT_MAX_EPOCHS=8
    DEFAULT_EVAL_EPISODES=48
    DEFAULT_EXPL_NOISE=0.14
    DEFAULT_EXPL_MIN=0.035
    DEFAULT_ACTOR_LR=0.00012
    DEFAULT_CRITIC_LR=0.00012
    ;;
  stage1g_collision_guard)
    NUM_AGENTS="${DRL_MULTI_NUM_AGENTS:-1}"
    MODEL_NAME="${DRL_MULTI_TRAIN_FILE_NAME:-TD3_velodyne_multi_v4_curriculum_stage1g_collision_guard_from_stage1f}"
    LOAD_MODEL_NAME="${DRL_MULTI_LOAD_MODEL_NAME:-TD3_velodyne_multi_v4_curriculum_stage1f_wall_parallel_rescue_from_stage1e_best}"
    CASES_PATH="$PROJECT_ROOT/experiments/02_课程学习/cases/stage1g_collision_guard_cases.json"
    VERSION="multi-agent-curriculum-stage1g-collision-guard-v1"
    DEFAULT_MAX_EPOCHS=6
    DEFAULT_EVAL_EPISODES=48
    DEFAULT_EXPL_NOISE=0.08
    DEFAULT_EXPL_MIN=0.025
    DEFAULT_ACTOR_LR=0.00006
    DEFAULT_CRITIC_LR=0.00006
    ;;
  stage1h_separated_reverse_guard)
    NUM_AGENTS="${DRL_MULTI_NUM_AGENTS:-1}"
    MODEL_NAME="${DRL_MULTI_TRAIN_FILE_NAME:-TD3_velodyne_multi_v4_curriculum_stage1h_separated_reverse_guard_from_stage1g}"
    LOAD_MODEL_NAME="${DRL_MULTI_LOAD_MODEL_NAME:-TD3_velodyne_multi_v4_curriculum_stage1g_collision_guard_from_stage1f_best}"
    CASES_PATH="$PROJECT_ROOT/experiments/02_课程学习/cases/stage1h_separated_reverse_guard_cases.json"
    VERSION="multi-agent-curriculum-stage1h-separated-reverse-guard-v1"
    DEFAULT_MAX_EPOCHS=4
    DEFAULT_EVAL_EPISODES=48
    DEFAULT_EXPL_NOISE=0.045
    DEFAULT_EXPL_MIN=0.02
    DEFAULT_ACTOR_LR=0.00004
    DEFAULT_CRITIC_LR=0.00004
    ;;
  stage1i_yaw_reverse_collision_guard)
    NUM_AGENTS="${DRL_MULTI_NUM_AGENTS:-1}"
    MODEL_NAME="${DRL_MULTI_TRAIN_FILE_NAME:-TD3_velodyne_multi_v4_curriculum_stage1i_yaw_reverse_collision_guard_from_stage1g}"
    LOAD_MODEL_NAME="${DRL_MULTI_LOAD_MODEL_NAME:-TD3_velodyne_multi_v4_curriculum_stage1g_collision_guard_from_stage1f_best}"
    CASES_PATH="$PROJECT_ROOT/experiments/02_课程学习/cases/stage1i_yaw_reverse_collision_cases.json"
    VERSION="multi-agent-curriculum-stage1i-yaw-reverse-collision-guard-v1"
    DEFAULT_MAX_EPOCHS=3
    DEFAULT_EVAL_EPISODES=72
    DEFAULT_EXPL_NOISE=0.025
    DEFAULT_EXPL_MIN=0.012
    DEFAULT_ACTOR_LR=0.00002
    DEFAULT_CRITIC_LR=0.00002
    ;;
  stage2a_manual_dense_crossing)
    NUM_AGENTS="${DRL_MULTI_NUM_AGENTS:-3}"
    MODEL_NAME="${DRL_MULTI_TRAIN_FILE_NAME:-TD3_velodyne_multi_v4_curriculum_stage2a_manual_dense_crossing_from_stage1g}"
    LOAD_MODEL_NAME="${DRL_MULTI_LOAD_MODEL_NAME:-TD3_velodyne_multi_v4_curriculum_stage1g_collision_guard_from_stage1f_best}"
    CASES_PATH="$PROJECT_ROOT/experiments/02_课程学习/cases/stage2a_manual_dense_crossing_cases.json"
    VERSION="multi-agent-curriculum-stage2a-manual-dense-crossing-v1"
    DEFAULT_MAX_EPOCHS=8
    DEFAULT_EVAL_EPISODES=48
    DEFAULT_EXPL_NOISE=0.055
    DEFAULT_EXPL_MIN=0.018
    DEFAULT_ACTOR_LR=0.00005
    DEFAULT_CRITIC_LR=0.00005
    ;;
  stage2_pre_pairwise_warmup)
    NUM_AGENTS="${DRL_MULTI_NUM_AGENTS:-2}"
    MODEL_NAME="${DRL_MULTI_TRAIN_FILE_NAME:-TD3_velodyne_multi_v4_curriculum_stage2_pre_pairwise_warmup_from_stage1g}"
    LOAD_MODEL_NAME="${DRL_MULTI_LOAD_MODEL_NAME:-TD3_velodyne_multi_v4_curriculum_stage1g_collision_guard_from_stage1f_best}"
    CASES_PATH="$PROJECT_ROOT/experiments/02_课程学习/cases/stage2_pre_pairwise_warmup_cases.json"
    VERSION="multi-agent-curriculum-stage2-pre-pairwise-warmup-v1"
    DEFAULT_MAX_EPOCHS=6
    DEFAULT_EVAL_EPISODES=48
    DEFAULT_EXPL_NOISE=0.045
    DEFAULT_EXPL_MIN=0.015
    DEFAULT_ACTOR_LR=0.00004
    DEFAULT_CRITIC_LR=0.00004
    ;;
  stage2_main_pairwise_repair)
    NUM_AGENTS="${DRL_MULTI_NUM_AGENTS:-2}"
    MODEL_NAME="${DRL_MULTI_TRAIN_FILE_NAME:-TD3_velodyne_multi_v4_curriculum_stage2_main_pairwise_repair_from_stage2_pre_best}"
    LOAD_MODEL_NAME="${DRL_MULTI_LOAD_MODEL_NAME:-TD3_velodyne_multi_v4_curriculum_stage2_pre_pairwise_warmup_from_stage1g_best}"
    CASES_PATH="$PROJECT_ROOT/experiments/02_课程学习/cases/stage2_main_pairwise_repair_cases.json"
    VERSION="multi-agent-curriculum-stage2-main-pairwise-repair-v1"
    DEFAULT_MAX_EPOCHS=8
    DEFAULT_EVAL_EPISODES=64
    DEFAULT_EXPL_NOISE=0.025
    DEFAULT_EXPL_MIN=0.008
    DEFAULT_ACTOR_LR=0.00002
    DEFAULT_CRITIC_LR=0.00003
    ;;
  stage2b_three_light_dense)
    NUM_AGENTS="${DRL_MULTI_NUM_AGENTS:-3}"
    MODEL_NAME="${DRL_MULTI_TRAIN_FILE_NAME:-TD3_velodyne_multi_v4_curriculum_stage2b_three_light_dense_from_2d_gentle}"
    LOAD_MODEL_NAME="${DRL_MULTI_LOAD_MODEL_NAME:-TD3_velodyne_multi_v4_curriculum_stage2_2d_local_critic_from_2a_gentle_best}"
    CASES_PATH="$PROJECT_ROOT/experiments/02_课程学习/cases/stage2b_three_light_dense_cases.json"
    VERSION="multi-agent-curriculum-stage2b-three-light-dense-v1"
    DEFAULT_MAX_EPOCHS=8
    DEFAULT_EVAL_EPISODES=48
    DEFAULT_EXPL_NOISE=0.06
    DEFAULT_EXPL_MIN=0.018
    DEFAULT_ACTOR_LR=0.000008
    DEFAULT_CRITIC_LR=0.00004
    ;;
  stage2b_three_transition)
    NUM_AGENTS="${DRL_MULTI_NUM_AGENTS:-3}"
    MODEL_NAME="${DRL_MULTI_TRAIN_FILE_NAME:-TD3_velodyne_multi_v4_curriculum_stage2b_three_transition_from_2d_gentle}"
    LOAD_MODEL_NAME="${DRL_MULTI_LOAD_MODEL_NAME:-TD3_velodyne_multi_v4_curriculum_stage2_2d_local_critic_from_2a_gentle_best}"
    CASES_PATH="$PROJECT_ROOT/experiments/02_课程学习/cases/stage2b_three_transition_cases.json"
    VERSION="multi-agent-curriculum-stage2b-three-transition-v1"
    DEFAULT_MAX_EPOCHS=8
    DEFAULT_EVAL_EPISODES=48
    DEFAULT_EXPL_NOISE=0.045
    DEFAULT_EXPL_MIN=0.014
    DEFAULT_ACTOR_LR=0.000006
    DEFAULT_CRITIC_LR=0.000035
    ;;
  stage2_dense)
    NUM_AGENTS="${DRL_MULTI_NUM_AGENTS:-5}"
    MODEL_NAME="${DRL_MULTI_TRAIN_FILE_NAME:-TD3_velodyne_multi_v4_curriculum_stage2_dense_5}"
    LOAD_MODEL_NAME="${DRL_MULTI_LOAD_MODEL_NAME:-TD3_velodyne_multi_v4_curriculum_stage1_single_best}"
    CASES_PATH="$PROJECT_ROOT/experiments/02_课程学习/cases/stage2_dense_multi_cases.json"
    VERSION="multi-agent-curriculum-stage2-dense-v1"
    DEFAULT_MAX_EPOCHS=8
    DEFAULT_EVAL_EPISODES=24
    DEFAULT_EXPL_NOISE=0.35
    DEFAULT_EXPL_MIN=0.08
    DEFAULT_ACTOR_LR=0.0003
    DEFAULT_CRITIC_LR=0.0003
    ;;
  stage2_dense_gentle)
    NUM_AGENTS="${DRL_MULTI_NUM_AGENTS:-5}"
    MODEL_NAME="${DRL_MULTI_TRAIN_FILE_NAME:-TD3_velodyne_multi_v4_curriculum_stage2_dense_gentle_from_5a}"
    LOAD_MODEL_NAME="${DRL_MULTI_LOAD_MODEL_NAME:-TD3_velodyne_multi_v4_curriculum_stage2_to_5a_shared_from_3d2_guarded_best}"
    CASES_PATH="$PROJECT_ROOT/experiments/02_课程学习/cases/stage2_dense_gentle_5_cases.json"
    VERSION="multi-agent-curriculum-stage2-dense-gentle-5-from-5a-v1"
    DEFAULT_MAX_EPOCHS=6
    DEFAULT_EVAL_EPISODES=40
    DEFAULT_EXPL_NOISE=0.035
    DEFAULT_EXPL_MIN=0.012
    DEFAULT_ACTOR_LR=0.000003
    DEFAULT_CRITIC_LR=0.000025
    ;;
  stage2_dense_bridge)
    NUM_AGENTS="${DRL_MULTI_NUM_AGENTS:-5}"
    MODEL_NAME="${DRL_MULTI_TRAIN_FILE_NAME:-TD3_velodyne_multi_v4_curriculum_stage2_dense_bridge_from_5a}"
    LOAD_MODEL_NAME="${DRL_MULTI_LOAD_MODEL_NAME:-TD3_velodyne_multi_v4_curriculum_stage2_to_5a_shared_from_3d2_guarded_best}"
    CASES_PATH="$PROJECT_ROOT/experiments/02_课程学习/cases/stage2_dense_bridge_5_cases.json"
    VERSION="multi-agent-curriculum-stage2-dense-bridge-5-from-5a-v1"
    DEFAULT_MAX_EPOCHS=4
    DEFAULT_EVAL_EPISODES=48
    DEFAULT_EXPL_NOISE=0.035
    DEFAULT_EXPL_MIN=0.012
    DEFAULT_ACTOR_LR=0.000003
    DEFAULT_CRITIC_LR=0.000025
    ;;
  stage2_pairwise_to_dense)
    NUM_AGENTS="${DRL_MULTI_NUM_AGENTS:-5}"
    MODEL_NAME="${DRL_MULTI_TRAIN_FILE_NAME:-TD3_velodyne_multi_v4_curriculum_stage2_pairwise_to_dense_from_5a}"
    LOAD_MODEL_NAME="${DRL_MULTI_LOAD_MODEL_NAME:-TD3_velodyne_multi_v4_curriculum_stage2_to_5a_shared_from_3d2_guarded_best}"
    CASES_PATH="$PROJECT_ROOT/experiments/02_课程学习/cases/stage2_pairwise_to_dense_5_cases.json"
    VERSION="multi-agent-curriculum-stage2-pairwise-to-dense-5-from-5a-v1"
    DEFAULT_MAX_EPOCHS=3
    DEFAULT_EVAL_EPISODES=48
    DEFAULT_EXPL_NOISE=0.022
    DEFAULT_EXPL_MIN=0.008
    DEFAULT_ACTOR_LR=0.000001
    DEFAULT_CRITIC_LR=0.00002
    DEFAULT_ACTOR_UPDATE_DELAY_STEPS=15000
    ;;
  stage3_asym_pair_5)
    NUM_AGENTS="${DRL_MULTI_NUM_AGENTS:-5}"
    MODEL_NAME="${DRL_MULTI_TRAIN_FILE_NAME:-TD3_velodyne_multi_v4_curriculum_stage3_asym_pair_5_from_5d}"
    LOAD_MODEL_NAME="${DRL_MULTI_LOAD_MODEL_NAME:-TD3_velodyne_multi_v4_curriculum_stage2_to_5d_geo_critic_from_5a_guarded_best}"
    CASES_PATH="$PROJECT_ROOT/experiments/02_课程学习/cases/stage3_asym_pair_5_cases.json"
    VERSION="multi-agent-curriculum-stage3-asym-pair-5-from-5d-v1"
    DEFAULT_LOAD_ACTOR_ONLY=1
    DEFAULT_MAX_EPOCHS=3
    DEFAULT_EVAL_EPISODES=48
    DEFAULT_EXPL_NOISE=0.018
    DEFAULT_EXPL_MIN=0.006
    DEFAULT_ACTOR_LR=0.000001
    DEFAULT_CRITIC_LR=0.00002
    DEFAULT_ACTOR_UPDATE_DELAY_STEPS=18000
    ;;
  stage3_asym_three_5)
    NUM_AGENTS="${DRL_MULTI_NUM_AGENTS:-5}"
    MODEL_NAME="${DRL_MULTI_TRAIN_FILE_NAME:-TD3_velodyne_multi_v4_curriculum_stage3_asym_three_5_from_pair_5d}"
    LOAD_MODEL_NAME="${DRL_MULTI_LOAD_MODEL_NAME:-TD3_velodyne_multi_v4_curriculum_stage3_asym_pair_5_from_5d_best}"
    CASES_PATH="$PROJECT_ROOT/experiments/02_课程学习/cases/stage3_asym_three_5_cases.json"
    VERSION="multi-agent-curriculum-stage3-asym-three-5-from-pair-5d-v1"
    DEFAULT_LOAD_ACTOR_ONLY=0
    DEFAULT_MAX_EPOCHS=3
    DEFAULT_EVAL_EPISODES=48
    DEFAULT_EXPL_NOISE=0.015
    DEFAULT_EXPL_MIN=0.005
    DEFAULT_ACTOR_LR=0.0000008
    DEFAULT_CRITIC_LR=0.00002
    DEFAULT_ACTOR_UPDATE_DELAY_STEPS=4000
    ;;
  stage4_asym_dense_5_bridge)
    NUM_AGENTS="${DRL_MULTI_NUM_AGENTS:-5}"
    MODEL_NAME="${DRL_MULTI_TRAIN_FILE_NAME:-TD3_multi_dense5_bridge_from_5d}"
    LOAD_MODEL_NAME="${DRL_MULTI_LOAD_MODEL_NAME:-TD3_velodyne_multi_v4_curriculum_stage2_to_5d_geo_critic_from_5a_guarded_best}"
    CASES_PATH="$PROJECT_ROOT/experiments/02_课程学习/cases/stage4_asym_dense_5_bridge_cases.json"
    VERSION="dense5-bridge-from-5d-v1"
    DEFAULT_LOAD_ACTOR_ONLY=0
    DEFAULT_MAX_EPOCHS=20
    DEFAULT_EVAL_EPISODES=40
    DEFAULT_EXPL_NOISE=0.018
    DEFAULT_EXPL_MIN=0.006
    DEFAULT_ACTOR_LR=0.000001
    DEFAULT_CRITIC_LR=0.00004
    DEFAULT_ACTOR_UPDATE_DELAY_STEPS=6000
    ;;
  stage4_asym_dense_5_moderate)
    NUM_AGENTS="${DRL_MULTI_NUM_AGENTS:-5}"
    MODEL_NAME="${DRL_MULTI_TRAIN_FILE_NAME:-TD3_multi_dense5_moderate_from_5d}"
    LOAD_MODEL_NAME="${DRL_MULTI_LOAD_MODEL_NAME:-TD3_velodyne_multi_v4_curriculum_stage2_to_5d_geo_critic_from_5a_guarded_best}"
    CASES_PATH="$PROJECT_ROOT/experiments/02_课程学习/cases/stage4_asym_dense_5_moderate_cases.json"
    VERSION="dense5-moderate-from-5d-v1"
    DEFAULT_LOAD_ACTOR_ONLY=1
    DEFAULT_MAX_EPOCHS=8
    DEFAULT_EVAL_EPISODES=40
    DEFAULT_EXPL_NOISE=0.020
    DEFAULT_EXPL_MIN=0.008
    DEFAULT_ACTOR_LR=0.000001
    DEFAULT_CRITIC_LR=0.00004
    DEFAULT_ACTOR_UPDATE_DELAY_STEPS=4000
    ;;
  stage2_three_dense)
    NUM_AGENTS="${DRL_MULTI_NUM_AGENTS:-3}"
    MODEL_NAME="${DRL_MULTI_TRAIN_FILE_NAME:-TD3_velodyne_multi_v4_curriculum_stage2_three_dense_3}"
    LOAD_MODEL_NAME="${DRL_MULTI_LOAD_MODEL_NAME:-TD3_velodyne_multi_v4_curriculum_stage1_single_best}"
    CASES_PATH="$PROJECT_ROOT/experiments/02_课程学习/cases/stage2_three_dense_cases.json"
    VERSION="multi-agent-curriculum-stage2-three-dense-v1"
    DEFAULT_MAX_EPOCHS=8
    DEFAULT_EVAL_EPISODES=24
    DEFAULT_EXPL_NOISE=0.32
    DEFAULT_EXPL_MIN=0.08
    DEFAULT_ACTOR_LR=0.0003
    DEFAULT_CRITIC_LR=0.0003
    ;;
  *)
    echo "Unknown curriculum stage: $STAGE"
    echo "Available stages: stage1_single, stage1b_single, stage1e_single_rescue, stage1f_wall_parallel_rescue, stage1g_collision_guard, stage1h_separated_reverse_guard, stage1i_yaw_reverse_collision_guard, stage2_pre_pairwise_warmup, stage2_main_pairwise_repair, stage2a_manual_dense_crossing, stage2b_three_transition, stage2b_three_light_dense, stage2_three_dense, stage2_pairwise_to_dense, stage2_dense_bridge, stage2_dense_gentle, stage2_dense, stage3_asym_pair_5, stage3_asym_three_5, stage4_asym_dense_5_moderate, stage4_asym_dense_5_bridge"
    exit 1
    ;;
esac

LAUNCHFILE="multi_robot_scenario_curriculum_${STAGE}_${NUM_AGENTS}.launch"
LAUNCH_PATH="$TD3_DIR/assets/$LAUNCHFILE"
PID_FILE="$PROJECT_ROOT/.train_multi_curriculum_${STAGE}_detached.pid"
CURRICULUM_SAMPLING="${DRL_MULTI_CURRICULUM_SAMPLING:-cycle}"
EVAL_EPISODES="${DRL_MULTI_EVAL_EPISODES:-$DEFAULT_EVAL_EPISODES}"
MAX_EPOCHS="${DRL_MULTI_MAX_EPOCHS:-$DEFAULT_MAX_EPOCHS}"
EXPL_NOISE="${DRL_MULTI_EXPL_NOISE:-$DEFAULT_EXPL_NOISE}"
EXPL_MIN="${DRL_MULTI_EXPL_MIN:-$DEFAULT_EXPL_MIN}"
ACTOR_LR="${DRL_MULTI_ACTOR_LR:-$DEFAULT_ACTOR_LR}"
CRITIC_LR="${DRL_MULTI_CRITIC_LR:-$DEFAULT_CRITIC_LR}"
if [[ "$STAGE" == "stage1g_collision_guard" || "$STAGE" == "stage1h_separated_reverse_guard" || "$STAGE" == "stage1i_yaw_reverse_collision_guard" ]]; then
  WALL_CLEARANCE_REWARD="${DRL_MULTI_USE_WALL_CLEARANCE_REWARD:-1}"
else
  WALL_CLEARANCE_REWARD="${DRL_MULTI_USE_WALL_CLEARANCE_REWARD:-0}"
fi
if [[ "$STAGE" == "stage1i_yaw_reverse_collision_guard" ]]; then
  DEFAULT_WALL_CLEARANCE_SAFE_DISTANCE=0.62
  DEFAULT_WALL_CLEARANCE_PENALTY=1.0
  DEFAULT_WALL_CLEARANCE_SPEED_WEIGHT=1.15
  DEFAULT_WALL_CLEARANCE_TURN_WEIGHT=0.12
elif [[ "$STAGE" == "stage1g_collision_guard" || "$STAGE" == "stage1h_separated_reverse_guard" ]]; then
  DEFAULT_WALL_CLEARANCE_SAFE_DISTANCE=0.55
  DEFAULT_WALL_CLEARANCE_PENALTY=0.7
  DEFAULT_WALL_CLEARANCE_SPEED_WEIGHT=0.9
  DEFAULT_WALL_CLEARANCE_TURN_WEIGHT=0.25
else
  DEFAULT_WALL_CLEARANCE_SAFE_DISTANCE=0.75
  DEFAULT_WALL_CLEARANCE_PENALTY=1.5
  DEFAULT_WALL_CLEARANCE_SPEED_WEIGHT=0.8
  DEFAULT_WALL_CLEARANCE_TURN_WEIGHT=0.4
fi
WALL_CLEARANCE_SAFE_DISTANCE="${DRL_MULTI_WALL_CLEARANCE_SAFE_DISTANCE:-$DEFAULT_WALL_CLEARANCE_SAFE_DISTANCE}"
WALL_CLEARANCE_PENALTY="${DRL_MULTI_WALL_CLEARANCE_PENALTY:-$DEFAULT_WALL_CLEARANCE_PENALTY}"
WALL_CLEARANCE_SPEED_WEIGHT="${DRL_MULTI_WALL_CLEARANCE_SPEED_WEIGHT:-$DEFAULT_WALL_CLEARANCE_SPEED_WEIGHT}"
WALL_CLEARANCE_TURN_WEIGHT="${DRL_MULTI_WALL_CLEARANCE_TURN_WEIGHT:-$DEFAULT_WALL_CLEARANCE_TURN_WEIGHT}"
if [[ "$STAGE" == "stage1e_single_rescue" || "$STAGE" == "stage1f_wall_parallel_rescue" || "$STAGE" == "stage1g_collision_guard" || "$STAGE" == "stage1h_separated_reverse_guard" || "$STAGE" == "stage1i_yaw_reverse_collision_guard" ]]; then
  LOCAL_NAVIGATION_REWARD="${DRL_MULTI_USE_LOCAL_NAVIGATION_REWARD:-1}"
elif [[ "$STAGE" == "stage2a_manual_dense_crossing" || "$STAGE" == "stage2_pre_pairwise_warmup" || "$STAGE" == "stage2_main_pairwise_repair" || "$STAGE" == "stage2b_three_transition" || "$STAGE" == "stage2b_three_light_dense" || "$STAGE" == "stage2_pairwise_to_dense" || "$STAGE" == "stage2_dense_gentle" || "$STAGE" == "stage2_dense_bridge" || "$STAGE" == "stage3_asym_pair_5" || "$STAGE" == "stage3_asym_three_5" || "$STAGE" == "stage4_asym_dense_5_moderate" || "$STAGE" == "stage4_asym_dense_5_bridge" ]]; then
  LOCAL_NAVIGATION_REWARD="${DRL_MULTI_USE_LOCAL_NAVIGATION_REWARD:-1}"
else
  LOCAL_NAVIGATION_REWARD="${DRL_MULTI_USE_LOCAL_NAVIGATION_REWARD:-0}"
fi
if [[ "$STAGE" == "stage2_pre_pairwise_warmup" ]]; then
  DEFAULT_DYNAMIC_REWARD=1
  DEFAULT_REWARD_MODE="interaction_only"
  DEFAULT_INTERACTION_SAFE_DISTANCE=0.9
  DEFAULT_INTERACTION_CLOSE_PENALTY=0.25
  DEFAULT_INTERACTION_STAGNATION_PENALTY=0.02
elif [[ "$STAGE" == "stage2_main_pairwise_repair" || "$STAGE" == "stage2b_three_transition" || "$STAGE" == "stage2b_three_light_dense" || "$STAGE" == "stage2_pairwise_to_dense" || "$STAGE" == "stage2_dense_gentle" || "$STAGE" == "stage2_dense_bridge" || "$STAGE" == "stage3_asym_pair_5" || "$STAGE" == "stage3_asym_three_5" || "$STAGE" == "stage4_asym_dense_5_moderate" || "$STAGE" == "stage4_asym_dense_5_bridge" ]]; then
  DEFAULT_DYNAMIC_REWARD=1
  DEFAULT_INTERACTION_SAFE_DISTANCE=0.9
  DEFAULT_INTERACTION_CLOSE_PENALTY=0.35
  DEFAULT_INTERACTION_STAGNATION_PENALTY=0.02
  if [[ "$STAGE" == "stage2_pairwise_to_dense" || "$STAGE" == "stage2_dense_gentle" || "$STAGE" == "stage2_dense_bridge" || "$STAGE" == "stage3_asym_pair_5" || "$STAGE" == "stage3_asym_three_5" || "$STAGE" == "stage4_asym_dense_5_moderate" || "$STAGE" == "stage4_asym_dense_5_bridge" ]]; then
    DEFAULT_REWARD_MODE="average_plus_interaction"
  else
    DEFAULT_REWARD_MODE="average"
  fi
else
  DEFAULT_DYNAMIC_REWARD=0
  DEFAULT_REWARD_MODE="average"
  DEFAULT_INTERACTION_SAFE_DISTANCE=1.2
  DEFAULT_INTERACTION_CLOSE_PENALTY=0.5
  DEFAULT_INTERACTION_STAGNATION_PENALTY=0.05
fi
DYNAMIC_REWARD="${DRL_MULTI_USE_DYNAMIC_REWARD:-$DEFAULT_DYNAMIC_REWARD}"
REWARD_MODE="${DRL_MULTI_REWARD_MODE:-$DEFAULT_REWARD_MODE}"
INTERACTION_SAFE_DISTANCE="${DRL_MULTI_INTERACTION_SAFE_DISTANCE:-$DEFAULT_INTERACTION_SAFE_DISTANCE}"
INTERACTION_CLOSE_PENALTY="${DRL_MULTI_INTERACTION_CLOSE_PENALTY:-$DEFAULT_INTERACTION_CLOSE_PENALTY}"
INTERACTION_STAGNATION_PENALTY="${DRL_MULTI_INTERACTION_STAGNATION_PENALTY:-$DEFAULT_INTERACTION_STAGNATION_PENALTY}"
if [[ "$STAGE" == "stage2_main_pairwise_repair" || "$STAGE" == "stage2b_three_transition" || "$STAGE" == "stage2b_three_light_dense" ]]; then
  DEFAULT_DISTANCE_WEIGHTED_REWARD=1
  DEFAULT_REWARD_SELF_WEIGHT=0.8
  DEFAULT_LOCAL_CRITIC=1
  DEFAULT_LOCAL_CRITIC_GEOMETRY_ONLY=0
elif [[ "$STAGE" == "stage2_pairwise_to_dense" || "$STAGE" == "stage2_dense_gentle" || "$STAGE" == "stage2_dense_bridge" || "$STAGE" == "stage3_asym_pair_5" || "$STAGE" == "stage3_asym_three_5" || "$STAGE" == "stage4_asym_dense_5_moderate" || "$STAGE" == "stage4_asym_dense_5_bridge" ]]; then
  DEFAULT_DISTANCE_WEIGHTED_REWARD=1
  DEFAULT_REWARD_SELF_WEIGHT=0.85
  DEFAULT_LOCAL_CRITIC=0
  DEFAULT_LOCAL_CRITIC_GEOMETRY_ONLY=0
else
  DEFAULT_DISTANCE_WEIGHTED_REWARD=0
  DEFAULT_REWARD_SELF_WEIGHT=""
  DEFAULT_LOCAL_CRITIC=0
  DEFAULT_LOCAL_CRITIC_GEOMETRY_ONLY=0
fi
DISTANCE_WEIGHTED_REWARD="${DRL_MULTI_USE_DISTANCE_WEIGHTED_REWARD:-$DEFAULT_DISTANCE_WEIGHTED_REWARD}"
REWARD_SELF_WEIGHT="${DRL_MULTI_REWARD_SELF_WEIGHT:-$DEFAULT_REWARD_SELF_WEIGHT}"
LOCAL_CRITIC="${DRL_MULTI_USE_LOCAL_CRITIC:-$DEFAULT_LOCAL_CRITIC}"
LOCAL_CRITIC_GEOMETRY_ONLY="${DRL_MULTI_LOCAL_CRITIC_GEOMETRY_ONLY:-$DEFAULT_LOCAL_CRITIC_GEOMETRY_ONLY}"
LOAD_ACTOR_ONLY="${DRL_MULTI_LOAD_ACTOR_ONLY:-${DEFAULT_LOAD_ACTOR_ONLY:-0}}"
ACTOR_UPDATE_DELAY_STEPS="${DRL_MULTI_ACTOR_UPDATE_DELAY_STEPS:-${DEFAULT_ACTOR_UPDATE_DELAY_STEPS:-0}}"
POLICY_FREQ="${DRL_MULTI_POLICY_FREQ:-2}"
ACTOR_ANCHOR_WEIGHT="${DRL_MULTI_ACTOR_ANCHOR_WEIGHT:-0}"
ACTOR_TRAIN_MODE="${DRL_MULTI_ACTOR_TRAIN_MODE:-full}"
RESUME_TRAINING="${DRL_MULTI_RESUME_TRAINING:-1}"
LOCAL_CRITIC_MAX_AGENTS="${DRL_MULTI_LOCAL_CRITIC_MAX_AGENTS:-10}"
LOCAL_NAV_HEADING_WEIGHT="${DRL_MULTI_LOCAL_NAV_HEADING_WEIGHT:-0.35}"
LOCAL_NAV_WRONG_WAY_PENALTY="${DRL_MULTI_LOCAL_NAV_WRONG_WAY_PENALTY:-0.25}"
LOCAL_NAV_TURN_WEIGHT="${DRL_MULTI_LOCAL_NAV_TURN_WEIGHT:-0.22}"
LOCAL_NAV_NEAR_GOAL_DISTANCE="${DRL_MULTI_LOCAL_NAV_NEAR_GOAL_DISTANCE:-0.9}"
LOCAL_NAV_HEADING_ERROR="${DRL_MULTI_LOCAL_NAV_HEADING_ERROR:-0.5}"

mkdir -p "$LOG_DIR"

timestamp="$(date +%Y%m%d_%H%M%S)"
log_file="$LOG_DIR/train_multi_curriculum_${STAGE}_detached_${timestamp}.log"

if [[ -f "$PID_FILE" ]]; then
  old_pid="$(cat "$PID_FILE" 2>/dev/null || true)"
  if [[ -n "$old_pid" ]] && kill -0 "$old_pid" 2>/dev/null; then
    echo "A detached curriculum training process is already running with PID $old_pid"
    exit 1
  fi
fi

existing_pid="$(
  (
    pgrep -af "^python3(\\.8)? .*train_velodyne_td3_multi\\.py$" \
      | awk 'NR==1 {print $1}'
  ) || true
)"
if [[ -n "$existing_pid" ]]; then
  echo "A multi-agent training process is already running with PID $existing_pid"
  echo "Please stop it before starting curriculum stage $STAGE."
  exit 1
fi

if [[ "$STAGE" == "stage4_asym_dense_5_bridge" && "$ACTOR_TRAIN_MODE" == "full" && "${DRL_MULTI_ALLOW_FULL_ACTOR_FINETUNE:-0}" != "1" ]]; then
  echo "Direct full-actor fine-tune on stage4_asym_dense_5_bridge is paused."
  echo "It already degraded from both 5D and 5A warm starts."
  echo "Use a dedicated dense-actor script with controlled unfreezing/adapter training instead."
  echo "Set DRL_MULTI_ALLOW_FULL_ACTOR_FINETUNE=1 only for deliberate reproduction."
  exit 1
fi

if port_in_use "$ROS_PORT"; then
  echo "ROS port $ROS_PORT is already in use. Please choose a different DRL_MULTI_ROS_PORT."
  exit 1
fi

if port_in_use "$GAZEBO_PORT"; then
  echo "Gazebo port $GAZEBO_PORT is already in use. Please choose a different DRL_MULTI_GAZEBO_PORT."
  exit 1
fi

python3 "$PROJECT_ROOT/scripts/generate_multi_robot_launch.py" \
  --num-agents "$NUM_AGENTS" \
  --output "$LAUNCH_PATH"

setsid bash -lc "
  source /opt/ros/noetic/setup.bash
  source '$PROJECT_ROOT/env.python.sh'
  export ROS_HOSTNAME=localhost
  export ROS_MASTER_URI=http://localhost:${ROS_PORT}
  export ROS_PORT_SIM=${ROS_PORT}
  export GAZEBO_MASTER_URI=http://localhost:${GAZEBO_PORT}
  export GAZEBO_RESOURCE_PATH='$ROS_WORKSPACE_ROOT/catkin_ws/src/multi_robot_scenario/launch'
  export DRL_MULTI_NUM_AGENTS='$NUM_AGENTS'
  export DRL_MULTI_TRAIN_LAUNCHFILE='$LAUNCHFILE'
  export DRL_MULTI_SCENARIO=curriculum
  export DRL_MULTI_CURRICULUM_CASES='$CASES_PATH'
  export DRL_MULTI_CURRICULUM_SAMPLING='$CURRICULUM_SAMPLING'
  export DRL_MULTI_USE_DYNAMIC_REWARD='$DYNAMIC_REWARD'
  export DRL_MULTI_REWARD_MODE='$REWARD_MODE'
  if [[ -n '$REWARD_SELF_WEIGHT' ]]; then export DRL_MULTI_REWARD_SELF_WEIGHT='$REWARD_SELF_WEIGHT'; fi
  export DRL_MULTI_USE_DISTANCE_WEIGHTED_REWARD='$DISTANCE_WEIGHTED_REWARD'
  export DRL_MULTI_INTERACTION_SAFE_DISTANCE='$INTERACTION_SAFE_DISTANCE'
  export DRL_MULTI_INTERACTION_CLOSE_PENALTY='$INTERACTION_CLOSE_PENALTY'
  export DRL_MULTI_INTERACTION_STAGNATION_PENALTY='$INTERACTION_STAGNATION_PENALTY'
  export DRL_MULTI_USE_LOCAL_CRITIC='$LOCAL_CRITIC'
  export DRL_MULTI_LOCAL_CRITIC_GEOMETRY_ONLY='$LOCAL_CRITIC_GEOMETRY_ONLY'
  export DRL_MULTI_LOCAL_CRITIC_MAX_AGENTS='$LOCAL_CRITIC_MAX_AGENTS'
  export DRL_MULTI_ACTIVE_NEIGHBORS_ONLY=1
  export DRL_MULTI_USE_WALL_CLEARANCE_REWARD='$WALL_CLEARANCE_REWARD'
  export DRL_MULTI_WALL_CLEARANCE_SAFE_DISTANCE='$WALL_CLEARANCE_SAFE_DISTANCE'
  export DRL_MULTI_WALL_CLEARANCE_PENALTY='$WALL_CLEARANCE_PENALTY'
  export DRL_MULTI_WALL_CLEARANCE_SPEED_WEIGHT='$WALL_CLEARANCE_SPEED_WEIGHT'
  export DRL_MULTI_WALL_CLEARANCE_TURN_WEIGHT='$WALL_CLEARANCE_TURN_WEIGHT'
  export DRL_MULTI_USE_LOCAL_NAVIGATION_REWARD='$LOCAL_NAVIGATION_REWARD'
  export DRL_MULTI_LOCAL_NAV_HEADING_WEIGHT='$LOCAL_NAV_HEADING_WEIGHT'
  export DRL_MULTI_LOCAL_NAV_WRONG_WAY_PENALTY='$LOCAL_NAV_WRONG_WAY_PENALTY'
  export DRL_MULTI_LOCAL_NAV_TURN_WEIGHT='$LOCAL_NAV_TURN_WEIGHT'
  export DRL_MULTI_LOCAL_NAV_NEAR_GOAL_DISTANCE='$LOCAL_NAV_NEAR_GOAL_DISTANCE'
  export DRL_MULTI_LOCAL_NAV_HEADING_ERROR='$LOCAL_NAV_HEADING_ERROR'
  export DRL_MULTI_BEST_METRIC=full_success
  export DRL_MULTI_EVAL_EPISODES='$EVAL_EPISODES'
  export DRL_MULTI_MAX_EPOCHS='$MAX_EPOCHS'
  export DRL_MULTI_EXPL_NOISE='$EXPL_NOISE'
  export DRL_MULTI_EXPL_MIN='$EXPL_MIN'
  export DRL_MULTI_ACTOR_LR='$ACTOR_LR'
  export DRL_MULTI_CRITIC_LR='$CRITIC_LR'
  export DRL_MULTI_ACTOR_UPDATE_DELAY_STEPS='$ACTOR_UPDATE_DELAY_STEPS'
  export DRL_MULTI_POLICY_FREQ='$POLICY_FREQ'
  export DRL_MULTI_ACTOR_ANCHOR_WEIGHT='$ACTOR_ANCHOR_WEIGHT'
  export DRL_MULTI_ACTOR_TRAIN_MODE='$ACTOR_TRAIN_MODE'
  export DRL_MULTI_RESUME_TRAINING='$RESUME_TRAINING'
  export DRL_MULTI_TRAINING_VERSION='${DRL_MULTI_TRAINING_VERSION:-$VERSION}'
  export DRL_MULTI_TRAIN_FILE_NAME='$MODEL_NAME'
  export DRL_MULTI_LOAD_MODEL=1
  export DRL_MULTI_LOAD_ACTOR_ONLY='$LOAD_ACTOR_ONLY'
  export DRL_MULTI_LOAD_MODEL_NAME='$LOAD_MODEL_NAME'
  cd '$ROS_WORKSPACE_ROOT/catkin_ws'
  source devel_isolated/setup.bash
  cd '$TD3_DIR'
  exec python3 -u train_velodyne_td3_multi.py
" >"$log_file" 2>&1 < /dev/null &

echo $! > "$PID_FILE"

echo "Detached curriculum training started."
echo "Stage: $STAGE"
echo "PID: $(cat "$PID_FILE")"
echo "Agents: $NUM_AGENTS"
echo "Model: $MODEL_NAME"
echo "Warm start: $LOAD_MODEL_NAME"
echo "Warm start actor only: $LOAD_ACTOR_ONLY"
echo "Cases: $CASES_PATH"
echo "Launch: $LAUNCH_PATH"
echo "ROS workspace root: $ROS_WORKSPACE_ROOT"
echo "Sampling: $CURRICULUM_SAMPLING"
echo "Max epochs: $MAX_EPOCHS"
echo "Eval episodes: $EVAL_EPISODES"
echo "Exploration noise: $EXPL_NOISE"
echo "Actor LR: $ACTOR_LR"
echo "Critic LR: $CRITIC_LR"
echo "Actor update delay steps: $ACTOR_UPDATE_DELAY_STEPS"
echo "Policy freq: $POLICY_FREQ"
echo "Actor anchor weight: $ACTOR_ANCHOR_WEIGHT"
echo "Actor train mode: $ACTOR_TRAIN_MODE"
echo "Resume training: $RESUME_TRAINING"
echo "Dynamic reward: $DYNAMIC_REWARD"
echo "Reward mode: $REWARD_MODE"
echo "Distance-weighted reward: $DISTANCE_WEIGHTED_REWARD"
echo "Reward self weight: ${REWARD_SELF_WEIGHT:-default}"
echo "Interaction safe distance: $INTERACTION_SAFE_DISTANCE"
echo "Interaction close penalty: $INTERACTION_CLOSE_PENALTY"
echo "Interaction stagnation penalty: $INTERACTION_STAGNATION_PENALTY"
echo "Local critic: $LOCAL_CRITIC"
echo "Local critic geometry only: $LOCAL_CRITIC_GEOMETRY_ONLY"
echo "Wall-clearance reward: $WALL_CLEARANCE_REWARD"
echo "Wall-clearance safe distance: $WALL_CLEARANCE_SAFE_DISTANCE"
echo "Wall-clearance penalty: $WALL_CLEARANCE_PENALTY"
echo "Local-navigation reward: $LOCAL_NAVIGATION_REWARD"
echo "Local-navigation heading weight: $LOCAL_NAV_HEADING_WEIGHT"
echo "Local-navigation wrong-way penalty: $LOCAL_NAV_WRONG_WAY_PENALTY"
echo "Local-navigation turn weight: $LOCAL_NAV_TURN_WEIGHT"
echo "Log: $log_file"
