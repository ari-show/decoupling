from __future__ import annotations

from torch import nn
import torch

from .retail_models import DayEncoder, GlobalEncoder, HourEncoder, InteractionEncoder, covariance_penalty, flatten_to_grid


class ResidualFlattenAE(nn.Module):
    def __init__(self, input_dim: int, days: int, hours: int, hidden_dim: int, dropout: float = 0.1):
        super().__init__()
        self.days = days
        self.hours = hours
        self.encoder = nn.Sequential(
            nn.Linear(input_dim * days * hours, hidden_dim),
            nn.ReLU(),
            nn.Dropout(dropout),
            nn.Linear(hidden_dim, hidden_dim),
            nn.ReLU(),
        )
        self.decoder = nn.Linear(hidden_dim, days * hours)

    def forward(self, x: torch.Tensor, mask: torch.Tensor) -> dict[str, torch.Tensor]:
        grid = flatten_to_grid(x)
        z = self.encoder(grid.reshape(grid.shape[0], -1))
        residual_hat = self.decoder(z).reshape(grid.shape[0], self.days, self.hours)
        return {"residual_hat": residual_hat, "z_global": z}


class CellLocalEncoder(nn.Module):
    def __init__(self, input_dim: int, hidden_dim: int, local_dim: int):
        super().__init__()
        self.net = nn.Sequential(
            nn.Linear(input_dim * 2, hidden_dim),
            nn.ReLU(),
            nn.Linear(hidden_dim, local_dim),
        )

    def forward(self, grid: torch.Tensor, mask: torch.Tensor) -> torch.Tensor:
        return self.net(torch.cat([grid, mask], dim=-1))


class ResidualMultiGrainAE(nn.Module):
    def __init__(
        self,
        input_dim: int,
        days: int,
        hours: int,
        hidden_dim: int,
        global_dim: int,
        local_dim: int,
        day_dim: int,
        hour_dim: int,
        interaction_dim: int,
        use_global: bool = True,
        use_local: bool = False,
        use_day: bool = True,
        use_hour: bool = True,
        use_interaction: bool = False,
        dropout: float = 0.1,
    ):
        super().__init__()
        self.days = days
        self.hours = hours
        self.global_dim = global_dim
        self.local_dim = local_dim
        self.day_dim = day_dim
        self.hour_dim = hour_dim
        self.interaction_dim = interaction_dim if use_interaction else 0
        self.use_global = use_global
        self.use_local = use_local
        self.use_day = use_day
        self.use_hour = use_hour
        self.use_interaction = use_interaction

        self.global_encoder = GlobalEncoder(input_dim, hidden_dim, global_dim)
        self.local_encoder = CellLocalEncoder(input_dim, hidden_dim, local_dim)
        self.day_encoder = DayEncoder(input_dim, hidden_dim, day_dim)
        self.hour_encoder = HourEncoder(input_dim, hidden_dim, hour_dim)
        self.interaction_encoder = InteractionEncoder(day_dim, hour_dim, hidden_dim, interaction_dim)
        latent_dim = 0
        latent_dim += global_dim if use_global else 0
        latent_dim += local_dim if use_local else 0
        latent_dim += day_dim if use_day else 0
        latent_dim += hour_dim if use_hour else 0
        latent_dim += interaction_dim if use_interaction else 0
        if latent_dim == 0:
            raise ValueError("at least one latent component must be enabled")
        self.decoder = nn.Sequential(
            nn.Linear(latent_dim, hidden_dim),
            nn.ReLU(),
            nn.Dropout(dropout),
            nn.Linear(hidden_dim, 1),
        )

    def encode(self, x: torch.Tensor, mask: torch.Tensor) -> dict[str, torch.Tensor]:
        grid = flatten_to_grid(x)
        mask_grid = flatten_to_grid(mask)
        z_global = self.global_encoder(grid, mask_grid)
        z_local = self.local_encoder(grid, mask_grid)
        z_day = self.day_encoder(grid, mask_grid)
        z_hour = self.hour_encoder(grid, mask_grid)
        z_interaction = self.interaction_encoder(z_day, z_hour)
        return {
            "grid": grid,
            "mask_grid": mask_grid,
            "z_global": z_global,
            "z_local": z_local,
            "z_day": z_day,
            "z_hour": z_hour,
            "z_interaction": z_interaction,
        }

    def _latent_grid(self, encoded: dict[str, torch.Tensor]) -> torch.Tensor:
        batch, days, hours = encoded["grid"].shape[:3]
        parts = []
        if self.use_global:
            parts.append(encoded["z_global"][:, None, None, :].expand(batch, days, hours, -1))
        if self.use_local:
            parts.append(encoded["z_local"])
        if self.use_day:
            parts.append(encoded["z_day"][:, :, None, :].expand(batch, days, hours, -1))
        if self.use_hour:
            parts.append(encoded["z_hour"][:, None, :, :].expand(batch, days, hours, -1))
        if self.use_interaction:
            parts.append(encoded["z_interaction"])
        return torch.cat(parts, dim=-1)

    def forward(self, x: torch.Tensor, mask: torch.Tensor) -> dict[str, torch.Tensor]:
        encoded = self.encode(x, mask)
        residual_hat = self.decode_from_encoded(encoded)
        out = {
            "residual_hat": residual_hat,
            "grid": encoded["grid"],
            "mask_grid": encoded["mask_grid"],
        }
        if self.use_global:
            out["z_global"] = encoded["z_global"]
        if self.use_local:
            out["z_local"] = encoded["z_local"]
        if self.use_day:
            out["z_day"] = encoded["z_day"]
        if self.use_hour:
            out["z_hour"] = encoded["z_hour"]
        if self.use_interaction:
            out["z_interaction"] = encoded["z_interaction"]
        return out

    def decode_from_encoded(self, encoded: dict[str, torch.Tensor]) -> torch.Tensor:
        return self.decoder(self._latent_grid(encoded)).squeeze(-1)

    def decode_from_parts(
        self,
        reference: dict[str, torch.Tensor],
        z_global: torch.Tensor | None = None,
        z_local: torch.Tensor | None = None,
        z_day: torch.Tensor | None = None,
        z_hour: torch.Tensor | None = None,
        z_interaction: torch.Tensor | None = None,
    ) -> torch.Tensor:
        encoded = dict(reference)
        if z_global is not None:
            encoded["z_global"] = z_global
        if z_local is not None:
            encoded["z_local"] = z_local
        if z_day is not None:
            encoded["z_day"] = z_day
        if z_hour is not None:
            encoded["z_hour"] = z_hour
        if z_interaction is not None:
            encoded["z_interaction"] = z_interaction
        if self.use_interaction and z_interaction is None and (z_day is not None or z_hour is not None):
            encoded["z_interaction"] = self.interaction_encoder(encoded["z_day"], encoded["z_hour"])
        return self.decode_from_encoded(encoded)


def residual_decouple_penalty(out: dict[str, torch.Tensor]) -> torch.Tensor:
    parts = [out.get("z_global"), out.get("z_local"), out.get("z_day"), out.get("z_hour")]
    return covariance_penalty([part for part in parts if part is not None])


class EmpiricalAnovaResidualModel(nn.Module):
    """Parameter-free naive baseline: masked main-effects ANOVA of the observed residuals.

    From the residual channel of the input grid, estimates the overall masked
    mean (global component), per-day masked means minus the overall mean
    (day component), and per-hour masked means minus the overall mean
    (hour component), then predicts ``r_hat = g + a + c`` with the interaction
    fixed at zero. Days or hours without observed cells receive a zero effect,
    which also covers the future-day setting where the residual channel of the
    trailing days is masked out: there the prediction carries over only the
    global and hour components, as a classical decomposition would.

    No learning takes place; a dummy parameter keeps the generic training loop
    (optimizer / GradScaler) functional while gradients are exactly zero.
    """

    def __init__(self, days: int, hours: int):
        super().__init__()
        self.days = days
        self.hours = hours
        self._dummy = nn.Parameter(torch.zeros(1))

    def forward(self, x: torch.Tensor, mask: torch.Tensor) -> dict[str, torch.Tensor]:
        grid = flatten_to_grid(x)
        mask_grid = flatten_to_grid(mask)
        residual = grid[..., 0]
        observed = mask_grid[..., 0]
        batch = residual.shape[0]

        total = (residual * observed).sum(dim=(1, 2))
        count = observed.sum(dim=(1, 2)).clamp_min(1.0)
        g = total / count

        day_count = observed.sum(dim=2)
        day_mean = (residual * observed).sum(dim=2) / day_count.clamp_min(1.0)
        day_effect = torch.where(day_count > 0, day_mean - g[:, None], torch.zeros_like(day_mean))

        hour_count = observed.sum(dim=1)
        hour_mean = (residual * observed).sum(dim=1) / hour_count.clamp_min(1.0)
        hour_effect = torch.where(hour_count > 0, hour_mean - g[:, None], torch.zeros_like(hour_mean))

        global_component = g[:, None, None].expand(batch, self.days, self.hours)
        day_component = day_effect[:, :, None].expand(batch, self.days, self.hours)
        hour_component = hour_effect[:, None, :].expand(batch, self.days, self.hours)
        interaction_component = torch.zeros_like(global_component)
        residual_hat = global_component + day_component + hour_component + self._dummy * 0.0
        return {
            "global_component": global_component,
            "day_component": day_component,
            "hour_component": hour_component,
            "interaction_component": interaction_component,
            "residual_hat": residual_hat,
        }


class OutputDecompositionResidualModel(nn.Module):
    """Residual model that decodes separate global/day/hour/interaction output components."""

    def __init__(
        self,
        input_dim: int,
        days: int,
        hours: int,
        hidden_dim: int,
        global_dim: int,
        day_dim: int,
        hour_dim: int,
        interaction_dim: int,
        dropout: float = 0.1,
        center_components: bool = True,
        use_interaction: bool = True,
    ):
        super().__init__()
        self.days = days
        self.hours = hours
        self.center_components = center_components
        self.use_interaction = use_interaction
        self.global_encoder = GlobalEncoder(input_dim, hidden_dim, global_dim)
        self.day_encoder = DayEncoder(input_dim, hidden_dim, day_dim)
        self.hour_encoder = HourEncoder(input_dim, hidden_dim, hour_dim)
        self.interaction_encoder = InteractionEncoder(day_dim, hour_dim, hidden_dim, interaction_dim)
        self.global_head = nn.Sequential(nn.Linear(global_dim, hidden_dim), nn.ReLU(), nn.Dropout(dropout), nn.Linear(hidden_dim, 1))
        self.day_head = nn.Sequential(nn.Linear(day_dim, hidden_dim), nn.ReLU(), nn.Dropout(dropout), nn.Linear(hidden_dim, 1))
        self.hour_head = nn.Sequential(nn.Linear(hour_dim, hidden_dim), nn.ReLU(), nn.Dropout(dropout), nn.Linear(hidden_dim, 1))
        self.interaction_head = nn.Sequential(nn.Linear(interaction_dim, hidden_dim), nn.ReLU(), nn.Dropout(dropout), nn.Linear(hidden_dim, 1))

    def encode(self, x: torch.Tensor, mask: torch.Tensor) -> dict[str, torch.Tensor]:
        grid = flatten_to_grid(x)
        mask_grid = flatten_to_grid(mask)
        z_global = self.global_encoder(grid, mask_grid)
        z_day = self.day_encoder(grid, mask_grid)
        z_hour = self.hour_encoder(grid, mask_grid)
        z_interaction = self.interaction_encoder(z_day, z_hour)
        return {
            "grid": grid,
            "mask_grid": mask_grid,
            "z_global": z_global,
            "z_day": z_day,
            "z_hour": z_hour,
            "z_interaction": z_interaction,
        }

    def decode_from_encoded(self, encoded: dict[str, torch.Tensor]) -> dict[str, torch.Tensor]:
        batch = encoded["grid"].shape[0]
        g_scalar = self.global_head(encoded["z_global"]).reshape(batch, 1, 1)
        global_component = g_scalar.expand(batch, self.days, self.hours)
        day_component = self.day_head(encoded["z_day"]).squeeze(-1)[:, :, None].expand(batch, self.days, self.hours)
        hour_component = self.hour_head(encoded["z_hour"]).squeeze(-1)[:, None, :].expand(batch, self.days, self.hours)
        if self.use_interaction:
            interaction_component = self.interaction_head(encoded["z_interaction"]).squeeze(-1)
        else:
            interaction_component = torch.zeros_like(global_component)
        if self.center_components:
            day_component = day_component - day_component.mean(dim=1, keepdim=True)
            hour_component = hour_component - hour_component.mean(dim=2, keepdim=True)
            interaction_component = interaction_component - interaction_component.mean(dim=1, keepdim=True)
            interaction_component = interaction_component - interaction_component.mean(dim=2, keepdim=True)
        residual_hat = global_component + day_component + hour_component + interaction_component
        return {
            "global_component": global_component,
            "day_component": day_component,
            "hour_component": hour_component,
            "interaction_component": interaction_component,
            "residual_hat": residual_hat,
        }

    def forward(self, x: torch.Tensor, mask: torch.Tensor) -> dict[str, torch.Tensor]:
        encoded = self.encode(x, mask)
        decoded = self.decode_from_encoded(encoded)
        return {
            **decoded,
            "grid": encoded["grid"],
            "mask_grid": encoded["mask_grid"],
            "z_global": encoded["z_global"],
            "z_day": encoded["z_day"],
            "z_hour": encoded["z_hour"],
            "z_interaction": encoded["z_interaction"],
        }


class UnifiedDecompositionResidualModel(nn.Module):
    """Unified architecture: one shared cell-level backbone encoder with axis-pooling
    readouts, and either axis-specific output heads (`shared_encoder`) or a single
    context-conditioned cell decoder followed by an exact ANOVA projection
    (`single_decoder`).

    In `single_decoder` mode the four components are obtained by projecting the
    decoded grid onto the orthogonal ANOVA subspaces (grand mean / row / column /
    remainder), so centering holds by construction and `center_components` is
    ignored.
    """

    def __init__(
        self,
        input_dim: int,
        days: int,
        hours: int,
        hidden_dim: int,
        global_dim: int,
        day_dim: int,
        hour_dim: int,
        interaction_dim: int,
        dropout: float = 0.1,
        architecture: str = "single_decoder",
        center_components: bool = True,
    ):
        super().__init__()
        if architecture not in {"shared_encoder", "single_decoder"}:
            raise ValueError(f"unknown unified architecture: {architecture}")
        self.days = days
        self.hours = hours
        self.architecture = architecture
        self.center_components = center_components
        self.backbone = nn.Sequential(
            nn.Linear(input_dim * 2, hidden_dim),
            nn.ReLU(),
            nn.Dropout(dropout),
            nn.Linear(hidden_dim, hidden_dim),
            nn.ReLU(),
        )
        self.global_proj = nn.Linear(hidden_dim, global_dim)
        self.day_proj = nn.Linear(hidden_dim, day_dim)
        self.hour_proj = nn.Linear(hidden_dim, hour_dim)
        # interaction latent は cell-level 特徴からではなく z_day×z_hour からのみ構成する。
        # cell-level 特徴を使うと、入力チャネル 0（観測残差）を interaction 経路が
        # コピーして窓内で恒等写像に退化する（2-Exp-33 と同型のリーク）。
        self.interaction_encoder = InteractionEncoder(day_dim, hour_dim, hidden_dim, interaction_dim)
        if architecture == "shared_encoder":
            def head(dim: int) -> nn.Sequential:
                return nn.Sequential(nn.Linear(dim, hidden_dim), nn.ReLU(), nn.Dropout(dropout), nn.Linear(hidden_dim, 1))

            self.global_head = head(global_dim)
            self.day_head = head(day_dim)
            self.hour_head = head(hour_dim)
            self.interaction_head = head(interaction_dim)
        else:
            dec_in = global_dim + day_dim + hour_dim + interaction_dim
            self.decoder = nn.Sequential(
                nn.Linear(dec_in, hidden_dim),
                nn.ReLU(),
                nn.Dropout(dropout),
                nn.Linear(hidden_dim, 1),
            )

    @staticmethod
    def _masked_pool(feats: torch.Tensor, mask: torch.Tensor, dims: tuple[int, ...]) -> torch.Tensor:
        weighted = feats * mask
        denom = mask.sum(dim=dims).clamp_min(1.0)
        return weighted.sum(dim=dims) / denom

    def forward(self, x: torch.Tensor, mask: torch.Tensor) -> dict[str, torch.Tensor]:
        grid = flatten_to_grid(x)
        mask_grid = flatten_to_grid(mask)
        feats = self.backbone(torch.cat([grid, mask_grid], dim=-1))
        cell_mask = mask_grid[..., :1]
        z_global = self.global_proj(self._masked_pool(feats, cell_mask, (1, 2)))
        z_day = self.day_proj(self._masked_pool(feats, cell_mask, (2,)))
        z_hour = self.hour_proj(self._masked_pool(feats, cell_mask, (1,)))
        z_interaction = self.interaction_encoder(z_day, z_hour)
        batch = grid.shape[0]
        if self.architecture == "shared_encoder":
            global_component = self.global_head(z_global).reshape(batch, 1, 1).expand(batch, self.days, self.hours)
            day_component = self.day_head(z_day).squeeze(-1)[:, :, None].expand(batch, self.days, self.hours)
            hour_component = self.hour_head(z_hour).squeeze(-1)[:, None, :].expand(batch, self.days, self.hours)
            interaction_component = self.interaction_head(z_interaction).squeeze(-1)
            if self.center_components:
                day_component = day_component - day_component.mean(dim=1, keepdim=True)
                hour_component = hour_component - hour_component.mean(dim=2, keepdim=True)
                interaction_component = interaction_component - interaction_component.mean(dim=1, keepdim=True)
                interaction_component = interaction_component - interaction_component.mean(dim=2, keepdim=True)
            residual_hat = global_component + day_component + hour_component + interaction_component
        else:
            dec_in = torch.cat(
                [
                    z_global[:, None, None, :].expand(batch, self.days, self.hours, -1),
                    z_day[:, :, None, :].expand(batch, self.days, self.hours, -1),
                    z_hour[:, None, :, :].expand(batch, self.days, self.hours, -1),
                    z_interaction,
                ],
                dim=-1,
            )
            decoded = self.decoder(dec_in).squeeze(-1)
            grand = decoded.mean(dim=(1, 2), keepdim=True)
            row = decoded.mean(dim=2, keepdim=True) - grand
            col = decoded.mean(dim=1, keepdim=True) - grand
            global_component = grand.expand(batch, self.days, self.hours)
            day_component = row.expand(batch, self.days, self.hours)
            hour_component = col.expand(batch, self.days, self.hours)
            interaction_component = decoded - grand - row - col
            residual_hat = decoded
        return {
            "grid": grid,
            "mask_grid": mask_grid,
            "z_global": z_global,
            "z_day": z_day,
            "z_hour": z_hour,
            "z_interaction": z_interaction,
            "global_component": global_component,
            "day_component": day_component,
            "hour_component": hour_component,
            "interaction_component": interaction_component,
            "residual_hat": residual_hat,
        }
