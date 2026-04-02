"""
The MAPTD algorithm 
-- Build over the TDMPC architecture
"""

import numpy as np
import torch
import torch.nn as nn
from copy import deepcopy
import algorithm.helper as h
import dynamics_gym


class DRL(nn.Module):
    """ Deep Reinforcement Learning (DRL) Agent """
    def __init__(self, cfg):
        super().__init__()
        self.cfg = cfg

        self._dynamics = dynamics_gym.env[cfg.task_title]()      
        self._nndynamics = dynamics_gym.env[cfg.task_title+'NN'](cfg.lr, cfg.device)
        self._pi = h.mlp(cfg.obs_shape[0], cfg.mlp_dim, cfg.action_dim)
        
        self._Q1 = h.q(cfg.obs_shape[0]+cfg.action_dim, cfg.mlp_dim)
        self._Q2 = h.q(cfg.obs_shape[0]+cfg.action_dim, cfg.mlp_dim)
        
        self.apply(h.orthogonal_init)
        for m in [self._Q1, self._Q2]:
            m[-1].weight.data.fill_(0)
            m[-1].bias.data.fill_(0)

    def track_q_grad(self, enable=True):
        """Utility function. Enables/disables gradient tracking of Q-networks."""
        for m in [self._Q1, self._Q2]:
            h.set_requires_grad(m, enable)

    def next_p(self, z, t, a):
        """Predicts next state (d) and single-step reward (R)."""
        device = z.device
        
        if len(z) < 1: 
            z, r = self._dynamics.one_step(z.cpu().numpy()[0], t, a.cpu().numpy()[0])
            z, r = z[np.newaxis,:].astype('float32') , r[np.newaxis,:].astype('float32')
            return torch.from_numpy(z).to(device), torch.from_numpy(r).to(device)
        else:
            obs, reward = [], []
            z, a = z.cpu().numpy(), a.cpu().numpy()
            for samples, action in zip(z, a):
                zt, rt = self._dynamics.one_step(samples, t, action)
                obs.append(zt)
                reward.append(rt)
            obs, reward = np.stack(( obs )).astype('float32'), np.stack(( reward )).astype('float32')
            return torch.from_numpy(obs).to(device), torch.from_numpy(reward).to(device)
        
    def next_nn(self, z, t, a):
        """Predicts next state (s(t+1)) and single-step reward (r=R(S,a)) using a NN surrogate."""
        device = z.device
        
        z, r = self._nndynamics.one_step(z.cpu().numpy(), t, a.cpu().numpy())
        return torch.from_numpy(z).to(device), torch.from_numpy(r).to(device)
        
    def pi(self, z, std=0):
        """Samples an action from the learned policy (pi)."""
        mu = torch.tanh(self._pi(z))
        if std > 0:
            std = torch.ones_like(mu) * std
            return h.TruncatedNormal(mu, std).sample(clip=0.3)
        return mu

    def Q(self, z, a):
        """Predict state-action value (Q)."""
        x = torch.cat([z, a], dim=-1)
        return self._Q1(x), self._Q2(x)


class MAPTD_oml():
    """Implementation of MAP-TD learning."""
    def __init__(self, cfg):
        self.cfg = cfg
        self.device = torch.device('cuda:' + str(cfg.deviceid))
        self.std = h.linear_schedule(cfg.std_schedule, 0)
        self.model = DRL(cfg).to(self.device)
        self.model_target = deepcopy(self.model)
        self.optim = torch.optim.Adam(self.model.parameters(), lr=self.cfg.lr)
        self.pi_optim = torch.optim.Adam(self.model._pi.parameters(), lr=self.cfg.lr)
        self.model.eval()
        self.model_target.eval()

    def state_dict(self):
        """Retrieve state dict of MAP-TD model, including slow-moving target network."""
        return {'model': self.model.state_dict(),
                'model_target': self.model_target.state_dict()}

    def save(self, fp):
        """Save state dict of MAP-TD model to filepath."""
        torch.save(self.state_dict(), fp)
	
    def load(self, fp):
        """Load a saved state dict from filepath into current agent."""
        d = torch.load(fp, map_location=self.device)
        self.model.load_state_dict(d['model'])
        self.model_target.load_state_dict(d['model_target'])

    @torch.no_grad()
    def estimate_value(self, current_model, z, force_t, actions, horizon):
        """Estimate value of a trajectory starting at latent state z and executing given actions."""
        G, discount = 0, 1
        for t in range(horizon):
            z, reward = current_model(z, force_t, actions[t])
            G += discount * reward
            discount *= self.cfg.discount
        G += discount * torch.min(*self.model.Q(z, self.model.pi(z, self.cfg.min_std)))
        return G

    @torch.no_grad()
    def plan(self, obs, force_t, eval_mode=False, step=None, t0=True):
        """
        Plan next action using TD-MPC inference.
        obs: raw input observation.
        force_t = time step for sinusoidal forcing function
        eval_mode: uniform sampling and action noise is disabled during evaluation.
		step: current time step. determines e.g. planning horizon.
		t0: whether current step is the first step of an episode.
		"""       
		# Seed steps
        if step < self.cfg.seed_steps and not eval_mode:
            return torch.empty(self.cfg.action_dim, dtype=torch.float32, device=self.device).uniform_(-1, 1)

		# Sample policy trajectories
        obs = torch.tensor(obs, dtype=torch.float32, device=self.device).unsqueeze(0)
        horizon = int(min(self.cfg.horizon, h.linear_schedule(self.cfg.horizon_schedule, step)))
        num_pi_trajs = int(self.cfg.mixture_coef * self.cfg.num_samples)
        current_model = self.model.next_p if step // self.cfg.episode_length % 2 == 0 else self.model.next_nn
        
        if num_pi_trajs > 0:
            pi_actions = torch.empty(horizon, num_pi_trajs, self.cfg.action_dim, device=self.device)
            z = obs.repeat(num_pi_trajs, 1)
            for t in range(horizon):
                pi_actions[t] = self.model.pi(z, self.cfg.min_std)
                z, _ = current_model(z, force_t, pi_actions[t])

        # Initialize state and parameters
        z = obs.repeat(self.cfg.num_samples+num_pi_trajs, 1)
        mean = torch.zeros(horizon, self.cfg.action_dim, device=self.device)
        std = 2*torch.ones(horizon, self.cfg.action_dim, device=self.device)
        if not t0 and hasattr(self, '_prev_mean'):
            mean[:-1] = self._prev_mean[1:]

        # Iterate CEM
        for i in range(self.cfg.iterations):
            actions = torch.clamp(mean.unsqueeze(1) + std.unsqueeze(1) * \
                      torch.randn(horizon, self.cfg.num_samples, self.cfg.action_dim, device=std.device), -1, 1)
            if num_pi_trajs > 0:
                actions = torch.cat([actions, pi_actions], dim=1)

			# Compute elite actions
            value = self.estimate_value(current_model, z, force_t, actions, horizon).nan_to_num_(0)
            elite_idxs = torch.topk(value.squeeze(1), self.cfg.num_elites, dim=0).indices
            elite_value, elite_actions = value[elite_idxs], actions[:, elite_idxs]

			# Update parameters
            max_value = elite_value.max(0)[0]
            score = torch.exp(self.cfg.temperature*(elite_value - max_value))
            score /= score.sum(0)
            _mean = torch.sum(score.unsqueeze(0) * elite_actions, dim=1) / (score.sum(0) + 1e-9)
            _std = torch.sqrt(torch.sum(score.unsqueeze(0) * (elite_actions - _mean.unsqueeze(1)) ** 2, dim=1) / (score.sum(0) + 1e-9))
            _std = _std.clamp_(self.std, 2)
            mean, std = self.cfg.momentum * mean + (1 - self.cfg.momentum) * _mean, _std

        # Outputs
        score = score.squeeze(1).cpu().numpy()
        actions = elite_actions[:, np.random.choice(np.arange(score.shape[0]), p=score)]
        self._prev_mean = mean
        mean, std = actions[0], _std[0]
        a = mean
        if not eval_mode:
            a += std * torch.randn(self.cfg.action_dim, device=std.device)
        return a

    def update_pi(self, zs):
        """Update policy."""
        self.pi_optim.zero_grad(set_to_none=True)
        self.model.track_q_grad(False)
    
   		# Loss is a weighted sum of Q-values
        pi_loss = 0
        for t,z in enumerate(zs):
            a = self.model.pi(z, self.cfg.min_std)
            Q = torch.min(*self.model.Q(z, a))
            pi_loss += -Q.mean() * (self.cfg.rho ** t)
   
        pi_loss.backward()
        torch.nn.utils.clip_grad_norm_(self.model._pi.parameters(), self.cfg.grad_clip_norm, error_if_nonfinite=False)
        self.pi_optim.step()
        self.model.track_q_grad(True)
        return pi_loss.item()

    @torch.no_grad()
    def _td_target(self, next_obs, reward):
    	"""Compute the TD-target from a reward and the observation at the following time step."""
    	next_z = next_obs
    	td_target = reward + self.cfg.discount * \
    		torch.min(*self.model_target.Q(next_z, self.model.pi(next_z, self.cfg.min_std)))
    	return td_target

    def update(self, replay_buffer, step, force_t):
        """Main update function. """
        obs, next_obses, action, reward, idxs, weights = replay_buffer.sample()
        
        # Update the surrogate model
        self.model._nndynamics.update(obs, next_obses[1], force_t, action[1])
        
        # Update the DRL agents
        self.optim.zero_grad(set_to_none=True)
        self.std = h.linear_schedule(self.cfg.std_schedule, step)
        self.model.train()

        z = obs
        zs = [z.detach()]
        value_loss, priority_loss = 0, 0
        for t in range(self.cfg.horizon):

            # Predictions
            Q1, Q2 = self.model.Q(z, action[t])
            with torch.no_grad():
                next_obs = next_obses[t]
                td_target = self._td_target(next_obs, reward[t])
            zs.append(z.detach())

			# Losses
            rho = (self.cfg.rho ** t)
            value_loss += rho * (h.mse(Q1, td_target) + h.mse(Q2, td_target))
            priority_loss += rho * (h.l1(Q1, td_target) + h.l1(Q2, td_target))
        
		# Optimize model
        total_loss = value_loss.clamp(max=1e4)
        weighted_loss = (total_loss.squeeze(1) * weights).mean()
        weighted_loss.register_hook(lambda grad: grad * (1/self.cfg.horizon))
        weighted_loss.backward()
        grad_norm = torch.nn.utils.clip_grad_norm_(self.model.parameters(), self.cfg.grad_clip_norm, error_if_nonfinite=False)
        self.optim.step()
        replay_buffer.update_priorities(idxs, priority_loss.clamp(max=1e4).detach())

		# Update policy + target network
        pi_loss = self.update_pi(zs)
        if step % self.cfg.update_freq == 0:
            h.ema(self.model, self.model_target, self.cfg.tau)

        self.model.eval()
        return {'value_loss': float(value_loss.mean().item()),
				'pi_loss': pi_loss,
				'total_loss': float(total_loss.mean().item()),
				'weighted_loss': float(weighted_loss.mean().item()),
				'grad_norm': float(grad_norm)}
