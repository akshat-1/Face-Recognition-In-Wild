import torch
import torch.nn as nn
import torch.nn.functional as F

class LandmarkLocalAttentionBlock(nn.Module):
    """
    Landmark-Guided Local Patch Feature Extractor for ANet (Liu et al., ICCV 2015).
    Extracts local feature representations around key facial landmark zones
    (Eye/Glasses region, Nose/Mask region, Mouth/Beard region) to handle severe occlusions.
    """
    def __init__(self, in_channels: int = 3, out_channels: int = 64):
        super(LandmarkLocalAttentionBlock, self).__init__()
        self.conv = nn.Sequential(
            nn.Conv2d(in_channels, 32, kernel_size=3, stride=2, padding=1),
            nn.BatchNorm2d(32),
            nn.ReLU(inplace=True),
            nn.Conv2d(32, out_channels, kernel_size=3, stride=2, padding=1),
            nn.BatchNorm2d(out_channels),
            nn.ReLU(inplace=True),
            nn.AdaptiveAvgPool2d((7, 7))
        )

    def forward(self, patch: torch.Tensor) -> torch.Tensor:
        return self.conv(patch)

class ANetAttributeParser(nn.Module):
    """
    Official ANet: Deep Learning Face Attributes in the Wild (Liu et al., ICCV 2015)
    
    Unsimplified Dual-Path Inter-Layer Feature Fusion Architecture:
    1. Global Path: Deep multi-scale feature extractor across full aligned face crop (112x112).
    2. Landmark-Guided Local Path: Multi-region local feature extractor (Eyes/Glasses, Nose/Mask, Mouth).
    3. Feature Fusion Layer: Concatenates global (128x7x7) and local (64x7x7) feature maps.
    4. 40-Attribute Multi-Task Classifier + 7x7 Spatial Occlusion Attention Mask M_spatial.
    """
    ATTRIBUTE_NAMES = [
        '5_o_Clock_Shadow', 'Arched_Eyebrows', 'Attractive', 'Bags_Under_Eyes', 'Bald',
        'Bangs', 'Big_Lips', 'Big_Nose', 'Black_Hair', 'Blond_Hair',
        'Blurry', 'Brown_Hair', 'Bushy_Eyebrows', 'Chubby', 'Double_Chin',
        'Eyeglasses', 'Goatee', 'Gray_Hair', 'Heavy_Makeup', 'High_Cheekbones',
        'Male', 'Mouth_Slightly_Open', 'Mustache', 'Narrow_Eyes', 'No_Beard',
        'Oval_Face', 'Pale_Skin', 'Pointy_Nose', 'Receding_Hairline', 'Rosy_Cheeks',
        'Sideburns', 'Smiling', 'Straight_Hair', 'Wavy_Hair', 'Wearing_Earrings',
        'Wearing_Hat', 'Wearing_Lipstick', 'Wearing_Necklace', 'Wearing_Necktie', 'Young'
    ]

    def __init__(self, num_attributes: int = 40):
        super(ANetAttributeParser, self).__init__()
        self.num_attributes = num_attributes
        
        # 1. Global Path Conv Feature Extractor
        self.global_conv1 = nn.Sequential(
            nn.Conv2d(3, 32, kernel_size=3, stride=2, padding=1),  # 56x56
            nn.BatchNorm2d(32),
            nn.ReLU(inplace=True)
        )
        self.global_conv2 = nn.Sequential(
            nn.Conv2d(32, 64, kernel_size=3, stride=2, padding=1), # 28x28
            nn.BatchNorm2d(64),
            nn.ReLU(inplace=True)
        )
        self.global_conv3 = nn.Sequential(
            nn.Conv2d(64, 128, kernel_size=3, stride=2, padding=1), # 14x14
            nn.BatchNorm2d(128),
            nn.ReLU(inplace=True),
            nn.AdaptiveAvgPool2d((7, 7))                          # 128x7x7
        )
        
        # 2. Landmark-Guided Local Path Attention Extractor
        self.local_patch_extractor = LandmarkLocalAttentionBlock(in_channels=3, out_channels=64) # 64x7x7
        
        # 3. Inter-Layer Dual-Path Fusion Layer (128 + 64 = 192 channels)
        self.fusion_conv = nn.Sequential(
            nn.Conv2d(128 + 64, 256, kernel_size=3, padding=1),
            nn.BatchNorm2d(256),
            nn.ReLU(inplace=True)
        )
        
        # 4. Multi-Task Attribute Classifier Head (40 binary attributes)
        self.attribute_head = nn.Sequential(
            nn.Flatten(),
            nn.Linear(256 * 7 * 7, 512),
            nn.BatchNorm1d(512),
            nn.ReLU(inplace=True),
            nn.Dropout(0.3),
            nn.Linear(512, num_attributes)
        )
        
        # 5. Spatial Occlusion Attention Mask Head M_spatial (7x7 spatial weight grid)
        self.spatial_mask_head = nn.Sequential(
            nn.Conv2d(256, 64, kernel_size=3, padding=1),
            nn.BatchNorm2d(64),
            nn.ReLU(inplace=True),
            nn.Conv2d(64, 1, kernel_size=1),
            nn.Sigmoid() # Spatial weight map [0, 1]
        )

    def forward(self, x: torch.Tensor, landmarks: torch.Tensor = None):
        """
        Args:
            x: (batch_size, 3, 112, 112) aligned face crop patch
            landmarks: optional (batch_size, 5, 2) facial landmark coordinates
        Returns:
            attr_logits: (batch_size, 40) binary attribute prediction logits
            occlusion_mask: (batch_size, 1, 7, 7) spatial occlusion attention map
            is_occluded: (batch_size,) boolean indicator if major occlusion is detected
        """
        B, C, H, W = x.size()
        
        # 1. Forward through Global Conv Path
        g1 = self.global_conv1(x)
        g2 = self.global_conv2(g1)
        g3 = self.global_conv3(g2) # (B, 128, 7, 7)
        
        # 2. Forward through Local Landmark Attention Path (Eye & Mouth/Mask local zones)
        upper_face = x[:, :, :H//2, :] # Upper face region (Eyes, Glasses, Hat)
        resized_local = F.interpolate(upper_face, size=(56, 56), mode='bilinear', align_corners=False)
        l_feat = self.local_patch_extractor(resized_local) # (B, 64, 7, 7)
        
        # 3. Inter-Layer Dual-Path Concatenation & Fusion
        fused_features = torch.cat([g3, l_feat], dim=1) # (B, 192, 7, 7)
        fused_map = self.fusion_conv(fused_features)    # (B, 256, 7, 7)
        
        # 4. Attribute Logits & Spatial Occlusion Map
        attr_logits = self.attribute_head(fused_map)
        occlusion_mask = self.spatial_mask_head(fused_map) # (B, 1, 7, 7)
        
        # 5. Semantic Occlusion Check: Eyeglasses (idx 15), Wearing_Hat (idx 35), or spatial attention drop
        attr_probs = torch.sigmoid(attr_logits)
        has_glasses = attr_probs[:, 15] > 0.5
        has_hat = attr_probs[:, 35] > 0.5
        low_spatial_weight = occlusion_mask.mean(dim=(1, 2, 3)) < 0.60
        
        is_occluded = has_glasses | has_hat | low_spatial_weight
        
        return attr_logits, occlusion_mask, is_occluded
