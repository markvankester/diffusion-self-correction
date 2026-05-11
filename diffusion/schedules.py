# Adapted from:
# https://github.com/ZHZisZZ/dllm

from __future__ import annotations
import dataclasses
import math
from typing import Any, ClassVar, Union
import torch

Number = Union[float, torch.Tensor]


@dataclasses.dataclass
class BaseAlphaScheduler:
    """
    Base class for alpha schedulers in diffusion language models.
    Alpha schedulers define the masking rate α(t) as a function of diffusion time t ∈ [0,1].
    """
    __registry__: ClassVar[dict[str, type[BaseAlphaScheduler]]] = {}

    def __init_subclass__(cls, **kwargs):
        super().__init_subclass__(**kwargs)
        BaseAlphaScheduler.__registry__[cls.__name__] = cls
        BaseAlphaScheduler.__registry__[cls.__name__.lower()] = cls

    def __call__(self, t: Number) -> Number:
        return self.alpha(t)

    def alpha(self, i: Number) -> Number:
        i_t = torch.as_tensor(i, dtype=torch.float32, device=i.device if isinstance(i, torch.Tensor) else None)
        if not torch.all((0.0 <= i_t) & (i_t <= 1.0)):
            raise ValueError(f"i={i} not in [0,1]")
        out = self._alpha(i_t)
        return out.item() if isinstance(i, float) else out

    def alpha_derivative(self, i: Number) -> Number:
        i_t = torch.as_tensor(i, dtype=torch.float32, device=i.device if isinstance(i, torch.Tensor) else None)
        if not torch.all((0.0 <= i_t) & (i_t <= 1.0)):
            raise ValueError(f"i={i} not in [0,1]")
        out = self._alpha_derivative(i_t)
        return out.item() if isinstance(i, float) else out

    def weight(self, i: Number) -> Number:
        """Loss weight w(t) = -α'(t) / (1 - α(t)), used in the MDLM objective."""
        return -self.alpha_derivative(i) / (1 - self.alpha(i) + 1e-6)

    def reverse_mask_prob(self, s: Number, t: Number) -> Number:
        """
        Probability a token *stays masked* going from time t -> s (reverse step).
        
        P(mask at s | mask at t) = (1 - α(s)) / (1 - α(t))
        
        The sampler uses  1 - reverse_mask_prob(s, t)  as the probability that
        a masked token gets *unmasked* in the reverse step from t to s.
        """
        t_t = torch.as_tensor(
            t, dtype=torch.float32,
            device=t.device if isinstance(t, torch.Tensor) else None,
        )
        s_t = torch.as_tensor(
            s, dtype=torch.float32,
            device=s.device if isinstance(s, torch.Tensor) else None,
        )
        if not torch.all((0.0 <= s_t) & (s_t < 1.0) & (0.0 < t_t) & (t_t <= 1.0)):
            raise ValueError(f"(t={t}, s={s}) out of range")
        if not torch.all(s_t < t_t):
            raise ValueError(f"Require s < t elementwise, but got (t={t}, s={s})")
        out = (1 - self(s_t)) / (1 - self(t_t))
        return out.item() if isinstance(t, float) and isinstance(s, float) else out

    def _alpha(self, i: torch.Tensor) -> torch.Tensor:
        raise NotImplementedError

    def _alpha_derivative(self, i: torch.Tensor) -> torch.Tensor:
        raise NotImplementedError


@dataclasses.dataclass
class LinearAlphaScheduler(BaseAlphaScheduler):
    """Linear masking schedule: α(t) = 1 - t."""
    def _alpha(self, i: torch.Tensor) -> torch.Tensor:
        return 1 - i

    def _alpha_derivative(self, i: torch.Tensor) -> torch.Tensor:
        return -torch.ones_like(i)


@dataclasses.dataclass
class CosineAlphaScheduler(BaseAlphaScheduler):
    """Cosine masking schedule: α(t) = 1 - cos(π/2 · (1-t))."""
    def _alpha(self, i: torch.Tensor) -> torch.Tensor:
        return 1 - torch.cos((math.pi / 2) * (1 - i))

    def _alpha_derivative(self, i: torch.Tensor) -> torch.Tensor:
        return -(math.pi / 2) * torch.sin((math.pi / 2) * (1 - i))
