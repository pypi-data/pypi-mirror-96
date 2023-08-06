from typing import Tuple

from torch import batch_norm, nn, ones, std_mean, zeros


class GANAdaptiveInstanceNorm(nn.Module):
    """
    Base class, should not be called directly.

    Custom Adaptive Instance Normalization from https://github.com/AdalbertoCq/Pathology-GAN/blob/master/models/generative/normalization.py (conditional_batch_norm)

    GAN related AdaIN Paper: https://arxiv.org/pdf/1812.04948.pdf
    """

    def __init__(self, inputs, c, spectral: bool = False, n_power_iterations: int = 1, eps: float = 1e-12, gain: float = 1e-4):
        """        
        :param inputs: number of inputs
        :type inputs: int
        :param c: TODO
        :type c: int
        :param spectral: defines if spectral normalization is used
        :type spectral: boolean
        :param n_power_iterations: number of power iterations fpr spectral normalization
        :type n_power_iterations: int
        :param eps: hyperparameter for spectral normalization
        :type eps: float
        :param gain: weight parameter for orthogonal initialization 
        :type gain: float
        """
        super(GANAdaptiveInstanceNorm, self).__init__()
        self.gain = gain  # orthogonal init

        def block_dense(in_feat, out_feat, activation=True, spectral=True, n_power_iterations=1, eps=1e-12):
            # Linear + Spectral Norm (optional) + Relu (optional)
            if spectral:
                layers = [nn.utils.spectral_norm(
                    nn.Linear(in_feat, out_feat), n_power_iterations=n_power_iterations, eps=eps)]
            else:
                layers = [nn.Linear(in_feat, out_feat)]

            if activation:
                layers.append(nn.ReLU(inplace=True))

            return layers

        self.decay = 0.9
        self.epsilon = 1e-5

        self.test_mean = zeros([inputs], requires_grad=False)
        self.test_variance = ones([inputs], requires_grad=False)

        # MLP for gamma, and beta
        inter_dim = int((inputs+c)/2)

        self.net = nn.Sequential(
            *block_dense(in_feat=c, out_feat=inter_dim, activation=True, spectral=spectral, n_power_iterations=n_power_iterations, eps=eps))

        self.gamma = nn.Sequential(
            *block_dense(in_feat=inter_dim, out_feat=inputs, activation=True, spectral=spectral, n_power_iterations=n_power_iterations, eps=eps))

        self.beta = nn.Sequential(
            *block_dense(in_feat=inter_dim, out_feat=inputs, activation=False, spectral=spectral, n_power_iterations=n_power_iterations, eps=eps))

        self.init_weights()

    def forward(self, x):
        # TODO check if split is required at all
        # if  len(x) == 4:
        # 	self.gamma = tf.expand_dims(tf.expand_dims(self.gamma, 1), 1)
        # 	self.beta = tf.expand_dims(tf.expand_dims(self.beta, 1), 1)

        if len(x) == 4:
            batch_variance, batch_mean = std_mean(x, dim=[2, 3], keepdim=True)
        else:
            batch_variance, batch_mean = std_mean(x, dim=[1], keepdim=True)

        batch_norm_output = batch_norm(
            x, batch_mean, batch_variance, self.beta, self.gamma, self.epsilon)

        return batch_norm_output

    def init_weights(self):
        for module in self.modules():
            if isinstance(module, nn.Conv2d):
                nn.init.orthogonal_(module.weight, gain=self.gain)
                nn.init.constant_(module.bias, 0)


class GANAdaptiveInstanceNorm1d(GANAdaptiveInstanceNorm):
    """
    Custom Adaptive Instance Normalization 1d Wrapper
    """

    def __init__(self, feat: int, spectral: bool = False, n_power_iterations: int = 1, eps: float = 1e-12, gain: float = 1e-4):
        """
        Init for Normalization1d

        :param feat: number of input features
        :type feat: int
        :param spectral: defines if spectral normalization is used
        :type spectral: boolean
        :param n_power_iterations: number of power iterations fpr spectral normalization
        :type n_power_iterations: int
        :param eps: hyperparameter for spectral normalization
        :type eps: float
        :param gain: weight parameter for orthogonal initialization 
        :type gain: float
        """
        # c is always 1 for 1d
        super(GANAdaptiveInstanceNorm1d, self).__init__(
            inputs=feat, c=1, spectral=spectral, n_power_iterations=n_power_iterations, eps=eps, gain=gain)


class GANAdaptiveInstanceNorm2d(GANAdaptiveInstanceNorm):
    """
    Custom Adaptive Instance Normalization 2d Wrapper
    """

    def __init__(self, channels: int, c: int, spectral: bool = False, n_power_iterations: int = 1, eps: float = 1e-12, gain: float = 1e-4):
        """
        Init for Normalization1d

        :param channels: number of channels
        :type channels: int
        :param c: TODO
        :type c: int
        :param spectral: defines if spectral normalization is used
        :type spectral: boolean
        :param n_power_iterations: number of power iterations fpr spectral normalization
        :type n_power_iterations: int
        :param eps: hyperparameter for spectral normalization
        :type eps: float
        :param gain: weight parameter for orthogonal initialization 
        :type gain: float
        """
        super(GANAdaptiveInstanceNorm2d, self).__init__(
            inputs=channels, c=c, spectral=spectral, n_power_iterations=n_power_iterations, eps=eps, gain=gain)

