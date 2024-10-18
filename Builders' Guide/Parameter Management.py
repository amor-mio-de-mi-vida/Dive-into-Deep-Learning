import torch
from torch import nn

if __name__ == "__main__":
    net = nn.Sequential(nn.LazyLinear(8),
                        nn.ReLU(),
                        nn.LazyLinear(1))

    X = torch.rand(size=(2, 4))
    print(net(X).shape)

    print(net[2].state_dict())

    print(type(net[2].bias), net[2].bias.data)

    print(net[2].weight.grad == None)

    print([(name, param.shape) for name, param in net.named_parameters()])

    # We need to give the shared layer a name so that we can refer to its
    # parameters
    shared = nn.LazyLinear(8)
    net = nn.Sequential(nn.LazyLinear(8), nn.ReLU(),
                        shared, nn.ReLU(),
                        shared, nn.ReLU(),
                        nn.LazyLinear(1))

    net(X)
    # Check whether the parameters are the same
    print(net[2].weight.data[0] == net[4].weight.data[0])
    net[2].weight.data[0, 0] = 100
    # Make sure that they are actually the same object rather than just having the
    # same value
    print(net[2].weight.data[0] == net[4].weight.data[0])


    