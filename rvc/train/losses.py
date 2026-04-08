from typing import List, Optional, Tuple, Union

import torch
import torch.nn as nn
from torch.nn import functional as F
from torch import Tensor

def phase_loss(x_fft: torch.Tensor, g_fft: torch.Tensor, reduction: str = 'mean') -> torch.Tensor:
    x_norm = x_fft / (x_fft.abs() + 1e-9)
    g_norm = g_fft / (g_fft.abs() + 1e-9)

    phase_similarity = (x_norm * g_norm.conj()).real
    loss = 1.0 - phase_similarity

    if reduction == 'mean':
        return loss.mean()
    elif reduction == 'sum':
        return loss.sum()
    elif reduction == 'none':
        return loss
    else:
        raise ValueError(f"Unsupported reduction mode: {reduction}")


def feature_loss(fmap_r, fmap_g):
    """
    Compute the feature loss between reference and generated feature maps.

    Args:
        fmap_r (list of torch.Tensor): List of reference feature maps.
        fmap_g (list of torch.Tensor): List of generated feature maps.
    """
    return 2 * sum(
        torch.mean(torch.abs(rl - gl))
        for dr, dg in zip(fmap_r, fmap_g)
        for rl, gl in zip(dr, dg)
    )


def discriminator_loss(disc_real_outputs, disc_generated_outputs):
    """
    Compute the discriminator loss for real and generated outputs.

    Args:
        disc_real_outputs (list of torch.Tensor): List of discriminator outputs for real samples.
        disc_generated_outputs (list of torch.Tensor): List of discriminator outputs for generated samples.
    """
    loss = 0
    # r_losses = []
    # g_losses = []
    for dr, dg in zip(disc_real_outputs, disc_generated_outputs):
        r_loss = torch.mean((1 - dr.float()) ** 2)
        g_loss = torch.mean(dg.float() ** 2)

        # r_losses.append(r_loss.item())
        # g_losses.append(g_loss.item())
        loss += r_loss + g_loss

    return loss # , r_losses, g_losses


def generator_loss(disc_outputs):
    """
    LSGAN Generator Loss:
    """
    loss = 0
    #gen_losses = []
    for dg in disc_outputs:
        l = torch.mean((1 - dg.float()) ** 2)
        # gen_losses.append(l.item())
        loss += l

    return loss #, gen_losses


def kl_loss(z_p, logs_q, m_p, logs_p, z_mask):
    """
    Compute the Kullback-Leibler divergence loss.

    Args:
        z_p (torch.Tensor): Sampled latent variable transformed by the flow [b, h, t_t].
        logs_q (torch.Tensor): Log variance of the posterior distribution q [b, h, t_t].
        m_p (torch.Tensor): Mean of the prior distribution p [b, h, t_t].
        logs_p (torch.Tensor): Log variance of the prior distribution p [b, h, t_t].
        z_mask (torch.Tensor): Mask for the latent variables [b, h, t_t].
    """
    kl = logs_p - logs_q - 0.5 + 0.5 * ((z_p - m_p) ** 2) * torch.exp(-2 * logs_p)
    kl = (kl * z_mask).sum()
    loss = kl / z_mask.sum()

    return loss


def kl_loss_floored(z_p, logs_q, m_p, logs_p, z_mask, free_bits=1.0):
    """
    KL divergence with Free Bits floor (Kingma et al.).
    Each latent dimension must carry at least `free_bits` nats of information.
    Dimensions already above the floor are unaffected — zero overhead.
    Prevents posterior collapse with strong decoders.

    Args:
        z_p (torch.Tensor): Sampled latent variable transformed by the flow [b, h, t_t].
        logs_q (torch.Tensor): Log variance of the posterior distribution q [b, h, t_t].
        m_p (torch.Tensor): Mean of the prior distribution p [b, h, t_t].
        logs_p (torch.Tensor): Log variance of the prior distribution p [b, h, t_t].
        z_mask (torch.Tensor): Mask for the latent variables [b, h, t_t].
        free_bits (float): Minimum KL per dimension in nats.
    """
    # kl per element: [b, h, t]
    kl = logs_p - logs_q - 0.5 + 0.5 * ((z_p - m_p) ** 2) * torch.exp(-2 * logs_p)
    kl = kl * z_mask

    # Average over batch and time per dimension: [h]
    kl_per_dim = kl.sum(dim=(0, 2)) / z_mask.sum(dim=(0, 2)).clamp(min=1)

    # Floor: each dimension contributes at least free_bits nats
    kl_floored = torch.clamp(kl_per_dim, min=free_bits)

    return kl_floored.mean()


def discriminator_tprls_loss(disc_real_outputs, disc_generated_outputs):
    """
    TPRLS Discriminator Loss
    """
    loss = 0
    tau = 0.04
    for dr, dg in zip(disc_real_outputs, disc_generated_outputs):
        dr = dr.float()
        dg = dg.float()
        m_DG = torch.median(dr - dg)
        diff = (dr - dg) - m_DG
        mask = dr < (dg + m_DG)
        masked = diff[mask]
        L_rel = torch.mean(masked ** 2) if masked.numel() > 0 else torch.tensor(0.0, device=dr.device)
        loss += tau - F.relu(tau - L_rel)
    return loss


def generator_tprls_loss(disc_real_outputs, disc_generated_outputs):
    """
    TPRLS Generator Loss
    """
    loss = 0
    tau = 0.04
    for dr, dg in zip(disc_real_outputs, disc_generated_outputs):
        dr = dr.float()
        dg = dg.float()
        diff = dg - dr
        m_DG = torch.median(diff)
        rel = diff - m_DG
        mask = diff < m_DG
        masked = rel[mask]
        L_rel = torch.mean(masked ** 2) if masked.numel() > 0 else torch.tensor(0.0, device=dg.device)
        loss += tau - F.relu(tau - L_rel)
    return loss


class HingeAdversarialLoss(nn.Module):
    """Module for calculating adversarial loss in GANs."""

    def __init__(self, clamped_generator: bool = True) -> None:
        """
        Hinge adversarial loss.

        Args:
            clamped_generator (bool): If True, uses clamped generator loss max{0, 1 - D(fake)} If False, uses unclamped -D(fake).mean().
        """
        super().__init__()

        self.adv_criterion = self._hinge_adv_loss_clamped if clamped_generator else self._hinge_adv_loss_unclamped
        self.fake_criterion = self._hinge_fake_loss
        self.real_criterion = self._hinge_real_loss

    def forward(
        self, p_fakes: List[Tensor], p_reals: Optional[List[Tensor]] = None
    ) -> Union[Tensor, Tuple[Tensor, Tensor]]:
        # Generator adversarial loss
        if p_reals is None:
            adv_loss = 0.0
            for p_fake in p_fakes:
                adv_loss += self.adv_criterion(p_fake)
            return adv_loss

        # Discriminator adversarial loss
        else:
            fake_loss, real_loss = 0.0, 0.0
            for p_fake, p_real in zip(p_fakes, p_reals):
                fake_loss += self.fake_criterion(p_fake)
                real_loss += self.real_criterion(p_real)
            return fake_loss, real_loss

    def _hinge_adv_loss_clamped(self, x: Tensor) -> Tensor:
        """Clamped hinge loss for generator: max{0, 1 - D(fake)}. Wavehax-aligned."""
        return -torch.mean(torch.min(x - 1, x.new_zeros(x.size())))

    def _hinge_adv_loss_unclamped(self, x: Tensor) -> Tensor:
        """Unclamped hinge loss for generator: -D(fake).mean()."""
        return -x.mean()

    def _hinge_real_loss(self, x: Tensor) -> Tensor:
        """Calculate hinge loss for real samples."""
        return -torch.mean(torch.min(x - 1, x.new_zeros(x.size())))

    def _hinge_fake_loss(self, x: Tensor) -> Tensor:
        """Calculate hinge loss for fake samples."""
        return -torch.mean(torch.min(-x - 1, x.new_zeros(x.size())))


class SoftHingeAdversarialLoss(nn.Module):
    """Combined adversarial loss using softplus for the discriminator and
    soft hinge for the generator:
    - Discriminator: softplus (non-saturating logistic, no margin — D never
      stops learning, every sample always contributes gradient)
    - Generator: soft hinge (margin at 1, smoothed by softplus — strong push
      when D(fake) < 1, gentle gradient when already fooling D)
    """

    def forward(
        self, p_fakes: List[Tensor], p_reals: Optional[List[Tensor]] = None
    ) -> Union[Tensor, Tuple[Tensor, Tensor]]:
        if p_reals is None:
            # Generator: soft hinge — margin-based, smooth
            adv_loss = 0.0
            for p_fake in p_fakes:
                adv_loss += F.softplus(1 - p_fake).mean()
            return adv_loss
        else:
            # Discriminator: softplus — non-saturating logistic, no margin
            fake_loss, real_loss = 0.0, 0.0
            for p_fake, p_real in zip(p_fakes, p_reals):
                fake_loss += F.softplus(p_fake).mean()
                real_loss += F.softplus(-p_real).mean()
            return fake_loss, real_loss


class LeCamRegularization(nn.Module):
    """LeCam regularization for discriminator stability.
    Prevents D from becoming too confident relative to its historical average,
    keeping gradients flowing to G at reasonable magnitude.
    Near-zero computational cost — operates on already-computed D outputs."""

    def __init__(self, decay: float = 0.999):
        super().__init__()
        self.register_buffer("ema_real", torch.zeros(1))
        self.register_buffer("ema_fake", torch.zeros(1))
        self.decay = decay

    @torch.no_grad()
    def update_ema(self, d_real_outputs: List[Tensor], d_fake_outputs: List[Tensor]):
        mean_real = torch.stack([d.detach().float().mean() for d in d_real_outputs]).mean()
        mean_fake = torch.stack([d.detach().float().mean() for d in d_fake_outputs]).mean()
        self.ema_real.lerp_(mean_real, 1 - self.decay)
        self.ema_fake.lerp_(mean_fake, 1 - self.decay)

    def forward(self, d_real_outputs: List[Tensor], d_fake_outputs: List[Tensor]) -> Tensor:
        loss = 0.0
        for d_real, d_fake in zip(d_real_outputs, d_fake_outputs):
            loss += F.relu(d_real - self.ema_fake).mean()
            loss += F.relu(self.ema_real - d_fake).mean()
        return loss / len(d_real_outputs)


def pitch_prediction_loss(log_f0_pred, vuv_pred, pitchf, x_mask):
    """
    Period VITS pitch prediction loss.
    Supervises the Frame Pitch Predictor with ground-truth F0.

    Args:
        log_f0_pred: Predicted log-F0 [B, 1, T].
        vuv_pred: Predicted voicing logits (pre-sigmoid) [B, 1, T].
        pitchf: Ground-truth F0 in Hz [B, T].
        x_mask: Sequence mask [B, 1, T].

    Returns:
        loss_f0: MSE on log-F0 for voiced frames.
        loss_vuv: BCE on voicing flags.
    """
    # Ground truth voicing: voiced if F0 > 0
    vuv_gt = (pitchf > 0).float().unsqueeze(1)  # [B, 1, T]

    # Log-F0 ground truth (clamp to avoid log(0))
    log_f0_gt = torch.log(pitchf.clamp(min=1e-5)).unsqueeze(1)  # [B, 1, T]

    # F0 MSE loss — only for voiced frames
    voiced_mask = vuv_gt * x_mask  # [B, 1, T]
    n_voiced = voiced_mask.sum().clamp(min=1)
    loss_f0 = ((log_f0_pred - log_f0_gt) ** 2 * voiced_mask).sum() / n_voiced

    # V/UV BCE loss — all frames
    n_frames = x_mask.sum().clamp(min=1)
    loss_vuv = F.binary_cross_entropy_with_logits(
        vuv_pred * x_mask, vuv_gt * x_mask, reduction="sum"
    ) / n_frames

    return loss_f0, loss_vuv


def envelope_loss(y_real, y_fake, 
                  pool=nn.MaxPool1d(kernel_size=5, stride=3), 
                  criterion=nn.L1Loss()):
    """
    Calculates the envelope loss between real and generated audio.
    Matches volume peaks and troughs to improve transient clarity.
    """

    # Calculate loss for both polarities (peaks and troughs)
    loss_pos = criterion(pool(y_real), pool(y_fake))
    loss_neg = criterion(pool(-y_real), pool(-y_fake))
    
    return loss_pos + loss_neg
