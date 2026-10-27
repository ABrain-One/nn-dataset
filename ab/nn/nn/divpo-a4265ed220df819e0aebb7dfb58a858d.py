import torch
import torch.nn as nn

def supported_hyperparameters():
    return {'lr', 'momentum'}

class Block(nn.Module):
    def __init__(self, in_channels, out_channels, kernel_size=3, stride=1, padding=1, dilation=1, groups=1, bias=False):
        super().__init__()
        self.conv = nn.Conv2d(in_channels, out_channels, kernel_size, stride, padding, dilation, groups, bias)
        self.bn = nn.BatchNorm2d(out_channels)
        self.relu = nn.ReLU(inplace=True)

    def forward(self, x):
        return self.relu(self.bn(self.conv(x)))

class Net(nn.Module):
    def __init__(self, in_shape, out_shape, prm, device):
        super().__init__()
        self.device = device
        in_channels = in_shape[1] if len(in_shape) == 4 else in_shape[0]
        num_classes = out_shape[0]
        self.stem = nn.Sequential(
            Block(in_channels, 32, kernel_size=3, padding=1),
            nn.MaxPool2d(2, 2),
            Block(32, 64, kernel_size=3, padding=1),
            nn.MaxPool2d(2, 2)
        )
        self.layer1 = Block(64, 64, kernel_size=3, padding=1)
        self.layer2 = nn.Sequential(
            nn.Conv2d(64, 128, kernel_size=3, stride=1, padding=1),
            nn.BatchNorm2d(128),
            nn.ReLU(inplace=True),
            nn.MaxPool2d(2, 2)
        )
        self.layer3 = Block(128, 128, kernel_size=3, padding=1)
        self.layer4 = nn.Sequential(
            nn.Conv2d(128, 128, kernel_size=3, stride=1, padding=1),
            nn.BatchNorm2d(128),
            nn.ReLU(inplace=True),
            nn.MaxPool2d(2, 2)
        )
        self.avgpool = nn.AdaptiveAvgPool2d((6, 6))
        self.classifier = nn.Linear(128 * 6 * 6, num_classes)
        self.criteria = (nn.CrossEntropyLoss().to(device),)
        self.optimizer = torch.optim.SGD(
            self.parameters(),
            lr=prm.get('lr', 0.01),
            momentum=prm.get('momentum', 0.9),
        )

    def forward(self, x):
        x = self.stem(x)
        x = self.layer1(x)
        x = self.layer2(x)
        x = self.layer3(x)
        x = self.layer4(x)
        x = self.avgpool(x)
        x = x.flatten(1)
        x = self.classifier(x)
        return x

    def train_setup(self, prm):
        self.to(self.device)
        self.criteria = (nn.CrossEntropyLoss().to(self.device),)
        self.optimizer = torch.optim.SGD(
            self.parameters(),
            lr=prm.get('lr', 0.01),
            momentum=prm.get('momentum', 0.9),
        )

    def learn(self, train_data):
        self.train()
        for inputs, labels in train_data:
            inputs = inputs.to(self.device)
            labels = labels.to(self.device)
            self.optimizer.zero_grad()
            outputs = self(inputs)
            loss = self.criteria[0](outputs, labels)
            loss.backward()
            self.optimizer.step()

# Dummy input to derive the correct in_channels and out_channels.
dummy_input = torch.randn(1, 3, 32, 32)
in_channels = dummy_input.shape[1]
# Expected output class count, for consistency with the dummy input.
# Since this is the first layer, it should match the number of channels from the dummy input.
expected_out_channels = in_channels

# Since this is the first layer, the input channels should match the number of channels from the dummy input.
layer = Block(in_channels, expected_out_channels, kernel_size=3, padding=1)

# The model architecture with the derived in_channels and expected out_channels.
model = Net(
    in_shape=(in_channels, 32, 32),
    out_shape=(expected_out_channels,),
    prm={'lr': 0.01, 'momentum': 0.9},
    device=torch.device('cpu')
)
model.train_setup({'lr': 0.01, 'momentum': 0.9})

# Target total params <= 500000. Optimize the model architecture for this limit.
# Since this is an edge-friendly latency budget, prioritize simplicity and small kernels.
# Examples of good architectures:
# - Simple sequences of blocks (e.g., layer after layer)
# - Fewer layers with deep blocks
# - Small kernels (e.g., 3x3 or less)
# - Stride to maintain spatial size
# - Fewer blocks with deeper ones
# The above examples should serve as a guide to keep the model under the parameter limit.