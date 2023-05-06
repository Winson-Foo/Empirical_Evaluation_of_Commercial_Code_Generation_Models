# Refactored code with comments for improved maintainability

import torch
import torch.nn as nn
import torch.nn.functional as F
import numpy as np
import math
from ..utils import *


# Define a BaseNet class for inheritance
class BaseNet:
    def __init__(self):
        pass

    def reset_noise(self):
        pass


# Define a function for layer initialization
def layer_init(layer, w_scale=1.0):
    nn.init.orthogonal_(layer.weight.data)
    layer.weight.data.mul_(w_scale)
    nn.init.constant_(layer.bias.data, 0)
    return layer


# Define a NoisyLinear class that inherits from nn.Module
class NoisyLinear(nn.Module):
    def __init__(self, in_features, out_features, std_init=0.4):
        super(NoisyLinear, self).__init__()

        self.in_features = in_features
        self.out_features = out_features
        self.std_init = std_init

        # Define all the parameters and buffers
        self.weight_mu = nn.Parameter(torch.zeros((out_features, in_features)), requires_grad=True)
        self.weight_sigma = nn.Parameter(torch.zeros((out_features, in_features)), requires_grad=True)
        self.register_buffer('weight_epsilon', torch.zeros((out_features, in_features)))

        self.bias_mu = nn.Parameter(torch.zeros(out_features), requires_grad=True)
        self.bias_sigma = nn.Parameter(torch.zeros(out_features), requires_grad=True)
        self.register_buffer('bias_epsilon', torch.zeros(out_features))

        self.register_buffer('noise_in', torch.zeros(in_features))
        self.register_buffer('noise_out_weight', torch.zeros(out_features))
        self.register_buffer('noise_out_bias', torch.zeros(out_features))

        # Initialize the parameters and noise buffers
        self.reset_parameters()
        self.reset_noise()

    def forward(self, x):
        # Calculate the weight and bias based on the training state
        if self.training:
            weight = self.weight_mu + self.weight_sigma.mul(self.weight_epsilon)
            bias = self.bias_mu + self.bias_sigma.mul(self.bias_epsilon)
        else:
            weight = self.weight_mu
            bias = self.bias_mu

        # Perform a linear operation using the weight, bias, and input
        return F.linear(x, weight, bias)

    def reset_parameters(self):
        # Compute the range for initialization of the weight and bias mu parameters
        mu_range = 1 / math.sqrt(self.weight_mu.size(1))

        # Initialize the weight and bias mu and sigma parameters
        self.weight_mu.data.uniform_(-mu_range, mu_range)
        self.weight_sigma.data.fill_(self.std_init / math.sqrt(self.weight_sigma.size(1)))
        
        self.bias_mu.data.uniform_(-mu_range, mu_range)
        self.bias_sigma.data.fill_(self.std_init / math.sqrt(self.bias_sigma.size(0)))

    def reset_noise(self):
        # Generate noise tensors for input, weight, and bias
        self.noise_in.normal_(std=Config.NOISY_LAYER_STD)
        self.noise_out_weight.normal_(std=Config.NOISY_LAYER_STD)
        self.noise_out_bias.normal_(std=Config.NOISY_LAYER_STD)

        # Transform the noise tensor using the transform_noise function to get the epsilon tensor
        self.weight_epsilon.copy_(self.transform_noise(self.noise_out_weight).ger(
            self.transform_noise(self.noise_in)))
        self.bias_epsilon.copy_(self.transform_noise(self.noise_out_bias))

    def transform_noise(self, x):
        # Apply the noise transformation to the noise tensor to get the epsilon tensor
        return x.sign().mul(x.abs().sqrt())