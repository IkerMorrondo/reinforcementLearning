import numpy as np
import pygame

class GridworldEnv:
    """3x4 Russell & Norvig Gridworld with Gymnasium-style Pygame rendering."""

    def __init__(self, render_mode=None, is_slippery=False):
        self.n_rows = 3
        self.n_cols = 4
        self.n_states = self.n_rows * self.n_cols
        self.n_actions = 4

        self.start_state = 8  # Bottom-left
        self.wall_state = 5  # Center obstacle
        self.terminal_states = {3: +1.0, 7: -1.0}  # Goal (+1) and Pit (-1)
        self.step_cost = 0.0
        self.is_slippery = is_slippery

        self.P = self._build_P()
        self.s = self.start_state

        # Rendering attributes
        self.render_mode = render_mode
        self.window_size = (self.n_cols * 120, self.n_rows * 120)  # (Width, Height)
        self.window = None
        self.clock = None

    def _build_P(self):
        actions = {0: (0, -1), 1: (1, 0), 2: (0, 1), 3: (-1, 0)}
        slips = {0: (1, 3), 1: (0, 2), 2: (1, 3), 3: (0, 2)}

        def get_next_state(r, c, act_idx):
            dr, dc = actions[act_idx]
            nr, nc = r + dr, c + dc
            if (
                nr < 0
                or nr >= self.n_rows
                or nc < 0
                or nc >= self.n_cols
                or (nr == 1 and nc == 1)
            ):
                return r * self.n_cols + c
            return nr * self.n_cols + nc

        P = {s: {a: [] for a in range(self.n_actions)} for s in range(self.n_states)}

        for r in range(self.n_rows):
            for c in range(self.n_cols):
                s = r * self.n_cols + c
                if s == self.wall_state:
                    continue
                if s in self.terminal_states:
                    for a in range(self.n_actions):
                        P[s][a] = [(1.0, s, 0.0, True)]
                    continue

                for a in range(self.n_actions):
                    if self.is_slippery:
                        outcomes = [(a, 0.8), (slips[a][0], 0.1), (slips[a][1], 0.1)]
                    else:
                        outcomes = [(a, 1.0)]

                    trans_map = {}
                    for act_idx, prob in outcomes:
                        s_prime = get_next_state(r, c, act_idx)
                        done = s_prime in self.terminal_states
                        reward = (
                            self.terminal_states[s_prime] if done else self.step_cost
                        )
                        key = (s_prime, reward, done)
                        trans_map[key] = trans_map.get(key, 0.0) + prob

                    P[s][a] = [
                        (prob, s_prime, r_val, d_val)
                        for (s_prime, r_val, d_val), prob in trans_map.items()
                    ]
        return P

    def reset(self, seed=None):
        if seed is not None:
            np.random.seed(seed)
        self.s = self.start_state

        if self.render_mode == "human":
            self.render()

        return self.s, {}

    def step(self, action):
        transitions = self.P[self.s][action]
        probs = [t[0] for t in transitions]

        idx = np.random.choice(len(transitions), p=probs)
        _, next_state, reward, terminated = transitions[idx]

        self.s = next_state

        if self.render_mode == "human":
            self.render()

        return next_state, reward, terminated, False, {}

    def render(self):
        """Gymnasium-compliant render supporting 'ansi', 'human', and 'rgb_array'."""
        if self.render_mode == "ansi":
            return self._render_ansi()
        elif self.render_mode in ("human", "rgb_array"):
            return self._render_pygame()

    def _render_ansi(self):
        """Renders grid as ASCII characters in terminal."""
        out = ""
        for r in range(self.n_rows):
            row_str = ""
            for c in range(self.n_cols):
                s = r * self.n_cols + c
                if s == self.s:
                    row_str += " A "  # Agent
                elif s == self.wall_state:
                    row_str += " W "  # Wall
                elif s in self.terminal_states:
                    row_str += " G " if self.terminal_states[s] > 0 else " H "
                else:
                    row_str += " . "  # Empty cell
            out += row_str + "\n"
        return out

    def _render_pygame(self):
        """Renders grid using Pygame window matching FrozenLake aesthetics."""
        if self.window is None:
            pygame.init()
            if self.render_mode == "human":
                pygame.display.init()
                pygame.display.set_caption("Gridworld Environment")
                self.window = pygame.display.set_mode(self.window_size)
            else:  # rgb_array
                self.window = pygame.Surface(self.window_size)

        if self.clock is None:
            self.clock = pygame.time.Clock()

        cell_w = self.window_size[0] // self.n_cols
        cell_h = self.window_size[1] // self.n_rows

        # Clear Canvas
        self.window.fill((255, 255, 255))

        # Color Palette
        COLOR_BG = (220, 240, 255)  # Light Blue
        COLOR_WALL = (100, 100, 100)  # Dark Gray
        COLOR_GOAL = (144, 238, 144)  # Light Green
        COLOR_HOLE = (255, 160, 122)  # Light Red / Hole
        COLOR_AGENT = (220, 20, 60)  # Crimson Red

        # Draw Cells
        for r in range(self.n_rows):
            for c in range(self.n_cols):
                s = r * self.n_cols + c
                rect = pygame.Rect(c * cell_w, r * cell_h, cell_w, cell_h)

                if s == self.wall_state:
                    pygame.draw.rect(self.window, COLOR_WALL, rect)
                elif s in self.terminal_states:
                    color = (
                        COLOR_GOAL
                        if self.terminal_states[s] > 0
                        else COLOR_HOLE
                    )
                    pygame.draw.rect(self.window, color, rect)
                else:
                    pygame.draw.rect(self.window, COLOR_BG, rect)

                # Draw Grid Borders
                pygame.draw.rect(self.window, (0, 0, 0), rect, 2)

                # Draw Agent Circle
                if s == self.s:
                    center = (c * cell_w + cell_w // 2, r * cell_h + cell_h // 2)
                    pygame.draw.circle(
                        self.window, COLOR_AGENT, center, min(cell_w, cell_h) // 3
                    )

        if self.render_mode == "human":
            pygame.event.pump()
            pygame.display.flip()
            self.clock.tick(4)  # 4 FPS speed control
        elif self.render_mode == "rgb_array":
            return np.transpose(
                np.array(pygame.surfarray.pixels3d(self.window)), (1, 0, 2)
            )

    def close(self):
        """Closes Pygame rendering window."""
        if self.window is not None:
            pygame.quit()
            self.window = None  # Reset window handle

import time
import tools

if __name__ == "__main__":
    # 1. custom env with pygame render
    env = GridworldEnv(render_mode="human")
    obs, info = env.reset()

    done = False
    while not done:
        action = np.random.choice(env.n_actions)
        obs, reward, terminated, truncated, info = env.step(action)
        done = terminated or truncated

    time.sleep(1)
    env.close()
    tools.plot_environment(env)
    

    # # 2. custom env with ANSI render
    # env = GridworldEnv(render_mode="ansi")
    # obs, info = env.reset()
    #
    # done = False
    # while not done:
    #     print(env.render())
    #     time.sleep(0.2)
    #     action = np.random.choice(env.n_actions)
    #     obs, reward, terminated, truncated, info = env.step(action)
    #     done = terminated or truncated
    # tools.plot_environment(env)

    # # 3. gymnasium frozenlake with human render
    # import gymnasium as gym
    # env = gym.make("FrozenLake-v1", render_mode="human")
    #
    # obs, info = env.reset()
    # terminated = False
    # truncated = False
    # step_count = 0
    #
    # while not (terminated or truncated) and step_count < 10:
    #     action = env.action_space.sample()  # Take random Gymnasium action
    #     next_obs, reward, terminated, truncated, info = env.step(action)
    #     step_count += 1
    #
    # env.close()
    # tools.plot_environment(env)

    # # 4. gymnasium frozenlake with ANSI render
    # import gymnasium as gym
    # env = gym.make("FrozenLake-v1", render_mode="ansi")
    #
    # obs, info = env.reset()
    # terminated = False
    # truncated = False
    # step_count = 0
    #
    # while not (terminated or truncated) and step_count < 10:
    #     print(env.render())
    #     action = env.action_space.sample()  # Take random Gymnasium action
    #     next_obs, reward, terminated, truncated, info = env.step(action)
    #     env.render()
    #     step_count += 1
    #
    # env.close()
    # tools.plot_environment(env)
