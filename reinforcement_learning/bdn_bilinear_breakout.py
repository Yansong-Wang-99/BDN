# docs and experiment results can be found at https://docs.cleanrl.dev/rl-algorithms/ppo/#ppo_ataripy
import os
import random
import time
from dataclasses import dataclass

import gymnasium as gym
import numpy as np
import torch
import torch.nn as nn
import torch.optim as optim
import tyro
from torch.distributions.categorical import Categorical
from torch.utils.tensorboard import SummaryWriter
from bdn_bilinear import BDN
from gymnasium.spaces import Discrete
from cleanrl_utils.atari_wrappers import (  # isort:skip
    ClipRewardEnv,
    EpisodicLifeEnv,
    FireResetEnv,
    MaxAndSkipEnv,
    NoopResetEnv,
)
import csv
import os
from collections import deque

torch.backends.cudnn.benchmark = True
torch.backends.cuda.matmul.allow_tf32 = True
torch.backends.cudnn.allow_tf32 = True
torch.set_float32_matmul_precision('high')

# bdn_v8a_multiframe_mspacman.py:1945956
@dataclass
class Args:
    exp_name: str = os.path.basename(__file__)[: -len(".py")]
    """the name of this experiment"""
    seed: int = 104
    """seed of the experiment"""
    torch_deterministic: bool = True
    """if toggled, `torch.backends.cudnn.deterdministic=False`"""
    cuda: bool = True
    """if toggled, cuda will be enabled by default"""
    track: bool = False
    """if toggled, this experiment will be tracked with Weights and Biases"""
    wandb_project_name: str = "cleanRL"
    """the wandb's project name"""
    wandb_entity: str = None
    """the entity (team) of wandb's project"""
    capture_video: bool = False
    """whether to capture videos of the agent performances (check out `videos` folder)"""

    # Algorithm specific arguments
    # env_id: str = "BreakoutNoFrameskip-v4"
    env_id: str = "BreakoutNoFrameskip-v4"
    """the id of the environment"""
    total_timesteps: int = int(1e7)
    """total timesteps of the experiments"""
    learning_rate: float = 2.5e-4
    """the learning rate of the optimizer"""
    num_envs: int = 128
    """the number of parallel game environments"""
    num_steps: int = 375
    """the number of steps to run in each environment per policy rollout"""
    anneal_lr: bool = True
    """Toggle learning rate annealing for policy and value networks"""
    gamma: float = 0.99
    """the discount factor gamma"""
    gae_lambda: float = 0.95
    """the lambda for the general advantage estimation"""
    num_minibatches: int = 375
    """the number of mini-batches"""
    update_epochs: int = 4
    """the K epochs to update the policy"""
    norm_adv: bool = True
    """Toggles advantages normalization"""
    clip_coef: float = 0.1
    """the surrogate clipping coefficient"""
    clip_vloss: bool = True
    """Toggles whether or not to use a clipped loss for the value function, as per the paper."""
    ent_coef: float = 0.01
    """coefficient of the entropy"""
    vf_coef: float = 0.5
    """coefficient of the value function"""
    max_grad_norm: float = 0.5
    """the maximum norm for the gradient clipping"""
    target_kl: float = None
    """the target KL divergence threshold"""

    # to be filled in runtime
    batch_size: int = 0
    """the batch size (computed in runtime)"""
    minibatch_size: int = 0
    """the mini-batch size (computed in runtime)"""
    num_iterations: int = 0
    """the number of iterations (computed in runtime)"""

    save_interval: int = 100
    """the frequency at which to save the model"""


def make_env(env_id, idx, capture_video, run_name):
    def thunk():
        if capture_video and idx == 0:
            env = gym.make(env_id, obs_type="grayscale")
            env = gym.wrappers.RecordVideo(env, f"videos/{run_name}")
        else:
            env = gym.make(env_id, obs_type="grayscale")
        env = gym.wrappers.RecordEpisodeStatistics(env)
        env = NoopResetEnv(env, noop_max=30)
        env = MaxAndSkipEnv(env, skip=4)
        env = EpisodicLifeEnv(env)
        if "FIRE" in env.unwrapped.get_action_meanings():
            env = FireResetEnv(env)
        env = ClipRewardEnv(env)
        env = gym.wrappers.ResizeObservation(env, (84, 84))
        env = gym.wrappers.FrameStack(env, 4)

        # env = ActionDiscretizer(env)

        return env
    return thunk

def evaluate(agent, device, args, writer, global_step, best_reward, num_eval_episodes=10):
    agent.eval()
    eval_env = gym.make(args.env_id, obs_type="grayscale", render_mode=None)
    eval_env = gym.wrappers.RecordEpisodeStatistics(eval_env)
    eval_env = NoopResetEnv(eval_env, noop_max=30)
    eval_env = MaxAndSkipEnv(eval_env, skip=4)
    eval_env = EpisodicLifeEnv(eval_env)
    if "FIRE" in eval_env.unwrapped.get_action_meanings():
        eval_env = FireResetEnv(eval_env)
    eval_env = ClipRewardEnv(eval_env)
    eval_env = gym.wrappers.ResizeObservation(eval_env, (84, 84))
    eval_env = gym.wrappers.FrameStack(eval_env, 4)


    returns = []
    for ep in range(num_eval_episodes):
        obs, _ = eval_env.reset(seed=args.seed + 100 + ep)
        obs = torch.from_numpy(np.array(obs)).to(device).unsqueeze(0)
        done = False
        total_reward = 0
        while not done:
            with torch.no_grad():
                action, _, _, _ = agent.get_action_and_value(obs, deterministic=True)
            obs, reward, terminated, truncated, _ = eval_env.step(action.item())
            done = terminated or truncated
            obs = torch.from_numpy(np.array(obs)).to(device).unsqueeze(0)
            total_reward += reward
        returns.append(total_reward)

    eval_env.close()

    avg_return = np.mean(returns)
    writer.add_scalar("charts/eval_return", avg_return, global_step)
    print("avg_return:",avg_return)
    if avg_return > best_reward:
        best_reward = avg_return
        checkpoint = {
            'iteration': iteration,
            'global_step': global_step,
            'model_state_dict': agent.state_dict(),
            'optimizer_state_dict': optimizer.state_dict(),
            'best_reward': best_reward,
            'args': vars(args),
            'seed': args.seed,
        }
        torch.save(checkpoint, f"{save_dir}/{run_name}_best.pt")
        # torch.save(agent.state_dict(), f"{save_dir}/{run_name}_best.pt")
        print(f"New best model saved with avg reward {best_reward:.2f}")
    # --- 保存 avg_return 到 CSV ---
    csv_path = os.path.join(save_dir, f"{run_name}_{args.seed}.csv")
    file_exists = os.path.exists(csv_path)

    with open(csv_path, mode='a', newline='') as f:
        writer = csv.writer(f)
        if not file_exists:
            writer.writerow(["global_step", "iteration", "avg_return"])  # 写表头
        writer.writerow([global_step, iteration, avg_return])
    agent.train()
    return best_reward


def layer_init(layer, std=np.sqrt(2), bias_const=0.0):
    torch.nn.init.orthogonal_(layer.weight, std)
    torch.nn.init.constant_(layer.bias, bias_const)
    return layer

class Agent(nn.Module):
    def __init__(self, envs):
        super().__init__()
        self.network = nn.Sequential(
            layer_init(nn.Conv2d(4, 32, 8, stride=4)),
            nn.ReLU(),
            layer_init(nn.Conv2d(32, 64, 4, stride=2)),
            nn.ReLU(),
            layer_init(nn.Conv2d(64, 64, 3, stride=1)),
            nn.ReLU(),
            nn.Flatten(),
            layer_init(nn.Linear(64 * 7 * 7, 512)),
            nn.ReLU(),
        )
        # self.K = 4
        self.T = 5  # 时间步数，可以根据你的需求设置
        # self.actor = layer_init(nn.Linear(512, envs.single_action_space.n), std=0.01)

        # 可选 feature 投影层
        self.feature_proj = nn.Sequential(
            layer_init(nn.Linear(512, 256)),  # 用正交初始化
            nn.ReLU(),
        )

        # 定义 BDN
        self.actor_bdn = BDN(hidden_size=[64, 32],
                             in_dim=256,
                             project_dim=256,
                             out_dim=32)

        self.batch_size = envs.num_envs
        # BDN 输出后接 head
        self.actor_head = layer_init(
            nn.Linear(32, envs.single_action_space.n), std=0.01
        )

        self.critic = nn.Sequential(
            layer_init(nn.Linear(512, 256)),
            nn.ReLU(),
            layer_init(nn.Linear(256, 1), std=1),
        )

    def get_value(self, x):

        return self.critic(self.network(x / 255.0))

    def get_action_and_value(self, x, action=None, deterministic=False):

        hidden = self.network(x / 255.0)
        B = hidden.shape[0]
        self.actor_bdn.reset_net(B)
        if B != self.batch_size:
            repeat_factor = (self.batch_size + B - 1) // B
            hidden = hidden.repeat(repeat_factor, 1)[:self.batch_size]

        x_feature_proj = self.feature_proj(hidden)
        x_seq = x_feature_proj.unsqueeze(1).repeat(1, self.T, 1)
        y_top = self.actor_bdn(x_seq)

        logits = self.actor_head(y_top)
        probs = Categorical(logits=logits)

        if action is None:
            if deterministic:
                action = torch.argmax(probs.probs, dim=-1)
            else:
                action = probs.sample()

        return action[:B], probs.log_prob(action)[:B], probs.entropy()[:B], self.critic(hidden)[:B]


def count_trainable_params(model):
    return sum(p.numel() for p in model.parameters() if p.requires_grad)


if __name__ == "__main__":
    print(f'{Args.seed}')
    args = tyro.cli(Args)
    args.batch_size = int(args.num_envs * args.num_steps)
    args.minibatch_size = int(args.batch_size // args.num_minibatches)
    args.num_iterations = args.total_timesteps // args.batch_size
    run_name = f"{args.env_id}__{args.exp_name}__{args.seed}__{int(time.time())}"
    if args.track:
        import wandb

        wandb.init(
            project=args.wandb_project_name,
            entity=args.wandb_entity,
            sync_tensorboard=True,
            config=vars(args),
            name=run_name,
            monitor_gym=True,
            save_code=True,
        )
    writer = SummaryWriter(f"runs/{run_name}")
    writer.add_text(
        "hyperparameters",
        "|param|value|\n|-|-|\n%s" % ("\n".join([f"|{key}|{value}|" for key, value in vars(args).items()])),
    )
    save_dir = f"runs/{run_name}"
    os.makedirs(save_dir, exist_ok=True)

    # TRY NOT TO MODIFY: seeding
    random.seed(args.seed)
    np.random.seed(args.seed)
    torch.manual_seed(args.seed)
    torch.backends.cudnn.deterministic = args.torch_deterministic

    device = torch.device("cuda:0" if torch.cuda.is_available() and args.cuda else "cpu")

    # env setup
    envs = gym.vector.AsyncVectorEnv(
        [make_env(args.env_id, i, args.capture_video, run_name) for i in range(args.num_envs)],
    )
    assert isinstance(envs.single_action_space, gym.spaces.Discrete), "only discrete action space is supported"

    agent = Agent(envs).to(device)
    params = count_trainable_params(agent.actor_bdn)
    print(f"Total trainable parameters: {params}")

    compiled_agent = torch.compile(agent)  # 用这个训练
    optimizer = optim.Adam(agent.parameters(), lr=args.learning_rate, eps=1e-5)

    s_o = np.array(envs.single_observation_space.shape).prod()
    # ALGO Logic: Storage setup
    obs = torch.zeros((args.num_steps, args.num_envs) + envs.single_observation_space.shape).to(device)
    actions = torch.zeros((args.num_steps, args.num_envs) + envs.single_action_space.shape).to(device)
    logprobs = torch.zeros((args.num_steps, args.num_envs)).to(device)
    rewards = torch.zeros((args.num_steps, args.num_envs)).to(device)
    dones = torch.zeros((args.num_steps, args.num_envs)).to(device)
    values = torch.zeros((args.num_steps, args.num_envs)).to(device)
    best_reward = -float("inf")
    # TRY NOT TO MODIFY: start the game
    global_step = 0
    start_time = time.time()
    next_obs, _ = envs.reset(seed=args.seed)
    next_obs = torch.Tensor(next_obs).to(device)
    next_done = torch.zeros(args.num_envs).to(device)

    for iteration in range(1, args.num_iterations + 1):
        agent.actor_bdn.reset_net(args.batch_size)
        # Annealing the rate if instructed to do so.
        if args.anneal_lr:
            frac = 1.0 - (iteration - 1.0) / args.num_iterations
            lrnow = frac * args.learning_rate
            optimizer.param_groups[0]["lr"] = lrnow

        for step in range(0, args.num_steps):
            global_step += args.num_envs
            obs[step] = next_obs
            dones[step] = next_done

            # ALGO LOGIC: action logic
            with torch.no_grad():
                action, logprob, _, value = compiled_agent.get_action_and_value(next_obs)
                values[step] = value.flatten()
            actions[step] = action
            logprobs[step] = logprob

            # TRY NOT TO MODIFY: execute the game and log data.
            next_obs, reward, terminations, truncations, infos = envs.step(action.cpu().numpy())
            next_done = np.logical_or(terminations, truncations)
            rewards[step] = torch.tensor(reward).to(device).view(-1)
            next_obs, next_done = torch.Tensor(next_obs).to(device), torch.Tensor(next_done).to(device)

            if "final_info" in infos:
                for info in infos["final_info"]:
                    if info and "episode" in info:
                        # 只在第一次遇到这个global_step时输出
                        if not hasattr(make_env, 'last_global_step') or make_env.last_global_step != global_step:
                            print(f"global_step={global_step}, episodic_return={info['episode']['r']}")
                            make_env.last_global_step = global_step
                        writer.add_scalar("charts/episodic_return", info['episode']['r'], global_step)
                        writer.add_scalar("charts/episodic_length", info['episode']['l'], global_step)
        # bootstrap value if not done
        with torch.no_grad():
            next_value = agent.get_value(next_obs).reshape(1, -1)
            advantages = torch.zeros_like(rewards).to(device)
            lastgaelam = 0
            for t in reversed(range(args.num_steps)):
                if t == args.num_steps - 1:
                    nextnonterminal = 1.0 - next_done
                    nextvalues = next_value
                else:
                    nextnonterminal = 1.0 - dones[t + 1]
                    nextvalues = values[t + 1]
                delta = rewards[t] + args.gamma * nextvalues * nextnonterminal - values[t]
                advantages[t] = lastgaelam = delta + args.gamma * args.gae_lambda * nextnonterminal * lastgaelam
            returns = advantages + values

        # flatten the batch
        b_obs = obs.reshape((-1,) + envs.single_observation_space.shape)
        b_logprobs = logprobs.reshape(-1)
        b_actions = actions.reshape((-1,) + envs.single_action_space.shape)
        b_advantages = advantages.reshape(-1)
        b_returns = returns.reshape(-1)
        b_values = values.reshape(-1)

        # Optimizing the policy and value network
        b_inds = np.arange(args.batch_size)
        clipfracs = []
        for epoch in range(args.update_epochs):
            np.random.shuffle(b_inds)
            for start in range(0, args.batch_size, args.minibatch_size):
                end = start + args.minibatch_size
                mb_inds = b_inds[start:end]

                _, newlogprob, entropy, newvalue = compiled_agent.get_action_and_value(b_obs[mb_inds], b_actions.long()[mb_inds])
                logratio = newlogprob - b_logprobs[mb_inds]
                ratio = logratio.exp()

                with torch.no_grad():
                    # calculate approx_kl http://joschu.net/blog/kl-approx.html
                    old_approx_kl = (-logratio).mean()
                    approx_kl = ((ratio - 1) - logratio).mean()
                    clipfracs += [((ratio - 1.0).abs() > args.clip_coef).float().mean().item()]

                mb_advantages = b_advantages[mb_inds]
                if args.norm_adv:
                    mb_advantages = (mb_advantages - mb_advantages.mean()) / (mb_advantages.std() + 1e-8)

                # Policy loss
                pg_loss1 = -mb_advantages * ratio
                pg_loss2 = -mb_advantages * torch.clamp(ratio, 1 - args.clip_coef, 1 + args.clip_coef)
                pg_loss = torch.max(pg_loss1, pg_loss2).mean()

                # Value loss
                newvalue = newvalue.view(-1)
                if args.clip_vloss:
                    v_loss_unclipped = (newvalue - b_returns[mb_inds]) ** 2
                    v_clipped = b_values[mb_inds] + torch.clamp(
                        newvalue - b_values[mb_inds],
                        -args.clip_coef,
                        args.clip_coef,
                    )
                    v_loss_clipped = (v_clipped - b_returns[mb_inds]) ** 2
                    v_loss_max = torch.max(v_loss_unclipped, v_loss_clipped)
                    v_loss = 0.5 * v_loss_max.mean()
                else:
                    v_loss = 0.5 * ((newvalue - b_returns[mb_inds]) ** 2).mean()

                entropy_loss = entropy.mean()
                loss = pg_loss - args.ent_coef * entropy_loss + v_loss * args.vf_coef

                optimizer.zero_grad()
                loss.backward()
                nn.utils.clip_grad_norm_(agent.parameters(), args.max_grad_norm)
                optimizer.step()

            if args.target_kl is not None and approx_kl > args.target_kl:
                break

        y_pred, y_true = b_values.cpu().numpy(), b_returns.cpu().numpy()
        var_y = np.var(y_true)
        explained_var = np.nan if var_y == 0 else 1 - np.var(y_true - y_pred) / var_y

        # --- 保存模型参数，每20次迭代保存一次 ---
        if iteration % 20 == 0:
            checkpoint = {
                'iteration': iteration,
                'global_step': global_step,
                'model_state_dict': agent.state_dict(),  # 用原始模型
                'optimizer_state_dict': optimizer.state_dict(),
                'best_reward': best_reward,
                'args': vars(args),
                'seed': args.seed,
            }
            torch.save(checkpoint, f"{save_dir}/{run_name}_iter{iteration}.pt")

        # torch.save(agent.state_dict(), f"{save_dir}/{run_name}_iter{iteration}.pt")

        # TRY NOT TO MODIFY: record rewards for plotting purposes
        writer.add_scalar("charts/learning_rate", optimizer.param_groups[0]["lr"], global_step)
        writer.add_scalar("losses/value_loss", v_loss.item(), global_step)
        writer.add_scalar("losses/policy_loss", pg_loss.item(), global_step)
        writer.add_scalar("losses/entropy", entropy_loss.item(), global_step)
        writer.add_scalar("losses/old_approx_kl", old_approx_kl.item(), global_step)
        writer.add_scalar("losses/approx_kl", approx_kl.item(), global_step)
        writer.add_scalar("losses/clipfrac", np.mean(clipfracs), global_step)
        writer.add_scalar("losses/explained_variance", explained_var, global_step)
        print("SPS:", int(global_step / (time.time() - start_time)))
        writer.add_scalar("charts/SPS", int(global_step / (time.time() - start_time)), global_step)
        # --- 在这里增加 evaluate ---
        if iteration % 1 == 0:  # 每次迭代都评估，可以改成每N次
            best_reward = evaluate(compiled_agent, device, args, writer, global_step, best_reward)

    checkpoint = {
        'iteration': iteration,
        'global_step': global_step,
        'model_state_dict': agent.state_dict(),
        'optimizer_state_dict': optimizer.state_dict(),
        'best_reward': best_reward,
        'args': vars(args),
        'seed': args.seed,
    }
    torch.save(checkpoint, f"{save_dir}/{run_name}_final.pt")
    # torch.save(agent.state_dict(), f"{save_dir}/{run_name}_final.pt")
    print( f"{save_dir}/{run_name}_final model saved.")
    envs.close()
    writer.close()

