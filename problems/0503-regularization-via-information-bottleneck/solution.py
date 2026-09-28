import numpy as np

def information_bottleneck_loss(task_loss: float, mu: np.ndarray, log_var: np.ndarray, beta: float) -> tuple:
    """
    Compute the Information Bottleneck regularized loss.
    
    Args:
        task_loss: Precomputed task loss (scalar)
        mu: Encoder means, shape (batch_size, latent_dim)
        log_var: Encoder log-variances, shape (batch_size, latent_dim)
        beta: Trade-off parameter for compression regularization
    
    Returns:
        Tuple of (total_loss, mean_kl_divergence), both rounded to 4 decimal places
    """
    # Compute the KL divergence for each sample across the latent dimensions
    # KL(q(z|x) || p(z)) = -0.5 * sum(1 + log_var - mu^2 - exp(log_var))
    kl_per_sample = -0.5 * np.sum(1 + log_var - np.square(mu) - np.exp(log_var), axis=-1)
    
    # Average KL divergence across the batch
    mean_kl = np.mean(kl_per_sample)
    
    # Total loss combining task loss and weighted regularization
    total_loss = task_loss + beta * mean_kl
    
    return (round(float(total_loss), 4), round(float(mean_kl), 4))