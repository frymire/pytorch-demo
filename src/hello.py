import torch

from torch import nn, Tensor
from torch.nn import Flatten, Sequential, Linear, ReLU, CrossEntropyLoss
from torch.optim import Optimizer
from torch.utils.data import DataLoader
from torchvision import datasets
from torchvision.datasets import FashionMNIST
from torchvision.transforms import v2


class NeuralNetwork(nn.Module):

    def __init__(self) -> None:
        super().__init__()
        self.flatten: Flatten = Flatten()
        self.linear_relu_stack: Sequential = Sequential(
            Linear(28*28, 512),
            ReLU(),
            Linear(512, 512),
            ReLU(),
            Linear(512, 10)
        )

    def forward(self, x: Tensor) -> Tensor:
        x: Tensor = self.flatten(x)
        logits: Tensor = self.linear_relu_stack(x)
        return logits


def train(
        data_set: FashionMNIST,
        data_loader: DataLoader,
        model: NeuralNetwork,
        loss_fn: CrossEntropyLoss,
        optimizer: Optimizer,
        detected_device: str) -> None:

    size: int = len(data_set)
    model.train()

    for batch, (X, y) in enumerate(data_loader):

        X, y = X.to(detected_device), y.to(detected_device)

        # Compute prediction error
        prediction: Tensor = model(X)
        loss = loss_fn(prediction, y)

        # Run backpropagation
        loss.backward()
        optimizer.step()
        optimizer.zero_grad()

        if batch % 100 == 0:
            loss, current = loss.item(), (batch + 1) * len(X)
            print(f"loss: {loss:>7f} [{current:>5d} / {size:>5d}]")


def test(data_loader: DataLoader, model: NeuralNetwork, loss_fn: CrossEntropyLoss, detected_device: str) -> None:

    size: int = len(data_loader.dataset)
    num_batches: int = len(data_loader)
    model.eval()
    test_loss, correct = 0, 0

    with torch.no_grad():

        for X, y in data_loader:
            X, y = X.to(detected_device), y.to(detected_device)
            prediction: Tensor = model(X)
            test_loss += loss_fn(prediction, y).item()
            correct += (prediction.argmax(1) == y).type(torch.float).sum().item()

        test_loss /= num_batches
        correct /= size
        print(f"Test Error: \n  Accuracy: {(100*correct):>0.1f}%, Average Loss: {test_loss:>8f}\n")


def main() -> None:

    training_data: FashionMNIST = datasets.FashionMNIST(
        root="data",
        train=True,
        download=True,
        transform=v2.Compose([v2.ToImage(), v2.ToDtype(torch.float32, scale=True)])
    )

    test_data: FashionMNIST = datasets.FashionMNIST(
        root="data",
        train=False,
        download=True,
        transform=v2.Compose([v2.ToImage(), v2.ToDtype(torch.float32, scale=True)])
    )

    BATCH_SIZE: int = 64

    training_data_loader: DataLoader = DataLoader(training_data, batch_size=BATCH_SIZE)
    test_data_loader: DataLoader = DataLoader(test_data, batch_size=BATCH_SIZE)

    for X, y in test_data_loader:
        print(f"Shape of X [N, C, H, W]: {X.shape}")
        print(f"Shape of y: {y.shape} {y.dtype}")
        break

    print(torch.cuda.is_available())
    accelerator: torch.device | None = torch.accelerator.current_accelerator()
    detected_device: str = accelerator.type if accelerator is not None else "cpu"
    print(f"Using {detected_device} device")

    model: NeuralNetwork = NeuralNetwork().to(detected_device)
    print(model)

    loss_fn: CrossEntropyLoss = CrossEntropyLoss()
    optimizer: Optimizer = torch.optim.SGD(model.parameters(), lr=1e-3)

    NUM_EPOCHS: int = 5
    for t in range(NUM_EPOCHS):
        print(f"Epoch: {t + 1}\n-------------------------------------")
        train(training_data, training_data_loader, model, loss_fn, optimizer, detected_device)
        test(test_data_loader, model, loss_fn, detected_device)
    print("Done!")


if __name__ == "__main__":
    main()
