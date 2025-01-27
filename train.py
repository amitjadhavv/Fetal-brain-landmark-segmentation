import torch
from torch.nn.parallel import DataParallel
from torch.utils.data import DataLoader
from Datasets.dataset import MRIDataset
from models.VNet import VNet
import torchio as tio
import numpy as np
from utils.support import EarlyStopping
from configs.config import Config
from tqdm import tqdm
from monai.losses import DiceLoss
from monai.metrics import DiceMetric

def remap_labels(labels, mapping):
    # Remap the labels based on the mapping
    remapped_labels = labels.clone()
    for old, new in mapping.items():
        remapped_labels[labels == old] = new
    return remapped_labels

# Define augmentations using torchio
transform = tio.Compose([
    #tio.RandomFlip(axes=(0, 1, 2)),          # Randomly flip along axes
    tio.RandomAffine(scales=(0.9, 1.1), degrees=30),  # Apply random scaling and rotation
    tio.RandomNoise(mean=0.0, std=0.1)     # Add random noise
])
class_mapping = {0: 0, 1: 1, 3: 2, 4: 3, 6: 4}
# Load dataset
image_paths = Config.get_image_paths()
mask_paths = Config.get_mask_paths()
train_dataset = MRIDataset(image_paths, mask_paths, split="train", transform=transform, class_mapping=class_mapping)
train_dataloader = DataLoader(train_dataset, batch_size=Config.BATCH_SIZE, shuffle=True)
# val_dataset = MRIDataset(image_paths,mask_paths, split="val",class_mapping=class_mapping)
# val_dataloader = DataLoader(val_dataset, batch_size=Config.BATCH_SIZE, shuffle=True)

# class_weight calculation
epsilon = 1e-6
norm_class_weights = None
class_weights=np.zeros(Config.NUM_CLASSES)
for batch in train_dataloader:
    masks = torch.flatten(batch[1]).to(torch.long)
    a=list(torch.bincount(masks).numpy())
    for j in range(Config.NUM_CLASSES):
        class_weights[j]+=a[j]/(sum(a)+epsilon)
class_weights = class_weights/len(train_dataloader)
foreground_weights=(1-class_weights)[1:]
inverse_values = 1 / foreground_weights
norm_class_weights = torch.tensor(inverse_values / inverse_values.sum())
# print(norm_class_weights)

# Initialize model
model = VNet(num_classes=Config.NUM_CLASSES)
if torch.cuda.device_count()>1:
    model = DataParallel(model)
model = model.to(Config.DEVICE)
optimizer = torch.optim.Adam(model.parameters(), lr=Config.LEARNING_RATE)
criterion = DiceLoss(include_background=False, softmax=True, squared_pred=True,weight=norm_class_weights, reduction="mean")
dice_metric = DiceMetric(include_background=False)

#set early stopping
# early_stopping = EarlyStopping(patience=5, delta=1e-4)

# # Training loop
for epoch in tqdm(range(Config.NUM_EPOCHS)):
    model.train()
    train_loss = 0
    train_metric = 0
    for images, masks in train_dataloader:
        images, masks = images.to(Config.DEVICE), masks.to(Config.DEVICE)
        masks = masks.squeeze(1)
        masks = masks.to(torch.long)
        one_hot = torch.nn.functional.one_hot(masks, num_classes=Config.NUM_CLASSES)  # Shape: (N, D, H, W, C)
        masks = one_hot.permute(0, 4, 1, 2, 3)
        # Forward pass
        outputs = model(images)
        loss = criterion(outputs, masks)
        # if norm_class_weights is not None:
        #     weights = norm_class_weights.view(1, -1, *([1] * (loss.ndim - 2))).to(Config.DEVICE)  # Broadcast weights to match loss shape
        #     loss = loss * weights  # Apply class weights
        # loss = loss.mean()  # Custom reduction
        # Backpropagation
        optimizer.zero_grad()
        loss.backward()
        optimizer.step()

        train_loss += loss.item()*images.size(0)
        dice = dice_metric(y_pred=outputs, y=masks)
        if dice.ndim > 0:
            dice = dice.mean()
        train_metric += dice.item() * images.size(0)
        break
    train_loss /= len(train_dataloader)
    train_metric /= len(train_dataloader)

    print(f"Epoch {epoch+1}/{Config.NUM_EPOCHS}, Train Loss: {train_loss:.4f}, Train Dice: {train_metric:.4f}")
    # model.eval()
    # val_loss = 0.0
    # val_metric = 0.0
    #
    # with torch.no_grad():
    #     for images, masks in val_dataloader:
    #         images, masks = images.to(Config.DEVICE), masks.to(Config.DEVICE)
    #         outputs = model(images)
    #         #one hot encoding
    #         masks = masks.squeeze(1)
    #         masks = masks.to(torch.long)
    #         one_hot = torch.nn.functional.one_hot(masks, num_classes=Config.NUM_CLASSES)  # Shape: (N, D, H, W, C)
    #         masks = one_hot.permute(0, 4, 1, 2, 3)
    #         loss = criterion(outputs, masks)
    #         if norm_class_weights is not None:
    #             weights = norm_class_weights.view(1, -1, *([1] * (loss.ndim - 2))).to(Config.DEVICE)  # Broadcast weights to match loss shape
    #             loss = loss * weights  # Apply class weights
    #         loss = loss.mean()
    #         val_loss += loss.item()
    #         dice = dice_metric(y_pred=outputs, y=masks)
    #         if dice.ndim > 0:
    #             dice = dice.mean()
    #         train_metric += dice.item() * images.size(0)
    #         val_metric += dice.item() * images.size(0)
    # val_loss /= len(val_dataloader)
    # val_metric /= len(val_dataloader)

    # print(f"Epoch {epoch + 1}/{Config.NUM_EPOCHS}, Val Loss: {val_loss:.4f}, Val Dice: {val_metric:.4f}")
    # early_stopping(train_metric)
    # if early_stopping.early_stop:
    #     print("Early stopping triggered!")
model_save_path = "V_net_model_cropped.pth"
torch.save(model.state_dict(), model_save_path)
print(f"Model state dictionary saved to {model_save_path}")
