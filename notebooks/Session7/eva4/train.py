import sys
from tqdm import tqdm

# from __future__ import print_function
import torch
import torch.nn as nn
import torch.nn.functional as F
import torch.optim as optim
from torchvision import datasets, transforms
import matplotlib.pyplot as plt

from eva4.common import reset_seed, get_config, get_device

def start_training(model, device, train_loader, test_loader, optimizer, scheduler, config):
  epochs = config.get("epochs")
  assert epochs > 0

  train_losses = []
  train_acc = []

  test_losses = []
  test_acc = []

  consecutive_desired_accuracy_remaining = config.get("consecutive_desired_accuracy", 0)

  for epoch in range(epochs):
    print("EPOCH:", epoch)
    train_epoch(model, device, train_loader, optimizer, epoch, train_losses, train_acc)
    accuracy = test_epoch(model, device, test_loader, test_losses, test_acc)
    scheduler.step()
    if config.get("break_on_reaching_desired_accuracy"):
      if accuracy >= config.get("desired_accuracy"):
        consecutive_desired_accuracy_remaining -= 1
      else:
        consecutive_desired_accuracy_remaining = config.get("consecutive_desired_accuracy", 0)

      if consecutive_desired_accuracy_remaining == 0:
        break
    


  fig, axs = plt.subplots(2,2,figsize=(15,10))
  axs[0, 0].plot(train_losses)
  axs[0, 0].set_title("Training Loss")
  axs[1, 0].plot(train_acc[4000:])
  axs[1, 0].set_title("Training Accuracy")
  axs[0, 1].plot(test_losses)
  axs[0, 1].set_title("Test Loss")
  axs[1, 1].plot(test_acc)
  axs[1, 1].set_title("Test Accuracy")

def train_epoch(model, device, train_loader, optimizer, epoch, train_losses, train_acc):
  model.train()
  pbar = tqdm(train_loader)
  correct = 0
  processed = 0
  for batch_idx, (data, target) in enumerate(pbar):
    # get samples
    data, target = data.to(device), target.to(device)

    # Init
    optimizer.zero_grad()
    # In PyTorch, we need to set the gradients to zero before starting to do backpropragation because PyTorch accumulates the gradients on subsequent backward passes. 
    # Because of this, when you start your training loop, ideally you should zero out the gradients so that you do the parameter update correctly.

    # Predict
    y_pred = model(data)

    # Calculate loss
    loss = F.nll_loss(y_pred, target)
    train_losses.append(loss)

    # Backpropagation
    loss.backward()
    optimizer.step()

    # Update pbar-tqdm
    
    pred = y_pred.argmax(dim=1, keepdim=True)  # get the index of the max log-probability
    correct += pred.eq(target.view_as(pred)).sum().item()
    processed += len(data)

    pbar.set_description(desc= f'Loss={loss.item()} Batch_id={batch_idx} Accuracy={100*correct/processed:0.2f}')
    accuracy = 100*correct/processed
    train_acc.append(accuracy)
    return accuracy

def test_epoch(model, device, test_loader, test_losses, test_acc):
    model.eval()
    test_loss = 0
    correct = 0
    with torch.no_grad():
        for data, target in test_loader:
            data, target = data.to(device), target.to(device)
            output = model(data)
            test_loss += F.nll_loss(output, target, reduction='sum').item()  # sum up batch loss
            pred = output.argmax(dim=1, keepdim=True)  # get the index of the max log-probability
            correct += pred.eq(target.view_as(pred)).sum().item()

    test_loss /= len(test_loader.dataset)
    test_losses.append(test_loss)

    print('\nTest set: Average loss: {:.4f}, Accuracy: {}/{} ({:.2f}%)\n'.format(
        test_loss, correct, len(test_loader.dataset),
        100. * correct / len(test_loader.dataset)))
    accuracy = 100. * correct / len(test_loader.dataset)
    test_acc.append(accuracy)
    return accuracy