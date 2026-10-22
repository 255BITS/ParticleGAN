"""Full public DDGAN transition games and ancestral-chain research toys.

The target is a known diagonal Gaussian mixture. Analytic posteriors are used
only for evaluation and scorer controls: training sees forward-process pairs.
The helpers and fixture hooks are shared by the separate AE-DDGAN composition.
"""
from __future__ import annotations

from copy import deepcopy
import hashlib
import json
import math
from pathlib import Path

import torch
from torch import nn

from particlegan import DDGAN, MoGParticlePrior, Recipe, UpdatePolicy, get_recipe, init
from particlegan.optim.constraint_geometry import constraint_geometry_backward
from experiments.forge.rng import NamedStreams
from .reproducibility import DEFAULT_SEED, construction_rng

VERSION = "api-model-ddgan-v1"
BASELINE = "bispf-optimized-quintic-v1"
ALPHA_BAR = (1., .9, .5, .05, .0001)
RESOURCES = dict(num_particles=128, z_dim=4, batch_size=64)
ROOT = Path(__file__).resolve().parents[2]
BOUNDS = {"projection_cdf_max": .12, "normalized_mean_max": .25,
          "covariance_eigen_min": .65, "covariance_eigen_max": 1.4}
_CASES = [dict(id="api-model-ddgan-" + kind + "-chain", legacy_ids=["denoising-toy-full-chain"],
    title="DDGAN " + kind + " transitions and four-step chain",
    goal="Learn conditional reverse transitions and the final ancestral distribution through the public DDGAN API",
    kind="ddgan_chain", default_steps=steps, batch_size=64, eval_samples=2048,
    default_recipe=BASELINE, evaluation_observations=24, terminal_observations=5,
    thresholds={"conditional_and_final": deepcopy(BOUNDS), **({"final_hq_min": .95,
        "final_mode_mass_tv_max": .10, "local_mean_sigma_max": .5,
        "local_covariance_eigenvalues": [.5, 1.5]} if kind == "bimodal" else {})},
    sampling="Public DDGAN [1,.9,.5,.05,.0001]; N(0,I) terminal start; fresh independent learned-MoG latent/kernel noise and Gaussian reverse noise at EVERY step; eight heldout time/observation transition panels",
    scope="New small analytic " + kind + " target, 2x32 MLPs and clean live serving. Actual forward-pair transition training and four-step reverse sampling; no historical 100-Gaussian or direct-posterior qualification.",
    target=kind, tier=tier) for kind, steps, tier in (("gaussian", 2500, 1), ("bimodal", 5000, 2))]
CASES = {case["id"]: case for case in _CASES}
for _case in _CASES:
    _limits = [("projection_cdf", "<=", .12), ("normalized_mean", "<=", .25),
        ("covariance_eigen_min", ">=", .65), ("covariance_eigen_max", "<=", 1.4)]
    _prefixes = ["final_"] + [f"t{t}_q{i}_" for t in range(1, 5) for i in range(2)]
    _case["forge_thresholds"] = [[prefix + name, op, bound]
        for prefix in _prefixes for name, op, bound in _limits]
    _case["forge_thresholds"] += [["panel_count", "==", 8], ["samples_per_panel", ">=", 2048]]
    if _case["target"] == "bimodal":
        _case["forge_thresholds"] += [["final_hq", ">=", .95], ["final_mode_mass_tv", "<=", .10],
            ["final_local_mean_sigma", "<=", .5], ["final_local_covariance_min", ">=", .5],
            ["final_local_covariance_max", "<=", 1.5]]


def list_cases():
    return deepcopy(_CASES)


class MixtureTarget:
    """Exact diagonal-mixture target and conditional reverse-transition law."""
    def __init__(self, kind="gaussian"):
        if kind == "gaussian":
            self.means = torch.tensor([[.6, -.35]])
            self.variances = torch.tensor([[.45 ** 2, .30 ** 2]])
        elif kind == "bimodal":
            self.means = torch.tensor([[-.75, 0.], [.75, 0.]])
            self.variances = torch.full((2, 2), .18 ** 2)
        else:
            raise ValueError("unknown analytic DDGAN target")
        self.kind = kind
        self.weights = torch.full((len(self.means),), 1 / len(self.means))

    @staticmethod
    def draw(weights, means, variances, n, generator):
        ids = torch.multinomial(weights, n, replacement=True, generator=generator)
        return means[ids] + variances[ids].sqrt() * torch.randn(n, 2, generator=generator,
            device=means.device, dtype=means.dtype)

    def sample(self, n, generator):
        return self.draw(self.weights, self.means, self.variances, n, generator)

    def posterior_parameters(self, xt, alpha_bar):
        """Return [B,K] weights and [B,K,2] clean Gaussian moments."""
        means, var, weights = (value.to(xt) for value in (self.means, self.variances, self.weights))
        a = float(alpha_bar)
        marginal_var = a * var + 1 - a
        logits = weights.log()[None] - .5 * (marginal_var.log()[None]
            + (xt[:, None] - math.sqrt(a) * means[None]).square() / marginal_var[None]).sum(-1)
        posterior_var = (1 / var + a / (1 - a)).reciprocal()
        posterior_mean = posterior_var[None] * (means[None] / var[None]
            + math.sqrt(a) * xt[:, None] / (1 - a))
        return logits.softmax(-1), posterior_mean, posterior_var.expand_as(posterior_mean)

    def oracle_clean(self, xt, alpha_bar, generator):
        weights, means, var = self.posterior_parameters(xt, alpha_bar)
        ids = torch.multinomial(weights, 1, generator=generator).squeeze(1)
        rows = torch.arange(len(xt), device=xt.device)
        return means[rows, ids] + var[rows, ids].sqrt() * torch.randn(xt.shape,
            generator=generator, device=xt.device, dtype=xt.dtype)

    def transition_parameters(self, xy, step, schedule):
        xt = self.means.new_tensor(xy).reshape(1, 2)
        weights, means, var = self.posterior_parameters(xt, schedule.ab[step])
        A, B, noise = (float(value[step]) for value in (schedule.A, schedule.B, schedule.posterior_var))
        return weights[0], A * means[0] + B * xt, A * A * var[0] + noise


class ChainGenerator(nn.Module):
    def __init__(self, z_dim=4, width=32, steps=4):
        super().__init__()
        self.steps = steps
        self.net = nn.Sequential(nn.Linear(2 + z_dim + 1, width), nn.LeakyReLU(.2),
            nn.Linear(width, width), nn.LeakyReLU(.2), nn.Linear(width, 2))

    def forward(self, xt, z, t):
        return self.net(torch.cat((xt, z, t[:, None].to(xt) / self.steps), 1))


class ChainCritic(nn.Module):
    def __init__(self, width=32, steps=4):
        super().__init__()
        self.steps = steps
        self.net = nn.Sequential(nn.Linear(5, width), nn.LeakyReLU(.2),
            nn.Linear(width, width), nn.LeakyReLU(.2), nn.Linear(width, 1))

    def forward(self, x, *, xt, t):
        return self.net(torch.cat((x, xt, t[:, None].to(x) / self.steps), 1)).squeeze(-1)


def sample_transition(generator, prior, schedule, xt, t, *, latent_rng, kernel_rng, reverse_rng,
                      support_observer=None):
    z, indices = prior.sample(len(xt), generator=latent_rng, noise_generator=kernel_rng)
    if support_observer is not None:
        support_observer(z)
    clean = generator(xt, z, t)
    eta = torch.randn(xt.shape, generator=reverse_rng, device=xt.device, dtype=xt.dtype)
    return schedule.reverse(clean, xt, t, eta), indices


def sample_chain(generator, prior, schedule, n, *, start_rng, latent_rng, kernel_rng,
                 reverse_rng, device="cpu", return_states=False):
    """Each loop iteration independently redraws latent IDs, jitter and eta."""
    xt = torch.randn(n, 2, generator=start_rng, device=device)
    states = [xt.clone()]
    for step in range(schedule.steps, 0, -1):
        t = torch.full((n,), step, device=device, dtype=torch.long)
        xt, _ = sample_transition(generator, prior, schedule, xt, t,
            latent_rng=latent_rng, kernel_rng=kernel_rng, reverse_rng=reverse_rng)
        states.append(xt.clone())
    return (xt, states) if return_states else xt


def distribution_metrics(points, weights, means, variances):
    """Analytic projection CDF plus exact mean/covariance normalization."""
    points, weights, means, variances = (value.detach().cpu().double()
        for value in (points, weights, means, variances))
    if not torch.isfinite(points).all():
        return dict(projection_cdf=math.inf, normalized_mean=math.inf,
                    covariance_eigen_min=-math.inf, covariance_eigen_max=math.inf)
    mean = (weights[:, None] * means).sum(0)
    covariance = torch.diag((weights[:, None] * variances).sum(0))
    centered = means - mean
    covariance += (weights[:, None] * centered).T @ centered
    eigenvalues, vectors = torch.linalg.eigh(covariance)
    whitening = vectors @ torch.diag(eigenvalues.rsqrt()) @ vectors.T
    normalized = (points - mean) @ whitening
    observed_cov = torch.cov(normalized.T, correction=0)
    observed_eigs = torch.linalg.eigvalsh(observed_cov)
    worst = 0.
    ranks = torch.arange(len(points), dtype=torch.float64) / len(points)
    for angle in torch.arange(8, dtype=torch.float64) * math.pi / 8:
        direction = torch.stack((angle.cos(), angle.sin()))
        projected = (points @ direction).sort().values
        projected_mean = means @ direction
        projected_var = variances @ direction.square()
        cdf = (.5 * (1 + torch.erf((projected[:, None] - projected_mean)
            / (2 * projected_var).sqrt())) * weights).sum(1)
        worst = max(worst, float((cdf - ranks).abs().max()),
                    float((cdf - ranks - 1 / len(points)).abs().max()))
    return dict(projection_cdf=worst, normalized_mean=float(normalized.mean(0).norm()),
        covariance_eigen_min=float(observed_eigs.min()), covariance_eigen_max=float(observed_eigs.max()))


def distribution_failures(metrics, prefix=""):
    limits = (("projection_cdf", None, .12), ("normalized_mean", None, .25),
              ("covariance_eigen_min", .65, None), ("covariance_eigen_max", None, 1.4))
    return [prefix + name for name, low, high in limits
        if not math.isfinite(metrics[name]) or (low is not None and metrics[name] < low)
        or (high is not None and metrics[name] > high)]


def final_metrics(points, target):
    metrics = distribution_metrics(points, target.weights, target.means, target.variances)
    failures = distribution_failures(metrics, "final_")
    if target.kind == "bimodal":
        points = points.detach().cpu().double()
        means, var = target.means.double(), target.variances.double()
        if not torch.isfinite(points).all():
            metrics.update(hq=0., mode_mass_tv=1., local_mean_sigma=math.inf,
                local_covariance_min=0., local_covariance_max=math.inf)
        else:
            ids = torch.cdist(points, means).argmin(1)
            residual = (points - means[ids]) / var[ids].sqrt()
            counts = torch.bincount(ids, minlength=2).double() / len(points)
            local = [residual[ids == k] for k in range(2)]
            eigs = [torch.linalg.eigvalsh(torch.cov(x.T, correction=0)) if len(x) > 2
                    else torch.tensor([0., math.inf]) for x in local]
            metrics.update(hq=float((residual.norm(dim=1) <= 3).double().mean()),
                mode_mass_tv=float(.5 * (counts - target.weights).abs().sum()),
                local_mean_sigma=max(float(x.mean(0).norm()) if len(x) else math.inf for x in local),
                local_covariance_min=min(float(x.min()) for x in eigs),
                local_covariance_max=max(float(x.max()) for x in eigs))
        for name, low, high in (("hq", .95, None), ("mode_mass_tv", None, .10),
                ("local_mean_sigma", None, .5), ("local_covariance_min", .5, None),
                ("local_covariance_max", None, 1.5)):
            if not math.isfinite(metrics[name]) or (low is not None and metrics[name] < low) or (high is not None and metrics[name] > high):
                failures.append("final_" + name)
    return metrics, failures


def task_recipe(case, recipe_name=None, recipe=None):
    """Bind task resources/objectives; preserve every trainer/prior mechanism."""
    fields = dict(RESOURCES, total_steps=case["default_steps"], model="ddgan",
        encoder_mode=case.get("encoder_mode", "none"), conditioning="scalar", num_classes=None,
        alpha_bar=ALPHA_BAR, prior_kind="mog", sigma_rel=0., standardize=False)
    if recipe is not None:
        if not isinstance(recipe, Recipe):
            raise TypeError("resolved recipe must be a public Recipe")
        for name in ("num_particles", "z_dim", "batch_size", "model", "encoder_mode", "conditioning", "num_classes", "standardize", "prior_kind"):
            if getattr(recipe, name) != fields[name]:
                raise ValueError("resolved Recipe contradicts task-owned " + name)
        if tuple(recipe.alpha_bar) != ALPHA_BAR or recipe.total_steps not in (None, fields["total_steps"]):
            raise ValueError("resolved Recipe contradicts frozen diffusion schedule/horizon")
        result = recipe
    elif recipe_name in (None, BASELINE):
        candidate = json.loads((ROOT / "configs/forge/ideas" / (BASELINE + ".json")).read_text())
        result = Recipe(**{**candidate["recipe_overrides"], **fields})
    else:
        result = get_recipe(recipe_name, **fields)
    from experiments.forge.api import policy_controls
    if (policy_controls(result) or result.row_policy != "independent" or result.input_noise_std
            or result.output_noise_std or result.kinetic_transport_weight
            or result.kinetic_transport_local_weight or result.constraint_geometry_mode == "strict_progress"):
        raise ValueError("DDGAN caller-owned transition host does not bind adaptive row/serving/noise/transport/strict-progress policies")
    return result


class DDGANFixture:
    api_components = ("DDGAN.forward_pair", "DDGAN.reverse", "MoGParticlePrior.sample",
        "init.deterministic_orthogonal_", "Recipe.make_optimizers", "Recipe.make_loss",
        "Recipe.make_critic_penalty", "Recipe.prior_regularization", "UpdatePolicy")

    def make_encoder(self):
        """Override in the separately declared AE-DDGAN composition."""
        return None

    def extra_generator_objective(self, clean, xt, t):
        """Return (extra loss, protected losses, scalar diagnostics)."""
        return clean.new_zeros(()), (), {}

    def __init__(self, case, *, device="cpu", seed=0, recipe_name=None, max_steps=None, recipe=None):
        self.case, self.seed, self.device = deepcopy(case), int(seed), torch.device(device)
        self.limit = case["default_steps"] if max_steps is None else max_steps
        if type(self.limit) is not int or not 0 < self.limit <= case["default_steps"]:
            raise ValueError("execution cap must be within the frozen task budget")
        self.recipe = task_recipe(case, recipe_name, recipe)
        self.target = MixtureTarget(case["target"])
        self.completed_steps, self.last_losses = 0, {}
        self.streams = NamedStreams(seed, device=self.device)
        with construction_rng(seed, "cpu"), self.streams.fork("init", component="models", device="cpu"):
            self.G, self.D = ChainGenerator(self.recipe.z_dim), ChainCritic()
            self.prior = MoGParticlePrior(sigma=.25, standardize=False, **{
                name: getattr(self.recipe, name) for name in ("num_particles", "z_dim")})
            self.E = self.make_encoder()
        for offset, module in enumerate((self.G, self.D, self.prior, self.E)):
            if module is not None:
                init.deterministic_orthogonal_(module, seed=seed + offset)
                module.to(self.device)
        self.schedule = DDGAN(ALPHA_BAR, device=self.device)
        self.recipe.apply_prior_policy(self.prior)
        self.opt_g, self.opt_d = self.recipe.make_optimizers(self.G, self.D, self.prior,
            encoder=self.E, separate_encoder_groups=self.E is not None,
            ema_critic=None if self.recipe.effective_critic_formulation == "bispf" else deepcopy(self.D))
        self.base_rates = [[group["lr"] for group in optimizer.param_groups] for optimizer in (self.opt_g, self.opt_d)]
        self.loss = self.recipe.make_loss()
        self.prior_regularizer = self.recipe.make_prior_regularizer(prior=self.prior)
        self.penalty = self.recipe.make_critic_penalty(self.opt_d, collect_stats=True)
        self.policy = UpdatePolicy(self.recipe, self.G, self.D, prior=self.prior,
            encoder=self.E, generator_optimizer=self.opt_g, critic_optimizer=self.opt_d,
            row_semantics="conditional", penalty=self.penalty, seed=seed, streams={
                "latent_generator": self._rng("prior", "policy_latent"),
                "penalty_generator": self._rng("noise", "policy_penalty"),
                "noise_generator": self._rng("noise", "policy_output"),
                "eval_generator": self._rng("eval", "policy_evaluation", "evaluation")})
        self.batch_digest = hashlib.sha256().hexdigest()
        self.initialization = "public deterministic_orthogonal: G=seed, D=seed+1, prior=seed+2, E=seed+3; R2Normal prior; no analytic weights"

    def _rng(self, family, component, purpose="training", *, cpu=False):
        return self.streams.generator(family, component=component, purpose=purpose,
                                      device="cpu" if cpu else self.device)

    def _training_pair(self, role):
        clean = self.target.sample(self.recipe.batch_size, self._rng("data", role, cpu=True)).to(self.device)
        t = torch.randint(1, self.schedule.steps + 1, (len(clean),),
            generator=self._rng("data", role + "_time", cpu=True)).to(self.device)
        real, xt = self.schedule.forward_pair(clean, t, generator=self._rng("noise", role + "_forward"))
        digest = hashlib.sha256(bytes.fromhex(self.batch_digest))
        for value in (clean, t):
            digest.update(value.detach().cpu().contiguous().numpy().tobytes())
        self.batch_digest = digest.hexdigest()
        return clean, real, xt, t

    def _transition(self, xt, t, role):
        result, indices = sample_transition(self.G, self.prior, self.schedule, xt, t,
            latent_rng=self._rng("prior", role + "_latent"), kernel_rng=self._rng("noise", role + "_kernel"),
            reverse_rng=self._rng("noise", role + "_reverse"),
            support_observer=self.policy.observe_support if role == "critic" else None)
        if role == "generator":
            self.bind_prior_rows(indices)
        return result, indices

    def bind_prior_rows(self, indices):
        """Composition hooks must also bind every encoder-selected prior row."""
        self.policy.observe_sampled_rows(indices.flatten())

    @property
    def batch_sequence_sha256(self):
        """Public runner/Forge provenance name for the checkpointed digest."""
        return self.batch_digest

    def step(self):
        if self.completed_steps >= self.limit:
            raise RuntimeError("declared DDGAN update budget exhausted")
        with torch.autograd.set_multithreading_enabled(False):
            try:
                return self._step()
            except Exception:
                self.policy.abort_step()
                raise

    def _step(self):
        _, real, xt, t = self._training_pair("critic")
        self.policy.begin_step(real, game_record=self.penalty.regularizer.record, execution_limit=self.limit)
        self.G.eval(); self.D.train()
        if self.E is not None:
            self.E.eval()
        with torch.no_grad():
            fake, _ = self._transition(xt, t, "critic")
        self.policy.observe_critic_pair(real, fake)
        self.opt_d.zero_grad()
        dl = self.loss.d_loss(self.D(real, xt=xt, t=t), self.D(fake, xt=xt, t=t))
        with self.streams.fork("noise", component="critic_penalty"):
            penalty = self.penalty(self.D, real, fake, xt=xt, t=t)
        (dl + penalty).backward()
        self.opt_d.step()
        self.policy.after_critic_step()
        clean, real, xt, t = self._training_pair("generator")
        flags = [p.requires_grad for p in self.D.parameters()]
        try:
            self.D.eval(); self.G.train(); self.D.requires_grad_(False)
            if self.E is not None:
                self.E.train()
            fake, _ = self._transition(xt, t, "generator")
            gl = self.loss.g_loss(self.D(fake, xt=xt, t=t), self.D(real, xt=xt, t=t).detach())
            prior_loss = self.recipe.prior_regularization(self.prior.z,
                regularizer=self.prior_regularizer, prior=self.prior)
            extra, protected, diagnostics = self.extra_generator_objective(clean, xt, t)
            self.opt_g.zero_grad()
            constraint_geometry_backward(gl + prior_loss + extra, self.opt_g, (gl,) + tuple(protected))
            self.policy.after_generator_backward(loss_gan=gl.detach(), loss_critic=dl.detach())
            self.opt_g.step()
            self.policy.after_generator_step()
        finally:
            for p, flag in zip(self.D.parameters(), flags):
                p.requires_grad_(flag)
        self.policy.finish_step()
        self.completed_steps = self.policy.completed_steps
        self.last_losses = dict(g_gan=float(gl.detach()), d_gan=float(dl.detach()),
            critic_penalty=float(penalty.detach()), prior_regularization=float(prior_loss.detach()), **diagnostics)
        if not all(math.isfinite(float(value)) for value in self.last_losses.values()):
            raise FloatingPointError("nonfinite DDGAN transition update")
        return dict(step=self.completed_steps, **self.last_losses)

    @torch.no_grad()
    def observe(self, n=2048, seed=10000):
        if type(n) is not int or n < 2:
            raise ValueError("evaluation requires at least two samples per panel")
        modes = {module: module.training for model in self._models().values() for module in model.modules()}
        evaluation = NamedStreams(int(seed), device=self.device)
        def rng(component, *, cpu=False):
            return evaluation.generator("eval", component=component,
                device="cpu" if cpu else self.device)
        try:
            for model in self._models().values():
                model.eval()
            samples = sample_chain(self.G, self.prior, self.schedule, n,
                start_rng=rng("start"), latent_rng=rng("latent"), kernel_rng=rng("kernel"),
                reverse_rng=rng("reverse"), device=self.device).cpu()
            final, failures = final_metrics(samples, self.target)
            metrics = {"final_" + key: value for key, value in final.items()}
            target = self.target.sample(n, rng("target", cpu=True))
            views = [dict(kind="scatter", title="Actual four-step chain: clean target and final samples",
                target=target, samples=samples, caption="N(0,I) start; new independent latent and reverse noise at every step. Conditional transitions are scored separately.")]
            panels = []
            cpu_schedule = DDGAN(ALPHA_BAR)
            for step in range(1, self.schedule.steps + 1):
                for index, xy in enumerate(((-.5, .25), (.5, -.25))):
                    label = f"t{step}_q{index}"
                    xt = torch.tensor(xy, device=self.device).expand(n, 2)
                    t = torch.full((n,), step, device=self.device, dtype=torch.long)
                    predicted, _ = sample_transition(self.G, self.prior, self.schedule, xt, t,
                        latent_rng=rng(label + "_latent"), kernel_rng=rng(label + "_kernel"),
                        reverse_rng=rng(label + "_reverse"))
                    parameters = self.target.transition_parameters(xy, step, cpu_schedule)
                    values = distribution_metrics(predicted, *parameters)
                    failures += distribution_failures(values, label + "_")
                    panels.append(values)
                    for name, value in values.items():
                        metrics[label + "_" + name] = value
                    if (step, index) in ((1, 0), (2, 1)):
                        reference = self.target.draw(*parameters, n, rng(label + "_target", cpu=True))
                        views.append(dict(kind="scatter", title=f"Reverse transition t={step}, fixed xt={xy}",
                            target=reference, samples=predicted.cpu(), caption="Exact conditional reverse distribution versus learned transition; oracle is evaluation only."))
            metrics.update(panel_count=len(panels), samples_per_panel=n,
                worst_transition_cdf=max(x["projection_cdf"] for x in panels))
            if n < self.case["eval_samples"]:
                failures.append("samples_per_panel")
            return dict(metrics=metrics, passed=not failures, failed_bounds=sorted(set(failures)), views=views)
        finally:
            for module, mode in modes.items():
                module.training = mode

    def _models(self):
        result = dict(G=self.G, D=self.D, prior=self.prior, schedule=self.schedule)
        if self.E is not None:
            result["E"] = self.E
        return result

    def state_dict(self):
        return deepcopy(dict(schema=VERSION, case_id=self.case["id"], seed=self.seed,
            device=str(self.device), limit=self.limit, recipe=self.recipe.to_dict(),
            completed_steps=self.completed_steps, models={name: model.state_dict() for name, model in self._models().items()},
            modes={name: {key: module.training for key, module in model.named_modules()} for name, model in self._models().items()},
            gradients={name: {key: None if p.grad is None else p.grad.clone() for key, p in model.named_parameters()} for name, model in self._models().items()},
            optimizers=[self.opt_g.state_dict(), self.opt_d.state_dict()], base_rates=self.base_rates,
            policy=self.policy.state_dict(),
            streams=self.streams.state_dict(), batch_digest=self.batch_digest,
            last_losses=self.last_losses, **self.recipe.prior_regularizer_checkpoint(self.prior_regularizer)))

    def load_state_dict(self, state):
        for name, value in (("schema", VERSION), ("case_id", self.case["id"]), ("seed", self.seed),
                ("device", str(self.device)), ("limit", self.limit), ("recipe", self.recipe.to_dict())):
            if state.get(name) != value:
                raise ValueError("DDGAN checkpoint identity mismatch: " + name)
        if type(state.get("completed_steps")) is not int or not 0 <= state["completed_steps"] <= self.limit:
            raise ValueError("invalid checkpoint update count")
        self.streams.validate_state_dict(state["streams"])
        self.recipe.restore_prior_regularizer(self.prior_regularizer, state.get("prior_regularizer"), validate_only=True)
        for name, model in self._models().items():
            model.load_state_dict(state["models"][name])
            for key, module in model.named_modules():
                module.training = state["modes"][name][key]
            for key, parameter in model.named_parameters():
                gradient = state["gradients"][name][key]
                parameter.grad = None if gradient is None else gradient.to(parameter).clone()
        for optimizer, values in zip((self.opt_g, self.opt_d), state["optimizers"]):
            optimizer.load_state_dict(values)
        self.streams.load_state_dict(state["streams"])
        self.recipe.restore_prior_regularizer(self.prior_regularizer, state.get("prior_regularizer"))
        self.policy.load_state_dict(state["policy"])
        self.completed_steps, self.base_rates = state["completed_steps"], deepcopy(state["base_rates"])
        self.last_losses, self.batch_digest = deepcopy(state["last_losses"]), state["batch_digest"]


def build_case(case_id, *, device="cpu", seed=DEFAULT_SEED, recipe_name=None, max_steps=None, recipe=None):
    if case_id not in CASES:
        raise ValueError("unknown DDGAN API toy: " + case_id)
    return DDGANFixture(CASES[case_id], device=device, seed=seed, recipe_name=recipe_name,
                        max_steps=max_steps, recipe=recipe)
