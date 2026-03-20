## 1. Logging in the cluster

For convenience, create a config file in `~/.ssh/config` with the following content:

```
Host turpan
    Hostname turpanlogin.calmip.univ-toulouse.fr
    User YOUR_USERNAME
    PreferredAuthentications password
    PubkeyAuthentication no
```

Then you can simply log in with:

```bash
ssh turpan
```

Change your password at first login:

```bash
passwd
```

## 2. Description of the cluster

This cluster is made of 15 compute node with 2 Nvidia A100 and 80Gb of RAM each. 

For the storage, you have access to three storage spaces:
- a 10Gb home directory (`~`), for storing code and softwares.
- a 1Tb `/work/formation/YOUR_USERNAME` directory, dedicated to computation input/output and results.
- a virtually infinite `/tmpdir/YOUR_USERNAME` directory, where you will store environments.

At logging, you will be in the login node, in your home directory.

!!! Note
    The compute nodes are not connected to the internet, so the scripts that automatically download stuff from the internet (datasets, weights, etc.) has to be first run on the login node. Once the data is downloaded, if the script automatically retrieve downloaded data, it can be run on the compute nodes.

## 3. Setting up the environment

You will use `uv` like in the previous practicals but with some subtlelties. 

The cluster has a shared environment with a pytorch version optimized for the compute nodes that can be accessed with `apptainer`, which is similar to `docker` but adapted for clusters. 

What you will do is to create a `uv` environment on top of the pytorch apptainer image. This way, you can access the optimized pytorch version while still being able to install custom dependencies with `uv`.

First, install `uv` on the login node:

```bash
curl -LsSf https://astral.sh/uv/install.sh | sh
```

### Pull the repo

First, clone your forked repo in the home directory. For convenience, you can clone the repo with ssh

![alt text](../assets/image.png)

Create an ssh key in the login node with `ssh-keygen` and add the content of `~/.ssh/id_rsa.pub` to your GitHub account.

![alt text](../assets/image2.png)

click 'SSH and GPG keys', then 'New SSH key', then paste the content of `~/.ssh/id_rsa.pub` (you can access it with `cat ~/.ssh/id_rsa.pub`) in the 'Key' field, give it a title and click 'Add SSH key'.

Then you can clone your forked repo with:

```bash
git clone your_forked_URL
```

Then add this repo as a remote to pull updates

```bash
git remote add upstream https://github.com/paulnovello/Advanced-AI
```

To update your forked repo with the latest changes from this original repo, run:

```bash
git fetch upstream
git merge upstream/main
```

### Work remotely from vscode

I strongly encourage you to use vscode remote environment to work on the project. On the leftbar of vscode, you should see an icon "Remote Explorer". Click on it, then click on "SSH" if needed, and click the left arrow next to "turpan". You will have to fill your password. Once you are connected, you can open the project folder and work on it as if it was local. You can even run the code in a terminal in vscode.

### Create the `uv` environment

Then you have to launch the `apptainer` image and create your env on top of it. 

First, create an env directory in `/tmpdir`:

```bash
mkdir -p /tmpdir/YOUR_USERNAME/envs/aai
```

Then, go to your project directory with `cd` and launch the apptainer image on the **login** node (do not forget to replace YOUR_USERNAME):

```bash
apptainer shell --env PATH=$HOME/.local/bin:$PATH --env UV_PROJECT_ENVIRONMENT=/tmpdir/YOUR_USERNAME/envs/aai --bind /tmpdir,/work --nv /work/conteneurs/sessions-interactives/pytorch-24.02-py3-calmip-si.sif
```

You are now in the `apptainer` image! Install the env using:

```bash
uv sync --only-group turpan
``` 

Now the environment should be up and running.

## 4. Running the code on the compute nodes

To run some code on the compute nodes, you have two choices. You can either use the node in interactive mode, meaning that you have a shell on the compute node where you can run commands one by one, or you can submit a job, meaning that you write a script with the commands you want to run and submit it to the cluster, which will run it for you.

### Interactive mode

Launch an interactive session on a compute node with (do not forget to replace YOUR_USERNAME):

```bash
srun -p shared -n1 --gres=gpu:1 --pty apptainer shell --env PATH=$HOME/.local/bin:$PATH  --env UV_PROJECT_ENVIRONMENT=/tmpdir/YOUR_USERNAME/envs/aai --bind /tmpdir,/work --nv /work/conteneurs/sessions-interactives/pytorch-24.02-py3-calmip-si.sif
```

You can check that you are on a compute node by using `nvidia-smi`. Then you can run your scripts as you would do in a local machine.

### Batch mode

This is where things get complicated :)

For long scirpts, often running overnight, you do not want to keep your terminal open. Instead, you will set up an instruction script (**a job**) giving the cluster all the information it needs to run your code. This script is an `.sbatch` script and looks like this:

```bash
#!/bin/bash
#SBATCH -J mon_job
#SBATCH --nodes 1
#SBATCH --ntasks 1
#SBATCH --cpus-per-task=8
#SBATCH --gres=gpu:1
#SBATCH -p shared
#SBATCH --time=00:15:00 
#SBATCH --reservation=tpirt4
#SBATCH --output=/users/formation/YOUR_USERNAME/job_results/out/job_%j.out
#SBATCH --error=/users/formation/YOUR_USERNAME/job_results/err/job_%j.err


apptainer exec \
--env PATH=$HOME/.local/bin:$PATH \
--env UV_PROJECT_ENVIRONMENT=/tmpdir/YOUR_USERNAME/envs/aai \
--bind /tmpdir,/work \
--nv /work/conteneurs/sessions-interactives/pytorch-24.02-py3-calmip-si.sif \
uv run python mon_script.py
```

You can find this tamplate on `sbatch_scripts/template.sbatch` in the project. Take the time to understand each `#SBATCH` line of the script:
- `--nodes 1`: Number of nodes to use (1 in our case)
- `--ntasks 1`: Number of tasks to run (1 in our case, it is the number of times the command will be run.
- `--cpus-per-task=8`: Number of CPU cores to allocate for this job (8 in our case, change it according to your needs)
- `--gres=gpu:1`: Number of GPU to use (1 in our case)
- `-p shared`: Partition to use (shared in our case, do not change this, it tells the cluster not to use the full node)
- `--time=00:15:00`: Time limit for the job (15 minutes in this case, change it according to your needs)
- `--reservation=tpirt4`: Reservation to use (tpirt4 in this case, change it according to the schedule of the PP sessions - see below)
- `--output`: Path to the file where the standard output of the job will be saved (change YOUR_USERNAME and the path according to your needs)
- `--error`: Path to the file where the standard error of the job will be saved (change YOUR_USERNAME and the path according to your needs)

**Replace `YOUR_USERNAME` and `mon_script.py` with your username and the script you want to run.**

Let's call this file `run_job.sbatch`. You can submit this job to the cluster with:

```bash
sbatch --reservation=tpirt4 run_job.sbatch
```

and check the status of your job with:

```bash
jobinfo job_id
```
where `job_id` is the id of your job given by the output of the `sbatch` command. You can also check the id using:

```bash
squeue -u $USER -l
```

which displays informations about runing jobs.


!!! Note
    The `--reservation=tpirt4` option is specific to this cluster and allows you to use the reserved resources for the Programming Practical sessions. The reference `tpirt4` will change for each PP following this schedule:


```
tpirt1 2026-03-09 14:00:00 - 18:00:00 (Duree : 04 H)
tpirt2 2026-03-13 14:00:00 - 18:00:00 (Duree : 04 H)
tpirt4 2026-03-20 14:00:00 - 18:00:00 (Duree : 04 H)
tpirt5 2026-04-03 14:00:00 - 18:00:00 (Duree : 04 H)
tpirt6 2026-05-27 10:30:00 - 16:00:00 (Duree : 05 H)
tpirt7 2026-05-29 14:00:00 - 18:00:00 (Duree : 04 H)
tpirt8 2026-06-01 14:00:00 - 18:00:00 (Duree : 04 H)
tpirt9 2026-06-03 14:00:00 - 18:00:00 (Duree : 04 H)
tpirt10 2026-06-05 14:00:00 - 18:00:00 (Duree : 04 H)
tpirt11 2026-06-08 14:00:00 - 18:00:00 (Duree : 04 H)
tpirt12 2026-06-10 14:00:00 - 18:00:00 (Duree : 04 H)
tpirt13 2026-06-12 14:00:00 - 18:00:00 (Duree : 04 H)
tpirt14 2026-06-19 14:00:00 - 18:00:00 (Duree : 04 H)
tpirt15 2026-06-22 08:00:00 - 10:00:00 (Duree : 02 H)
tpirt16 2026-06-23 10:00:00 - 12:00:00 (Duree : 02 H)
tpirt17 2026-06-24 14:00:00 - 16:00:00 (Duree : 02 H)
tpirt18 2026-06-26 08:00:00 - 10:00:00 (Duree : 02 H)
```

The code will run silently on the cluster but it will output `stdin` and `stderr` in `--output` and `--error` paths specified in the `.sbatch` script. First, create the paths:

```bash
mkdir -p ~/job_results/out
mkdir -p ~/job_results/err
```

Then you can check the output and error of your job with (Replace job_id with your job_id):

```bash
cat ~/job_results/out/job_job_id.out
cat ~/job_results/err/job_job_id.err
```

Or open it in vscode and refresh it when you want to check the output / error.