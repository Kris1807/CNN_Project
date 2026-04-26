import torch.nn as nn
from torchvision import models


# A small baseline CNN for comparison against the transfer-learning model.
class SimpleCNN(nn.Module):
    def __init__(self, num_classes=7):
        super().__init__()
        # The feature extractor gradually increases channel depth while reducing spatial size.
        self.features = nn.Sequential(
            nn.Conv2d(1, 32, 3, padding=1),
            nn.ReLU(),
            nn.BatchNorm2d(32),
            nn.MaxPool2d(2),
            nn.Conv2d(32, 64, 3, padding=1),
            nn.ReLU(),
            nn.BatchNorm2d(64),
            nn.MaxPool2d(2),
            nn.Conv2d(64, 128, 3, padding=1),
            nn.ReLU(),
            nn.BatchNorm2d(128),
            nn.MaxPool2d(2),
        )
        # The classifier maps the learned spatial features to the 7 emotion classes.
        self.classifier = nn.Sequential(
            nn.Flatten(),
            nn.Linear(128 * 6 * 6, 256),
            nn.ReLU(),
            nn.Dropout(0.4),
            nn.Linear(256, num_classes),
        )

    def forward(self, x):
        return self.classifier(self.features(x))


# ResNet18 starts from pretrained ImageNet weights and replaces the final layer for FER classification.
def build_resnet18(num_classes=7):
    model = models.resnet18(weights=models.ResNet18_Weights.DEFAULT)
    model.fc = nn.Linear(model.fc.in_features, num_classes)
    return model
