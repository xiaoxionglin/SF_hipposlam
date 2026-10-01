import os
import random
import shutil
import time
from os.path import join
from typing import Dict, Optional

import cv2
import deepmind_lab
import gymnasium as gym
import numpy as np

from sample_factory.utils.typing import PolicyID
from sample_factory.utils.utils import ensure_dir_exists, log
from sf_working_directories.zeynep.dmlab.dmlab30 import (
    DMLAB_INSTRUCTIONS,
    DMLAB_MAX_INSTRUCTION_LEN,
    DMLAB_VOCABULARY_SIZE,
)
from sf_working_directories.zeynep.dmlab.dmlab_level_cache import DmlabLevelCache
from sf_working_directories.zeynep.dmlab.dmlab_utils import string_to_hash_bucket

ACTION_SET = (
    (0, 0, 0, 1, 0, 0, 0),  # Forward
    (0, 0, 0, -1, 0, 0, 0),  # Backward
    (0, 0, -1, 0, 0, 0, 0),  # Strafe Left
    (0, 0, 1, 0, 0, 0, 0),  # Strafe Right
    (-20, 0, 0, 0, 0, 0, 0),  # Look Left
    (20, 0, 0, 0, 0, 0, 0),  # Look Right
    (-20, 0, 0, 1, 0, 0, 0),  # Look Left + Forward
    (20, 0, 0, 1, 0, 0, 0),  # Look Right + Forward
    (0, 0, 0, 0, 1, 0, 0),  # Fire.
)

REDUCED_ACTION_SET = (
    (0, 0, 0, 1, 0, 0, 0),  # Forward
    # (0, 0, 0, -1, 0, 0, 0),  # Backward
    (0, 0, -1, 0, 0, 0, 0),  # Strafe Left
    (0, 0, 1, 0, 0, 0, 0),  # Strafe Right
    # (-20, 0, 0, 0, 0, 0, 0),  # Look Left
    # (20, 0, 0, 0, 0, 0, 0),  # Look Right
    (-20, 0, 0, 1, 0, 0, 0),  # Look Left + Forward
    (20, 0, 0, 1, 0, 0, 0),  # Look Right + Forward
    # (0, 0, 0, 0, 1, 0, 0),  # Fire.
)

EXTENDED_ACTION_SET = (
    (0, 0, 0, 1, 0, 0, 0),  # Forward
    (0, 0, 0, -1, 0, 0, 0),  # Backward
    (0, 0, -1, 0, 0, 0, 0),  # Strafe Left
    (0, 0, 1, 0, 0, 0, 0),  # Strafe Right
    (-10, 0, 0, 0, 0, 0, 0),  # Small Look Left
    (10, 0, 0, 0, 0, 0, 0),  # Small Look Right
    (-60, 0, 0, 0, 0, 0, 0),  # Large Look Left
    (60, 0, 0, 0, 0, 0, 0),  # Large Look Right
    (0, 10, 0, 0, 0, 0, 0),  # Look Down
    (0, -10, 0, 0, 0, 0, 0),  # Look Up
    (-10, 0, 0, 1, 0, 0, 0),  # Forward + Small Look Left
    (10, 0, 0, 1, 0, 0, 0),  # Forward + Small Look Right
    (-60, 0, 0, 1, 0, 0, 0),  # Forward + Large Look Left
    (60, 0, 0, 1, 0, 0, 0),  # Forward + Large Look Right
    (0, 0, 0, 0, 1, 0, 0),  # Fire.
)


def dmlab_level_to_level_name(level):
    level_name = level.split("/")[-1]
    return level_name


class DmlabGymEnv(gym.Env):
    def __init__(
        self,
        task_id,
        level,
        action_repeat,
        res_w,
        res_h,
        benchmark_mode,
        renderer,
        dataset_path,
        with_instructions,
        extended_action_set,
        level_cache_path,
        gpu_index,
        dmlab_level_caches_per_policy: Dict[PolicyID, DmlabLevelCache] = None,
        extra_cfg=None,
        render_mode: Optional[str] = None,
    ):
        self.width = res_w
        self.height = res_h

        # self._main_observation = 'DEBUG.CAMERA_INTERLEAVED.PLAYER_VIEW_NO_RETICLE'
        self.main_observation = "RGB_INTERLEAVED"
        self.instructions_observation = DMLAB_INSTRUCTIONS
        self.with_instructions = with_instructions and not benchmark_mode

        self.action_repeat = action_repeat

        self.random_state = None

        self.task_id = task_id
        self.level = level
        self.level_name = dmlab_level_to_level_name(self.level)

        # the policy index which currently acts in the environment
        self.curr_policy_idx = 0
        self.dmlab_level_caches_per_policy = dmlab_level_caches_per_policy
        self.use_level_cache = self.dmlab_level_caches_per_policy is not None
        self.curr_cache = None
        if self.use_level_cache:
            self.curr_cache = self.dmlab_level_caches_per_policy[self.curr_policy_idx]

        self.instructions = np.zeros([DMLAB_MAX_INSTRUCTION_LEN], dtype=np.int32)

        observation_format = [self.main_observation]
        if self.with_instructions:
            observation_format += [self.instructions_observation]

        config = {
            "width": self.width,
            "height": self.height,
            "gpuDeviceIndex": str(gpu_index),
            "datasetPath": dataset_path,
        }

        if extra_cfg is not None:
            config.update(extra_cfg)
        config = {k: str(v) for k, v in config.items()}

        self.render_mode: Optional[str] = render_mode

        self.level_cache_path = ensure_dir_exists(level_cache_path)

        # this object provides fetch and write methods, hence using "self" for env level cache
        env_level_cache = self if self.use_level_cache else None

        self.env_uses_level_cache = False  # will be set to True when this env instance queries the cache
        self.last_reset_seed = None

        self.dmlab = deepmind_lab.Lab(
            level,
            observation_format,
            config=config,
            renderer=renderer,
            level_cache=env_level_cache,
        )

        self.action_set = EXTENDED_ACTION_SET if extended_action_set else ACTION_SET
        self.action_list = np.array(self.action_set, dtype=np.intc)  # DMLAB requires intc type for actions

        self.last_observation = None

        self.render_scale = 5
        self.render_fps = 30
        self.last_frame = time.time()

        self.action_space = gym.spaces.Discrete(len(self.action_set))

        self.observation_space = gym.spaces.Dict(
            obs=gym.spaces.Box(low=0, high=255, shape=(self.height, self.width, 3), dtype=np.uint8)
        )
        if self.with_instructions:
            self.observation_space.spaces[self.instructions_observation] = gym.spaces.Box(
                low=0,
                high=DMLAB_VOCABULARY_SIZE,
                shape=[DMLAB_MAX_INSTRUCTION_LEN],
                dtype=np.int32,
            )

        self.benchmark_mode = benchmark_mode
        if self.benchmark_mode:
            log.warning("DmLab benchmark mode is true! Use this only for testing, not for actual training runs!")

        self.seed()

    def seed(self, seed=None):
        if self.benchmark_mode:
            initial_seed = 42
        else:
            if seed is None:
                initial_seed = random.randint(0, int(1e9))
            else:
                initial_seed = seed

        self.random_state = np.random.RandomState(seed=initial_seed)
        return [initial_seed]

    def format_obs_dict(self, env_obs_dict):
        """SampleFactory traditionally uses 'obs' key for the 'main' observation."""
        env_obs_dict["obs"] = env_obs_dict.pop(self.main_observation)

        instr = env_obs_dict.get(self.instructions_observation)
        self.instructions[:] = 0
        if instr is not None:
            instr_words = instr.split()
            for i, word in enumerate(instr_words):
                self.instructions[i] = string_to_hash_bucket(word, DMLAB_VOCABULARY_SIZE)

            env_obs_dict[self.instructions_observation] = self.instructions

        return env_obs_dict

    def reset(self, **kwargs):
        if self.use_level_cache:
            self.curr_cache = self.dmlab_level_caches_per_policy[self.curr_policy_idx]
            self.last_reset_seed = self.curr_cache.get_unused_seed(self.level, self.random_state)
        else:
            self.last_reset_seed = self.random_state.randint(0, 2**31 - 1)

        self.dmlab.reset(seed=self.last_reset_seed)
        self.last_observation = self.format_obs_dict(self.dmlab.observations())
        return self.last_observation, {}

    def step(self, action):
        if self.benchmark_mode:
            # the performance of many DMLab environments heavily depends on what agent is actually doing
            # therefore for purposes of measuring throughput we ignore the actions, this way the agent executes
            # random policy and we can measure raw throughput more precisely
            action = random.randrange(0, self.action_space.n)

        reward = self.dmlab.step(self.action_list[action], num_steps=self.action_repeat)
        terminated = not self.dmlab.is_running()
        truncated = False

        if not terminated:
            obs_dict = self.format_obs_dict(self.dmlab.observations())
            self.last_observation = obs_dict

        info = {"num_frames": self.action_repeat}
        return self.last_observation, reward, terminated, truncated, info

    def render(self) -> Optional[np.ndarray]:
        if self.last_observation is None and self.dmlab.is_running():
            self.last_observation = self.dmlab.observations()

        img = self.last_observation["obs"]
        if self.render_mode == "rgb_array":
            return img
        elif self.render_mode != "human":
            raise Exception(f"Rendering mode {self.render_mode} not supported")

        img = np.transpose(img, (1, 2, 0))  # CHW to HWC

        img = cv2.cvtColor(img, cv2.COLOR_RGB2BGR)

        scale = self.render_scale
        img_big = cv2.resize(img, (self.width * scale, self.height * scale), interpolation=cv2.INTER_NEAREST)
        cv2.imshow("dmlab_examples", img_big)

        since_last_frame = time.time() - self.last_frame
        wait_time_sec = max(1.0 / self.render_fps - since_last_frame, 0.001)
        wait_time_ms = max(int(1000 * wait_time_sec), 1)
        cv2.waitKey(wait_time_ms)
        self.last_frame = time.time()

    def close(self):
        self.dmlab.close()

    def fetch(self, key, pk3_path):
        """Environment object itself acts as a proxy to the global level cache."""
        if not self.env_uses_level_cache:
            self.env_uses_level_cache = True
            # log.debug('Env %s uses level cache!', self.level_name)

        path = join(self.level_cache_path, key)

        if os.path.isfile(path):
            # copy the cached file to the path expected by DeepMind Lab
            shutil.copyfile(path, pk3_path)
            return True
        else:
            log.warning("Cache miss in environment %s key: %s!", self.level_name, key)
            return False

    def write(self, key, pk3_path):
        """Environment object itself acts as a proxy to the global level cache."""
        if self.use_level_cache:
            log.debug("Add new level to cache! Level %s seed %r key %s", self.level_name, self.last_reset_seed, key)
            self.curr_cache.add_new_level(self.level, self.last_reset_seed, key, pk3_path)


class DmlabGymEnv_custom(gym.Env):
    def __init__(
        self,
        task_id,
        level,
        action_repeat,
        res_w,
        res_h,
        benchmark_mode,
        renderer,
        dataset_path,
        with_instructions,
        extended_action_set,
        level_cache_path,
        gpu_index,
        dmlab_level_caches_per_policy: Dict[PolicyID, DmlabLevelCache] = None,
        extra_cfg=None,
        render_mode: Optional[str] = None,
        depth_sensor=True,
        reduced_action_set=False,
        with_number_instruction=True,
        with_pos_obs=False,
        reward_input = False,
        high_level = False
    ):

        # self.depth_sensor = depth_sensor
        self.width = res_w
        self.height = res_h

        # self._main_observation = 'DEBUG.CAMERA_INTERLEAVED.PLAYER_VIEW_NO_RETICLE'
        self.main_observation = "RGB_INTERLEAVED"
        self.num_channels = 3
        if depth_sensor:
            self.main_observation = "RGBD_INTERLEAVED"
            self.num_channels = 4
        self.instructions_observation = DMLAB_INSTRUCTIONS
        self.with_instructions = False #with_instructions and not benchmark_mode
        self.with_number_instruction = with_number_instruction

        self.action_repeat = action_repeat

        self.random_state = None

        self.task_id = task_id
        self.level = level
        self.level_name = dmlab_level_to_level_name(self.level)

        # the policy index which currently acts in the environment
        self.curr_policy_idx = 0
        self.dmlab_level_caches_per_policy = dmlab_level_caches_per_policy
        self.use_level_cache = self.dmlab_level_caches_per_policy is not None
        self.curr_cache = None
        if self.use_level_cache:
            self.curr_cache = self.dmlab_level_caches_per_policy[self.curr_policy_idx]

        self.instructions = np.zeros([DMLAB_MAX_INSTRUCTION_LEN], dtype=np.int32)
        if self.with_number_instruction:
            self.instructions = np.zeros([1], dtype=np.int32)

        observation_format = [self.main_observation]
        if self.with_instructions or self.with_number_instruction:
            observation_format += [self.instructions_observation]
        self.with_pos_obs = with_pos_obs
        if self.with_pos_obs:
            observation_format += ["DEBUG.POS.TRANS", "DEBUG.POS.ROT"]

        #### 1. ADDED THIS BLOCK ###
        # Ask DeepMind Lab C++ engine for our custom Lua tensors
        observation_format += [
            'highrew_hit', 'highrew_miss', 'lowrew_hit', 'lowrew_miss',
            'highrew_hit_total', 'highrew_miss_total',
            'lowrew_hit_total', 'lowrew_miss_total',
            'flexibility', 'inst_block'
        ]

        self.reward_input = reward_input
        if not self.reward_input:
            log.debug("REWARD INPUT IS DISABLED")
        else:
            log.debug("REWARD INPUT IS ENABLED")
            observation_format += ["reward_input"]

        # Initialize step-tracking temporary pulse variables
        self._temp_hi_hit = 0.0
        self._temp_hi_miss = 0.0
        self._temp_lo_hit = 0.0
        self._temp_lo_miss = 0.0

        # Initialize history tracking arrays for local timelines
        self.hi_hit_history = []
        self.hi_miss_history = []
        self.lo_hit_history = []
        self.lo_miss_history = []
        self.current_episode_step = 0
        ###########################

        config = {
            "width": self.width,
            "height": self.height,
            "gpuDeviceIndex": str(gpu_index),
            "datasetPath": dataset_path,
        }

        if extra_cfg is not None:
            config.update(extra_cfg)
        config = {k: str(v) for k, v in config.items()}

        self.high_level=high_level
        if self.high_level:
            log.warning("HighLevel mode is enabled for this environment!")
            observation_format += ['outcome_event', 'prev_trial_reward', 'chosen_arm']

        self.render_mode: Optional[str] = render_mode

        self.level_cache_path = ensure_dir_exists(level_cache_path)

        # this object provides fetch and write methods, hence using "self" for env level cache
        env_level_cache = self if self.use_level_cache else None

        self.env_uses_level_cache = False  # will be set to True when this env instance queries the cache
        self.last_reset_seed = None

        self.dmlab = deepmind_lab.Lab(
            level,
            observation_format,
            config=config,
            renderer=renderer,
            level_cache=env_level_cache,
        )

        self.action_set = EXTENDED_ACTION_SET if extended_action_set else ACTION_SET
        if reduced_action_set:
            log.info("using reduced action set!")
            self.action_set = REDUCED_ACTION_SET
        self.action_list = np.array(self.action_set, dtype=np.intc)  # DMLAB requires intc type for actions

        self.last_observation = None

        self.render_scale = 5
        self.render_fps = 30
        self.last_frame = time.time()

        self.action_space = gym.spaces.Discrete(len(self.action_set))

        self.observation_space = gym.spaces.Dict(
            obs=gym.spaces.Box(low=0, high=255, shape=(self.height, self.width, self.num_channels), dtype=np.uint8)
        )
        if self.with_instructions:
            self.observation_space.spaces[self.instructions_observation] = gym.spaces.Box(
                low=0,
                high=DMLAB_VOCABULARY_SIZE,
                shape=[DMLAB_MAX_INSTRUCTION_LEN],
                dtype=np.int32,
            )
        if self.with_number_instruction:
            self.observation_space.spaces[self.instructions_observation] = gym.spaces.Box(
                low=0,
                high=5,
                shape=[1],
                dtype=np.int32,
            )
        if self.with_pos_obs:
            self.observation_space.spaces["pos"] = gym.spaces.Box(
                low=-100,
                high=2500,
                shape=[3],
                dtype=np.float64,
            )
            self.observation_space.spaces["rot"] = gym.spaces.Box(
                low=-1000,
                high=1000,
                shape=[3],
                dtype=np.float64,
            )
        
        ## ADDED ##
        if self.reward_input:
            self.observation_space.spaces["reward_input"] = gym.spaces.Box(
                low=-np.inf,
                high=np.inf,
                shape=(1,),
                dtype=np.float32,
            )

        if self.high_level:
            self.observation_space.spaces["outcome_event"] = gym.spaces.Box(
                low=0.0,
                high=1.0,
                shape=(1,),
                dtype=np.float32,
            )
            self.observation_space.spaces["prev_trial_reward"] = gym.spaces.Box(
                low=0.0,
                high=1.0,
                shape=(1,),
                dtype=np.float32,
            )
            # self.observation_space.spaces["inst_block"] = gym.spaces.Box(
            #     low=0,
            #     high=2,
            #     shape=(1,),
            #     dtype=np.int32,
            # )

            self.observation_space.spaces["chosen_arm"] = gym.spaces.Box(
                low=0,
                high=2,
                shape=(1,),
                dtype=np.int32,
            ) # 1 means RIGHT 2 means LEFT 0 means NONE
        ###########
        
        # if self.depth_sensor:
        #     self.observation_space.spaces['depth'] = gym.spaces.Box(
        #         low=0,
        #         high=255,
        #         shape=[DMLAB_MAX_INSTRUCTION_LEN],
        #         dtype=np.int32,
        #     )

        self.benchmark_mode = benchmark_mode
        if self.benchmark_mode:
            log.warning("DmLab benchmark mode is true! Use this only for testing, not for actual training runs!")

        self.seed()

    def seed(self, seed=None):
        if self.benchmark_mode:
            initial_seed = 42
        else:
            if seed is None:
                initial_seed = random.randint(0, int(1e9))
            else:
                initial_seed = seed

        self.random_state = np.random.RandomState(seed=initial_seed)
        return [initial_seed]

    def format_obs_dict(self, env_obs_dict):
        """SampleFactory traditionally uses 'obs' key for the 'main' observation."""
        env_obs_dict["obs"] = env_obs_dict.pop(self.main_observation)

        instr = env_obs_dict.get(self.instructions_observation)
        self.instructions[:] = 0
        
        ## ADDED to pass reward_input from Lua to Python
        if self.reward_input:
            reward_input = env_obs_dict.pop(
                "reward_input",
                np.zeros((1,), dtype=np.float32),
            )

            env_obs_dict["reward_input"] = np.asarray(
                reward_input,
                dtype=np.float32,
            ).reshape(1) 

        # Required for HL-RNN to know when a trial has ended and what the outcome was from obs dictionary:
        if self.high_level:
            chosen_arm = env_obs_dict.pop("chosen_arm", [0])
            env_obs_dict["chosen_arm"] = np.asarray(chosen_arm, dtype=np.int32).reshape(1)

            outcome_event = env_obs_dict.pop("outcome_event", [0.0])
            env_obs_dict["outcome_event"] = np.asarray(outcome_event, dtype=np.float32).reshape(1)

            prev_trial_reward = env_obs_dict.pop("prev_trial_reward", [0.0])
            env_obs_dict["prev_trial_reward"] = np.asarray(prev_trial_reward, dtype=np.float32).reshape(1)

            inst_block = env_obs_dict.pop("inst_block", [0])
            env_obs_dict["inst_block"] = np.asarray(inst_block, dtype=np.int32).reshape(1)
        ##########################################

        if instr is not None:
            if self.with_number_instruction:
                # print(instr)
                self.instructions[0] = int(instr)
                self._last_instruction = self.instructions[0] #### ADDED to track instruction switch
            else:
                instr_words = instr.split()
                for i, word in enumerate(instr_words):
                    self.instructions[i] = string_to_hash_bucket(word, DMLAB_VOCABULARY_SIZE)

        env_obs_dict[self.instructions_observation] = self.instructions

        # --- ADDED PART: EXTRACT CUSTOM FLAGS FROM OBSERVATION AND KEEP THEM LOCALLY TO ADD INTO INFO ---
        # Extract instantaneous frame pulses for step history tracking
        self._temp_hi_hit = float(env_obs_dict.pop('highrew_hit', [0.0])[0])
        self._temp_hi_miss = float(env_obs_dict.pop('highrew_miss', [0.0])[0])
        self._temp_lo_hit = float(env_obs_dict.pop('lowrew_hit', [0.0])[0])
        self._temp_lo_miss = float(env_obs_dict.pop('lowrew_miss', [0.0])[0])

        # Grab the running totals sent directly from Lua
        self._total_hi_hit = float(env_obs_dict.pop('highrew_hit_total', [0.0])[0])
        self._total_hi_miss = float(env_obs_dict.pop('highrew_miss_total', [0.0])[0])
        self._total_lo_hit = float(env_obs_dict.pop('lowrew_hit_total', [0.0])[0])
        self._total_lo_miss = float(env_obs_dict.pop('lowrew_miss_total', [0.0])[0])

        self._flexibility = float(env_obs_dict.pop('flexibility', [0.0])[0])
        #self._inst_block = int(env_obs_dict.pop('inst_block', [0])[0])
        # -----------------------------------------

      # if self.with_pos_obs:
        #     env_obs_dict
        return env_obs_dict

    def reset(self, **kwargs):
        if self.use_level_cache:
            self.curr_cache = self.dmlab_level_caches_per_policy[self.curr_policy_idx]
            self.last_reset_seed = self.curr_cache.get_unused_seed(self.level, self.random_state)
        else:
            self.last_reset_seed = self.random_state.randint(0, 2**31 - 1)

        self.dmlab.reset(seed=self.last_reset_seed)
        self.last_observation = self.format_obs_dict(self.dmlab.observations())

        # --- ADDED: Initialize Episode Step Trackers ---
        self.current_episode_step = 0
        
        # History lists for tracking exact step timelines
        self.hi_hit_history = []
        self.hi_miss_history = []
        self.lo_hit_history = []
        self.lo_miss_history = []
        # -----------------------------------------------

        # Debugging: Print the expected and actual observation shapes
        #current_obs = self.last_observation
        #print("\n=== DEBUGGING SHAPES ===")
        #print("EXPECTED SPACE:", self.observation_space)
        #print("ACTUAL OBS SHAPES:", {k: getattr(v, 'shape', type(v)) for k, v in current_obs.items()})
        #print("========================\n")

        return self.last_observation, {}

    def step(self, action):
        if self.benchmark_mode:
            # the performance of many DMLab environments heavily depends on what agent is actually doing
            # therefore for purposes of measuring throughput we ignore the actions, this way the agent executes
            # random policy and we can measure raw throughput more precisely
            action = random.randrange(0, self.action_space.n)

        reward = self.dmlab.step(self.action_list[action], num_steps=self.action_repeat)
        terminated = not self.dmlab.is_running()
        truncated = False

        info = {"num_frames": self.action_repeat}

        # --- ADDED: Tick the episode clock ---
        self.current_episode_step += 1
        # -------------------------------------

        if not terminated:
            obs_dict = self.format_obs_dict(self.dmlab.observations())
            self.last_observation = obs_dict

        ###### ADDED Accumulate totals for the WandB graphs INTO INFO #######
        info["highrew_hit"] = getattr(self, '_temp_hi_hit', 0.0) > 0
        info["highrew_miss"] = getattr(self, '_temp_hi_miss', 0.0) > 0
        info["lowrew_hit"] = getattr(self, '_temp_lo_hit', 0.0) > 0
        info["lowrew_miss"] = getattr(self, '_temp_lo_miss', 0.0) > 0


        if terminated or truncated:
            if "episode_extra_stats" not in info:
                info["episode_extra_stats"] = dict()

            # Directly pull the final totals calculated by Lua and feed them to WandB
            info["episode_extra_stats"]["custom/highrew_hit"] = self._total_hi_hit
            info["episode_extra_stats"]["custom/highrew_miss"] = self._total_hi_miss
            info["episode_extra_stats"]["custom/lowrew_hit"] = self._total_lo_hit
            info["episode_extra_stats"]["custom/lowrew_miss"] = self._total_lo_miss

            total_correct = self._total_hi_hit + self._total_lo_hit
            total_incorrect = self._total_hi_miss + self._total_lo_miss
            total_trials = total_correct + total_incorrect
            info["episode_extra_stats"]["custom/arm_obedience"] = total_correct / total_trials if total_trials > 0 else 0.0

            info["episode_extra_stats"]["custom/flexibility"] = self._flexibility

            info["episode_extra_stats"]["custom/instr_switch"] = self._last_instruction 

            #info["episode_extra_stats"]["custom/inst_block"] = self._inst_block
            
            # Save raw step histories locally
            info["hi_hit_history"] = self.hi_hit_history.copy()
            info["hi_miss_history"] = self.hi_miss_history.copy()
            info["lo_hit_history"] = self.lo_hit_history.copy()
            info["lo_miss_history"] = self.lo_miss_history.copy()

            # Reset local step clocks and history
            self.current_episode_step = 0
            self.hi_hit_history.clear()
            self.hi_miss_history.clear()
            self.lo_hit_history.clear()
            self.lo_miss_history.clear()
        ########################################################

        return self.last_observation, reward, terminated, truncated, info

    def render(self) -> Optional[np.ndarray]:
        if self.last_observation is None and self.dmlab.is_running():
            self.last_observation = self.dmlab.observations()

        img = self.last_observation["obs"]
        if self.render_mode == "rgb_array":
            return img
        elif self.render_mode != "human":
            raise Exception(f"Rendering mode {self.render_mode} not supported")

        img = np.transpose(img, (1, 2, 0))  # CHW to HWC

        img = cv2.cvtColor(img, cv2.COLOR_RGB2BGR)

        scale = self.render_scale
        img_big = cv2.resize(img, (self.width * scale, self.height * scale), interpolation=cv2.INTER_NEAREST)
        cv2.imshow("dmlab_examples", img_big)

        since_last_frame = time.time() - self.last_frame
        wait_time_sec = max(1.0 / self.render_fps - since_last_frame, 0.001)
        wait_time_ms = max(int(1000 * wait_time_sec), 1)
        cv2.waitKey(wait_time_ms)
        self.last_frame = time.time()

    def close(self):
        self.dmlab.close()

    def fetch(self, key, pk3_path):
        """Environment object itself acts as a proxy to the global level cache."""
        if not self.env_uses_level_cache:
            self.env_uses_level_cache = True
            # log.debug('Env %s uses level cache!', self.level_name)

        path = join(self.level_cache_path, key)

        if os.path.isfile(path):
            # copy the cached file to the path expected by DeepMind Lab
            shutil.copyfile(path, pk3_path)
            return True
        else:
            log.warning("Cache miss in environment %s key: %s!", self.level_name, key)
            return False

    def write(self, key, pk3_path):
        """Environment object itself acts as a proxy to the global level cache."""
        if self.use_level_cache:
            log.debug("Add new level to cache! Level %s seed %r key %s", self.level_name, self.last_reset_seed, key)
            self.curr_cache.add_new_level(self.level, self.last_reset_seed, key, pk3_path)
